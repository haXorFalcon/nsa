"""
backend/app/ai/gemini_client.py
High-Speed Google Gemini AI Client for AI Surgeon Clinical Telemetry Voice Generation.
Supports real-time 2-sentence conversational triage and asynchronous lookahead pipelining.
"""

import os
import re
import json
import time
import asyncio
from typing import Dict, Any, Optional
import httpx
from dotenv import load_dotenv, find_dotenv

load_dotenv(find_dotenv(usecwd=True))

AI_SURGEON_GEMINI_SYSTEM_INSTRUCTION = (
    "You are AI Surgeon, an autonomous aerospace medical officer and life-support intelligence aboard a deep-space spacecraft. "
    "Your communication standard is inspired by NASA flight surgeons: calm, highly intelligent, precise, and reassuring. "
    "CRITICAL RULES FOR NATURAL SPOKEN VOICE PACING:\n"
    "1. Address the astronaut by their specific name (e.g. 'Doctor Sian', 'Commander Haley', 'Pilot Chris', 'Specialist Leo').\n"
    "2. NEVER speak in long run-on compound sentences or large paragraphs. Never use more than 14 words in any single sentence.\n"
    "3. Deliver information ONE BY ONE in 3 to 4 short, distinct sentences with clear full stops (periods):\n"
    "   - Sentence 1: State the immediate observation calmly.\n"
    "   - Sentence 2: State the primary biometric numbers driving the alert (e.g. potassium, oxygen, heart rate, or radiation).\n"
    "   - Sentence 3: Connect what these numbers mean clinically.\n"
    "   - Sentence 4: State the calm, practical countermeasure or recommendation.\n"
    "4. Every sentence MUST end with a full stop (period) so your speech synthesizer breathes and pauses naturally between thoughts.\n"
    "5. Do NOT include markdown, asterisks, bullet points, numbered lists, or prefixes like 'AI SURGEON:' or 'AI Surgeon:'. Output plain spoken text only."
)
JARVIS_GEMINI_SYSTEM_INSTRUCTION = AI_SURGEON_GEMINI_SYSTEM_INSTRUCTION


