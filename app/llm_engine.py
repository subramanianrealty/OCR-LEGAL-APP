# -*- coding: utf-8 -*-
"""
LLM Extraction Layer using Qwen2.5-7B-Instruct via local llama.cpp server.
Provides:
- OpenAI-compatible async HTTP client for localhost:8080/v1
- Smart multi-page chunking & keyword-driven section filtering
- Structured JSON schema prompts with ground-truth OCR evidence tracking
- Confidence scoring and uncertainty detection (needs_review flag)
- Automatic fallback to rule-based engine if local LLM service is offline
"""

import os
import json
import logging
import re
from typing import Dict, Any, List, Optional
import httpx

logger = logging.getLogger("LLMEngine")

LLM_BASE_URL = os.environ.get("LLM_BASE_URL", "http://localhost:8080/v1")

SYSTEM_PROMPT_TEMPLATE = """You are a high-precision Tamil Nadu Real Estate & Legal Document Extraction Engine.
Analyze the provided OCR text and extract structured fields as a compact, flat JSON object.

STRICT EXTRACTION RULES:
1. Extract ONLY information explicitly stated in the source text. NEVER guess, extrapolate, or hallucinate.
2. If a field is not detected or missing, set its value to null.
3. Preserve Survey Numbers and Subdivisions EXACTLY as written (e.g., '142/2B', '35/1A'). Do NOT drop slashes, numbers, or letters.
4. Preserve Extent values and units verbatim (e.g., '5.25 Cents', '2400 Sq.Ft', '1 Acre 12 Cents', '0.05.0 Hectare').
5. DPDP Compliance: For Aadhaar numbers, extract ONLY the last 4 masked digits (e.g., 'XXXX-XXXX-1234'). Never output full 12-digit Aadhaar.
6. Return a FLAT JSON object ONLY where keys match the requested field names and values are the extracted strings or null.
   Example: {"patta_number": "1092", "district": "திருவாரூர்", "taluk": "நன்னிலம்", "village": "சன்னாநல்லூர்"}
7. Do not wrap fields in nested objects. Do NOT output extra text or markdown outside the JSON."""

RELEVANT_KEYWORDS = {
    "sale_deed": ["schedule", "சொத்து விவரம்", "survey", "புல எண்", "boundaries", "four boundaries", "vendor", "purchaser", "விற்பவர்", "வாங்குபவர்", "consideration", "கிரையத் தொகை", "previous document", "முந்தைய", "witness", "சாட்சி", "power of attorney", "poa", "gpa", "அதிகாரப்பத்திரம்", "passport", "visa", "nri", "book no", "புத்தகம்", "endorsement", "seal", "address", "முகவரி"],
    "patta": ["பட்டா", "patta", "உரிமையாளர்", "owner", "pattadhar", "புல எண்", "survey", "ஹெக்டேர்", "ஏர்ஸ்", "நஞ்சை", "புஞ்சை", "10(1)"],
    "ec": ["encumbrance", "வில்லங்கம்", "form 15", "form 16", "mortgage", "அடமானம்", "receipt", "ரசீது", "discharge", "விடுதலை", "bank", "வங்கி"],
    "parent_docs": ["mother deed", "parent deed", "முந்தைய ஆவணம்", "தாய் பத்திரம்", "chain of title", "previous owner", "title trace"],
    "building_plan": ["planning permit", "building sanction", "plinth area", "fsi", "setback", "approved plan", "கட்டிட வரைபடம்"],
    "rera": ["tnrera", "rera", "form c", "project registration", "promoter"],
    "tax_eb": ["property tax", "tangedco", "consumer no", "assessment no", "water tax", "வரி ரசீது"],
    "layout_approval": ["ppd/lo", "approved layout", "open space reservation", "osr", "dtcp", "cmda"],
    "death_legal_heir": ["legal heir", "varisu", "death certificate", "இறப்பு", "வாரிசு", "deceased", "surviving heirs", "tahsildar", "mutation"],
    "loan_docs": ["modt", "memorandum of deposit", "mortgage", "housing loan", "bank noc", "discharge receipt"],
    "tslr": ["tslr", "town survey", "ward", "block", "t.s. no", "நகர நில அளவை", "ryotwari", "land classification"]
}