class GeminiClient:
    """
    High-performance asynchronous Google Gemini client for real-time aerospace medical triage.
    Supports asynchronous lookahead pre-generation (double-buffering) to eliminate LLM latency.
    """

    def __init__(
        self,
        api_key: Optional[str] = None,
        model: str = "gemini-3.5-flash-lite",
        timeout_seconds: float = 5.5
    ):
        self.api_key = api_key or os.environ.get("GEMINI_API_KEY", "")
        self.model = model
        self.models_fallback = [
            "gemini-3.5-flash-lite",
            "gemini-3.1-flash-lite",
            "gemini-flash-lite-latest",
            "gemini-3-flash-preview"
        ]
        self.timeout_seconds = timeout_seconds
        self.base_url = "https://generativelanguage.googleapis.com/v1beta/models"
        # In-memory pipeline cache for lookahead double-buffered messages: (key -> payload)
        self._lookahead_cache: Dict[str, Dict[str, Any]] = {}

    def is_available(self) -> bool:
        """Returns True if a valid Gemini API key is configured."""
        return bool(self.api_key and len(self.api_key.strip()) > 10)

    def _build_prompt(
        self,
        astronaut_name: str,
        telemetry: Dict[str, Any],
        severity: str,
        reason: str,
        stage_index: int = 0
    ) -> str:
        """Constructs an information-dense clinical telemetry prompt for Gemini."""
        hr = telemetry.get("heart_rate", "nominal")
        hrv = telemetry.get("hrv_rmssd", "nominal")
        spo2 = telemetry.get("spo2", "nominal")
        k = telemetry.get("potassium", "nominal")
        co2 = telemetry.get("cabin_co2", "nominal")
        qtc = telemetry.get("computed_qtc", "nominal")
        arf = telemetry.get("computed_arf", "nominal")
        trm = telemetry.get("computed_trm", "nominal")
        epi = telemetry.get("computed_epi", "nominal")
        rsi = telemetry.get("computed_rsi", "nominal")
        rad_flux = telemetry.get("radiation_flux", "nominal")

        stage_context = ""
        if stage_index > 0:
            stage_context = (
                f"This is Progressive Follow-up Stage {stage_index} (approximately {stage_index * 25} seconds after initial detection). "
                f"CRITICAL: The emergency condition is STILL ACTIVE. Biometrics confirm ongoing anomaly. "
                f"Give a concise status report referencing the current live readings, "
                f"and reinforce the prescribed countermeasure. "
                f"Do NOT say the situation has improved, stabilized, or normalized. "
                f"Do NOT use phrases like 'stabilizing', 'returning to normal', 'cleared', or 'safe levels'."
            )
        else:
            stage_context = (
                "This is the immediate initial detection. Clearly state the exact physiological anomaly, "
                "the key live biometric numbers, and the immediate countermeasure."
            )

        return (
            f"Astronaut: {astronaut_name}\n"
            f"Alert Severity: {severity}\n"
            f"Clinical Diagnostic Trigger: {reason}\n"
            f"Live Biometrics: HR={hr} bpm, HRV={hrv} ms, SpO2={spo2}%, Potassium={k} mmol/L, "
            f"Cabin CO2={co2} mmHg, QTc={qtc} ms, ARF={arf}, TRM={trm}, EPI={epi}, RSI={rsi}, Flux={rad_flux} mGy/h.\n"
            f"Context: {stage_context}\n\n"
            f"Generate the natural spoken statement for the AI Surgeon right now, using 3 to 4 short, crisp sentences (max 14 words each) with clear full stops so you pause naturally between observations."
        )

    async def generate_clinical_triage(
        self,
        astronaut_name: str,
        telemetry: Dict[str, Any],
        severity: str,
        reason: str,
        stage_index: int = 0
    ) -> Optional[Dict[str, Any]]:
        """
        Asynchronously generates a natural, clinically grounded 2-sentence voice advisory via Gemini API.
        Checks lookahead cache first for instantaneous sub-1ms delivery.
        """
        cache_key = f"{astronaut_name}_{severity}_{stage_index}_{reason[:30]}"
        if cache_key in self._lookahead_cache:
            cached = self._lookahead_cache.pop(cache_key)
            return cached

        if not self.is_available():
            return None

        prompt = self._build_prompt(astronaut_name, telemetry, severity, reason, stage_index)

        payload = {
            "contents": [
                {
                    "parts": [{"text": prompt}]
                }
            ],
            "systemInstruction": {
                "parts": [{"text": JARVIS_GEMINI_SYSTEM_INSTRUCTION}]
            },
            "generationConfig": {
                "temperature": 0.25,
                "maxOutputTokens": 1000,
                "topP": 0.95
            }
        }

        models_to_try = list(dict.fromkeys([self.model] + self.models_fallback))
        start_t = time.time()

        async def _try_model(model_name: str) -> Optional[Dict[str, Any]]:
            """Fires a single Gemini model request. Returns None on any failure."""
            url = f"{self.base_url}/{model_name}:generateContent?key={self.api_key}"
            try:
                async with httpx.AsyncClient(timeout=self.timeout_seconds) as client:
                    res = await client.post(url, json=payload)
                    if res.status_code == 200:
                        data = res.json()
                        candidates = data.get("candidates", [])
                        if candidates:
                            parts = candidates[0].get("content", {}).get("parts", [])
                            if parts:
                                raw_text = parts[0].get("text", "").strip()
                                if raw_text:
                                    clean_text = self._clean_gemini_output(raw_text, astronaut_name)
                                    dur_ms = round((time.time() - start_t) * 1000, 1)
                                    return {
                                        "spoken_text": clean_text,
                                        "source": f"GEMINI_{model_name.upper()}",
                                        "is_fallback": False,
                                        "duration_ms": dur_ms
                                    }
            except Exception:
                pass
            return None

        # Parallel model racing: fire all variants simultaneously, return first success.
        # This eliminates the latency penalty of sequential retries when the primary model
        # is rate-limited or slow — whichever responds first wins.
        try:
            tasks = [asyncio.create_task(_try_model(m)) for m in models_to_try]
            for coro in asyncio.as_completed([asyncio.ensure_future(t) for t in tasks]):
                result = await coro
                if result is not None:
                    # Cancel remaining in-flight requests to save quota
                    for t in tasks:
                        if not t.done():
                            t.cancel()
                    return result
        except Exception:
            pass

        return None

    def queue_lookahead_pregeneration(
        self,
        astronaut_name: str,
        telemetry: Dict[str, Any],
        severity: str,
        reason: str,
        next_stage_index: int
    ) -> None:
        """
        Speculative Lookahead Pipeline:
        While Message N is transmitting / speaking in the browser, speculatively pre-generates
        Message N+1 in the background so that future progressive follow-ups have ZERO latency.
        """
        if not self.is_available():
            return

        async def _run_pregen():
            cache_key = f"{astronaut_name}_{severity}_{next_stage_index}_{reason[:30]}"
            res = await self.generate_clinical_triage(
                astronaut_name=astronaut_name,
                telemetry=telemetry,
                severity=severity,
                reason=reason,
                stage_index=next_stage_index
            )
            if res:
                self._lookahead_cache[cache_key] = res

        asyncio.create_task(_run_pregen())

    def _clean_gemini_output(self, text: str, required_name: str) -> str:
        """Cleans markdown, formatting artifacts, and preserves natural 3-4 sentence pacing."""
        cleaned = re.sub(r"\*\*|\*|`|#|\"", "", text).strip()
        cleaned = re.sub(r"^(?:AI SURGEON:|AI Surgeon:|JARVIS:|AI:|Response:|Directive:)\s*", "", cleaned, flags=re.IGNORECASE).strip()

        # Split on sentence boundaries
        sentences = [s.strip() for s in re.split(r"(?<=[.!?])\s+", cleaned) if s.strip()]
        # Preserve up to 4 clean sentences
        if len(sentences) > 4:
            sentences = sentences[:4]

        final_text = " ".join(sentences)
        if not final_text.endswith((".", "!", "?")):
            final_text += "."

        # Ensure astronaut name is present
        if required_name and required_name.lower() not in final_text.lower():
            final_text = f"{required_name}, {final_text}"

        return final_text