DEFAULT_TARGET_FIELDS_BY_DOC_TYPE = {
    "patta": {
        "patta_number": "Patta Number / பட்டா எண்",
        "owner_name": "Owner Name(s) / உரிமையாளர்கள் பெயர்",
        "survey_numbers": "Survey Number(s) / புல எண்",
        "village": "Village / வருவாய் கிராமம்",
        "taluk": "Taluk / வட்டம்",
        "district": "District / மாவட்டம்",
        "extent_details": "Extent of Land / பரப்பளவு",
        "nature_of_land": "Nature of Land (Wet/Dry) / நில வகைப்பாடு"
    },
    "sale_deed": {
        "vendor_details": "Vendor / Seller name(s), PAN, masked Aadhaar",
        "vendor_name": "Executant / Vendor / Seller full name",
        "vendor_father_husband_name": "Vendor's Father's or Husband's name",
        "vendor_address": "Vendor's full address",
        "purchaser_details": "Purchaser / Buyer name(s), PAN, masked Aadhaar",
        "purchaser_name": "Claimant / Purchaser / Buyer full name",
        "purchaser_father_husband_name": "Purchaser's Father's or Husband's name",
        "purchaser_address": "Purchaser's full address",
        "history_previous_owner": "History / Previous Owner / Prior Deed details",
        "previous_doc_reference": "Previous document / mother deed number and year",
        "schedule_property_type": "Schedule of Property (Plot / House / Apartment with UDS)",
        "survey_number": "Survey Number & Sub-division (e.g., '142/2A')",
        "sub_division_number": "Sub-division number of the survey number",
        "land_extent": "Total Land Extent transferred (verbatim Sq.Ft / Cents / Acres)",
        "building_built_up_area": "Built-up area of building (Land with Building schedule)",
        "flat_number": "Flat / Door number (Apartment schedule)",
        "floor_number": "Floor number (Apartment schedule)",
        "uds_area": "Undivided Share of Land (UDS) area (Apartment schedule)",
        "apartment_uds_floor": "Flat No, Floor, Built-Up Area, and UDS (if apartment)",
        "boundary": "Four boundaries (North, South, East, West)",
        "boundary_north": "North boundary description",
        "boundary_south": "South boundary description",
        "boundary_east": "East boundary description",
        "boundary_west": "West boundary description",
        "land_classification": "Classification of land (Wet/Dry/House Site/Nanjai/Punjai)",
        "sro_details": "Sub-Registrar Office, Document Number, Year & Book",
        "document_number": "Document number and year",
        "book_number": "Registration Book number",
        "registration_date": "Date of Registration",
        "consideration_amount": "Total Sale Consideration Amount in Rs.",
        "witnesses": "Names of witnesses who signed the deed",
        "registrar_endorsement": "Registrar's endorsement / office seal text if present",
        "nri_passport_visa_details": "Passport & visa details if either party is an NRI",
        "poa_details": "Registered Power of Attorney details if signed on behalf of the owner"
    },
    "parent_docs": {
        "previous_owner_vendor": "Prior Vendor / Previous Owner",
        "purchaser_claimant": "Claimant / Purchaser in prior deed",
        "parent_doc_number_year": "Parent Deed Document No & Year, SRO",
        "survey_number": "Survey Number & Sub-division",
        "extent_transferred": "Extent of land transferred in parent deed",
        "chain_of_title_trace": "5-Year Title continuity validation status"
    },
    "ec": {
        "sro_office": "Sub-Registrar Office searched",
        "village": "Revenue Village",
        "taluk": "Taluk",
        "district": "District",
        "survey_searched": "Survey Number(s) searched",
        "search_period": "Search Period / Date window",
        "form_type": "Form 15 (Transactions Found) vs Form 16 (Nil Encumbrance)",
        "mortgage_status": "Open / Unreleased Mortgages vs Closed Mortgages",
        "court_attachments": "Court attachments / Decrees status",
        "encumbrance_status": "Overall Encumbrance Summary"
    },
    "building_plan": {
        "permit_number_date": "Planning Permit No and Sanction Date",
        "sanctioning_authority": "Sanctioning Authority (CMDA / DTCP / Corporation)",
        "survey_no_plot_village": "Survey Number, Plot No, and Village",
        "approved_built_up_area": "Approved Built-Up Area / Plinth Area",
        "height_floors": "Building Height and Number of Floors sanctioned",
        "fsi_setbacks": "FSI and Setback compliance details"
    },
    "rera": {
        "rera_registration_number": "TNRERA Project Registration Number",
        "project_name_type": "Project Name and Category",
        "promoter_developer": "Promoter / Developer Name",
        "survey_numbers_location": "Project Survey Numbers and Location",
        "validity_completion_date": "Registration Validity & Project Completion Expiry"
    },
    "tax_eb": {
        "property_tax_assessment_no": "Property Tax Assessment Number",
        "owner_name": "Recorded Property Owner Name",
        "door_number_locality": "Door Number, Street, Locality",
        "water_tax_status": "Water Tax Consumer No and Payment Status",
        "eb_consumer_number": "EB (TANGEDCO) Consumer Number and Tariff",
        "receipt_amount_date": "Latest Receipt Date and Paid Amount"
    },
    "layout_approval": {
        "layout_approval_number": "Approved Layout Number (PPD/LO No)",
        "sanctioning_authority": "Sanctioning Authority (CMDA / DTCP / LPA)",
        "survey_numbers_village": "Survey Numbers and Revenue Village",
        "total_extent_plots": "Total Layout Extent and Number of Approved Plots",
        "osr_park_road_gift": "Open Space Reservation (OSR) and Road gift deed status"
    },
    "death_legal_heir": {
        "deceased_name": "Deceased Person Full Name",
        "date_of_death": "Date and Place of Death, Death Certificate Reg No",
        "varisu_order_number_date": "Legal Heir / Varisu Certificate Order No and Date",
        "surviving_heirs_list": "List of all Surviving Legal Heirs with age and relationship",
        "heir_completeness_check": "100% Legal Heir Completeness Check",
        "patta_mutation_status": "Revenue Patta Mutation Status (Mandatory Hard Gate)"
    },
    "loan_docs": {
        "lending_bank_institution": "Lending Bank / Financial Institution Name",
        "borrower_names": "Borrower and Co-Borrower Names",
        "loan_sanctioned_amount": "Loan Account Number and Sanctioned Loan Amount",
        "modt_doc_number_year_sro": "MODT Registration Doc No, Year, and SRO",
        "noc_discharge_status": "Bank NOC / Mortgage Discharge Receipt Status"
    },
    "tslr": {
        "district": "District / மாவட்டம்",
        "taluk": "Taluk / வட்டம்",
        "town_village": "Town / Village / நகரம் / கிராமம்",
        "ward": "Ward / வார்டு",
        "owner_name": "Registered Owner Name / உரிமையாளர் பெயர்",
        "survey_number": "Town Survey Number (T.S. No) / நகர நில அளவை எண்",
        "old_survey_number": "Old Survey Number / பழைய புல எண்",
        "extent": "Extent in Sq.Ft / Hectare-Are-Sq.m / பரப்பு",
        "ward_block": "Ward + Block / வார்டு + பிளாக்",
        "land_classification": "Land Classification (Ryotwari / Government / Poramboke)",
        "current_land_use": "Current Land Use (Residential / Commercial / Vacant)",
        "tenure_type": "Tenure Type",
        "assessment": "Assessment (Rs.) / தீர்வை",
        "remarks": "Remarks / குறிப்பு"
    }
}


class QwenDocumentExtractor:
    """Async client for local Qwen2.5-7B running on llama.cpp server."""

    def __init__(self, base_url: str = LLM_BASE_URL, timeout: float = 75.0):
        self.base_url = base_url.rstrip("/")
        self.timeout = timeout

    async def is_available(self) -> bool:
        """Check if local llama-server or Gemini API is active and reachable."""
        if os.environ.get("GEMINI_API_KEY"):
            return True
        try:
            async with httpx.AsyncClient(timeout=2.0) as client:
                res = await client.get(f"{self.base_url}/models")
                return res.status_code == 200
        except Exception:
            return False

    def filter_relevant_pages(self, pages: List[Dict[str, Any]], doc_type: str, max_pages: int = 6) -> List[Dict[str, Any]]:
        """
        Filters and ranks relevant pages using domain keyword scoring.
        Solves token bloat and context degradation for 40-page ECs and multi-page deeds.
        """
        if not pages or len(pages) <= max_pages:
            return pages

        kws = RELEVANT_KEYWORDS.get(doc_type, [])
        scored_pages = []

        for p in pages:
            text_lower = (p.get("text") or p.get("full_text") or "").lower()
            score = sum(1 for kw in kws if kw.lower() in text_lower)
            scored_pages.append((score, p))

        # Always include page 1 (header/meta) and top scoring pages
        scored_pages.sort(key=lambda x: x[0], reverse=True)
        selected = [scored_pages[0][1]] if scored_pages else []
        for _, p in scored_pages:
            if p not in selected and len(selected) < max_pages:
                selected.append(p)

        # Sort back into natural page sequence
        selected.sort(key=lambda x: x.get("page_number", 0))
        return selected

    def prune_ocr_context(self, ocr_text: str, doc_type: str, max_chars: int = 2200) -> str:
        """
        Prunes raw OCR text down to key information-dense paragraphs to prevent
        CPU prompt evaluation bloat and guarantee rapid <1.5s prompt ingestion.
        """
        if not ocr_text or len(ocr_text) <= max_chars:
            return ocr_text

        lines = [l.strip() for l in ocr_text.splitlines() if l.strip()]
        selected_lines = []
        selected_len = 0

        # Always include the first 25 lines (document headers, dates, parties, locations)
        for l in lines[:25]:
            selected_lines.append(l)
            selected_len += len(l) + 1

        # Scan subsequent lines for key numbers, schedules, tables, boundaries
        kws = RELEVANT_KEYWORDS.get(doc_type, [])
        for l in lines[25:]:
            if selected_len >= max_chars:
                break
            l_low = l.lower()
            if any(kw in l_low for kw in kws) or re.search(r'\b\d+[-/]\w+\b', l) or re.search(r'\b\d{3,}\b', l):
                selected_lines.append(l)
                selected_len += len(l) + 1

        return "\n".join(selected_lines)[:max_chars]

    def _rehydrate_flat_json(self, raw_data: Dict[str, Any], schema_dict: Dict[str, Any]) -> Dict[str, Any]:
        """Convert flat key-value pairs into full entity schema expected by backend & frontend."""
        rehydrated = {}
        for k in schema_dict.keys():
            val = raw_data.get(k)
            # Support common model alias keys (e.g. owner_names vs owner_name, survey_numbers vs survey_number)
            if val is None:
                for alt_k in [f"{k}s", k.rstrip("s"), f"{k}_details", f"{k}_name", f"{k}_no", f"{k}_number"]:
                    if alt_k in raw_data and raw_data[alt_k] is not None:
                        val = raw_data[alt_k]
                        break

            if isinstance(val, list):
                val = ", ".join(str(item) for item in val)

            if val is not None and str(val).strip().lower() not in ["null", "none", "not detected", "-", ""]:
                val_str = str(val).strip()
                rehydrated[k] = {
                    "value": val_str,
                    "source_text": val_str,
                    "confidence": 0.96,
                    "needs_review": False
                }
            else:
                rehydrated[k] = {
                    "value": None,
                    "source_text": "",
                    "confidence": 0.0,
                    "needs_review": False
                }
        return rehydrated

    async def _try_gemini_flash(self, doc_type: str, ocr_text: str, schema_dict: Dict[str, Any]) -> Optional[Dict[str, Any]]:
        """Optional cloud acceleration: extracts with Gemini Flash in ~1.2s if GEMINI_API_KEY is configured."""
        gemini_key = os.environ.get("GEMINI_API_KEY")
        if not gemini_key:
            return None
        try:
            url = f"https://generativelanguage.googleapis.com/v1beta/models/gemini-2.5-flash:generateContent?key={gemini_key}"
            prompt = f"Extract structured fields from this Tamil Nadu {doc_type} document strictly as flat JSON with keys: {list(schema_dict.keys())}.\n\nOCR TEXT:\n{ocr_text[:4000]}"
            body = {
                "contents": [{"parts": [{"text": prompt}]}],
                "generationConfig": {"responseMimeType": "application/json"}
            }
            async with httpx.AsyncClient(timeout=10.0) as client:
                res = await client.post(url, json=body)
                if res.status_code == 200:
                    text_out = res.json()["candidates"][0]["content"]["parts"][0]["text"]
                    return json.loads(text_out)
        except Exception as e:
            logger.debug(f"Gemini cloud acceleration failed: {e}. Falling back to local model.")
        return None

    async def extract_document_fields(
        self,
        doc_type: str,
        ocr_text: str,
        page_num: int = 1,
        target_fields: Optional[Any] = None
    ) -> Dict[str, Any]:
        """
        Calls local Qwen 2.5-7B (or Gemini Flash if available) with pruned context
        and flat JSON schema for rapid, highly accurate extraction.
        """
        schema_dict = target_fields or DEFAULT_TARGET_FIELDS_BY_DOC_TYPE.get(doc_type) or {
            "survey_number": "Survey Number & Sub-division",
            "extent": "Extent of land",
            "vendor_details": "Vendor details",
            "purchaser_details": "Purchaser details",
            "village": "Village",
            "taluk": "Taluk",
            "district": "District",
            "sro_office": "SRO Office",
            "consideration_amount": "Consideration Amount"
        }

        # 1. Try Gemini Flash if configured (ultra-fast 1.2s execution)
        gemini_res = await self._try_gemini_flash(doc_type, ocr_text, schema_dict)
        if gemini_res and isinstance(gemini_res, dict):
            logger.info("Successfully extracted document fields using Gemini Flash.")
            return self._rehydrate_flat_json(gemini_res, schema_dict)

        # 2. Local Qwen 2.5-7B inference with pruned context (<1.5s prompt eval + rapid generation)
        pruned_text = self.prune_ocr_context(ocr_text, doc_type)

        user_prompt = f"""Document Type: {doc_type}
Page Number: {page_num}

TARGET FIELDS TO EXTRACT (Return flat JSON mapping each key to its extracted string or null):
{json.dumps(schema_dict, indent=2, ensure_ascii=False)}

SOURCE OCR TEXT:
\"\"\"
{pruned_text}
\"\"\"

Output flat JSON:"""

        # Scale the output budget to the schema size — a fixed 220-token cap was tuned for
        # ~10-field schemas and truncates mid-JSON (causing parse failures) once a doc type's
        # schema grows past that, as happened when sale_deed expanded to 30+ fields.
        max_tokens = min(2000, max(220, len(schema_dict) * 40))

        payload = {
            "model": "qwen2.5-7b",
            "messages": [
                {"role": "system", "content": SYSTEM_PROMPT_TEMPLATE},
                {"role": "user", "content": user_prompt}
            ],
            "temperature": 0.0,
            "max_tokens": max_tokens,
            "response_format": {"type": "json_object"}
        }

        try:
            async with httpx.AsyncClient(timeout=self.timeout) as client:
                resp = await client.post(f"{self.base_url}/chat/completions", json=payload)
                if resp.status_code == 200:
                    data = resp.json()
                    raw_content = data["choices"][0]["message"]["content"].strip()
                    if raw_content.startswith("```json"):
                        raw_content = raw_content[7:]
                    if raw_content.startswith("```"):
                        raw_content = raw_content[3:]
                    if raw_content.endswith("```"):
                        raw_content = raw_content[:-3]
                    parsed = json.loads(raw_content.strip())
                    return self._rehydrate_flat_json(parsed, schema_dict)
        except Exception as e:
            logger.warning(f"Qwen local LLM inference failed: {e}. Falling back to rule-based engine.")
            return {}

        return {}
