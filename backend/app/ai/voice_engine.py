"""
backend/app/ai/voice_engine.py
JARVIS-style Voice Warning Engine and hands-free spoken response synthesizer.
Packages aerospace-grade audio warning payloads with priority tones, Web Speech API instructions,
and synchronized frequency tokens for HUD canvas visualizers.
"""

import time
import math
import uuid
import re
import asyncio
from typing import AsyncGenerator, Dict, Any, List, Optional

from .decision_engine import DecisionEngine
from .ollama_client import OllamaClient
from .gemini_client import GeminiClient
from .fallback_templates import get_fallback_script, get_progressive_script


class VoiceEngine:
    """
    Synthesizes JARVIS voice alerts, manages alarm cooldowns (anti-chatter filter),
    and resolves hands-free crew voice interactions.
    """

    TONE_MAPPINGS = {
        "CRITICAL": "klaxon",
        "WARNING": "chime",
        "INFO": "beep",
        "NOMINAL": "none"
    }

    AUDIO_PROFILES = {
        "CRITICAL": {"rate": 1.00, "pitch": 1.00, "volume": 1.0, "voice": "en-GB"},
        "WARNING": {"rate": 1.00, "pitch": 1.00, "volume": 0.98, "voice": "en-GB"},
        "INFO": {"rate": 1.00, "pitch": 1.00, "volume": 0.90, "voice": "en-GB"},
        "NOMINAL": {"rate": 1.00, "pitch": 0.98, "volume": 0.85, "voice": "en-GB"}
    }

    def __init__(
        self,
        ollama_client: Optional[OllamaClient] = None,
        gemini_client: Optional[GeminiClient] = None,
        cooldown_seconds: float = 30.0
    ):
        self.ollama = ollama_client or OllamaClient()
        self.gemini = gemini_client or GeminiClient()
        self.cooldown_seconds = cooldown_seconds
        # astronaut_id -> {"timestamp": float, "severity": str, "count": int}
        self._last_alert_state: Dict[str, Dict[str, Any]] = {}

    def should_suppress_alert(self, astronaut_id: str, severity: str, is_progressive: bool = False) -> bool:
        """
        Anti-chatter filter preventing alert fatigue.
        Allows immediate override if severity escalates (e.g. WARNING -> CRITICAL)
        or if this is a progressive follow-up recommendation stage.
        Also suppresses individual alerts if a vessel-wide ALL_CREW alert is active.
        """
        if is_progressive:
            return False

        now = time.time()

        # If a vessel-wide ALL_CREW alert is active within cooldown window, suppress individual alerts
        if astronaut_id != "ALL_CREW":
            all_crew_state = self._last_alert_state.get("ALL_CREW")
            if all_crew_state:
                time_since_all = now - all_crew_state["timestamp"]
                if time_since_all < self.cooldown_seconds:
                    if all_crew_state["severity"] == "CRITICAL" or severity == all_crew_state["severity"]:
                        return True

        last_state = self._last_alert_state.get(astronaut_id)
        if not last_state:
            return False

        # Severity escalation always bypasses cooldown
        if severity == "CRITICAL" and last_state["severity"] != "CRITICAL":
            return False

        # If within cooldown window and same or lower severity, suppress
        time_elapsed = now - last_state["timestamp"]
        if time_elapsed < self.cooldown_seconds and severity == last_state["severity"]:
            return True

        return False

    def reset_suppression_cooldowns(self) -> None:
        """Clears all suppression timers and cooldowns, e.g. on scenario change or manual reset."""
        self._last_alert_state.clear()

    def record_alert_dispatched(self, astronaut_id: str, severity: str) -> None:
        """Updates internal alarm chatter tracking."""
        self._last_alert_state[astronaut_id] = {
            "timestamp": time.time(),
            "severity": severity,
            "count": self._last_alert_state.get(astronaut_id, {}).get("count", 0) + 1
        }

    @staticmethod
    def generate_visualizer_tokens(text: str) -> List[Dict[str, Any]]:
        """
        Generates simulated 5-band frequency energies for each word token
        to drive the HUD 5-bar canvas waveform visualizer in lockstep with speech.
        """
        words = text.split()
        tokens = []
        for i, word in enumerate(words):
            # Compute pseudo-spectral frequency weights using phoneme hash
            seed = sum(ord(c) for c in word) + i
            band_sub = round(0.4 + 0.6 * math.sin(seed * 0.1) ** 2, 2)
            band_bass = round(0.5 + 0.5 * math.cos(seed * 0.2) ** 2, 2)
            band_mid = round(0.6 + 0.4 * math.sin(seed * 0.3) ** 2, 2)
            band_highmid = round(0.3 + 0.7 * math.cos(seed * 0.4) ** 2, 2)
            band_treble = round(0.2 + 0.8 * math.sin(seed * 0.5) ** 2, 2)

            tokens.append({
                "word": word,
                "bands": [band_sub, band_bass, band_mid, band_highmid, band_treble]
            })
        return tokens

    async def create_voice_warning(
        self,
        astronaut_id: str,
        astronaut_name: str,
        telemetry: Dict[str, Any],
        severity: str,
        reason: str,
        scenario_phase: Optional[str] = None,
        stage_index: int = 0
    ) -> Dict[str, Any]:
        """
        Constructs the complete JARVIS Voice Warning payload.
        Consults Ollama with sub-1500ms fallback, or delivers progressive follow-up script.
        """
        triage_res = None

        # Priority 1: High-Speed Gemini API (if configured / available)
        if self.gemini.is_available():
            triage_res = await self.gemini.generate_clinical_triage(
                astronaut_name=astronaut_name,
                telemetry=telemetry,
                severity=severity,
                reason=reason,
                stage_index=stage_index
            )

        # Priority 2: Local Ollama AI or Deterministic Clinical Reason Engine
        if not triage_res:
            if stage_index > 0:
                speech_raw = get_progressive_script(
                    scenario_key=scenario_phase or reason,
                    severity=severity,
                    astronaut_name=astronaut_name,
                    astronaut_id=astronaut_id,
                    stage_index=stage_index,
                    reason=reason,
                    telemetry=telemetry
                )
                triage_res = {
                    "spoken_text": speech_raw,
                    "source": f"progressive_sentry_stage_{stage_index}",
                    "is_fallback": True,
                    "duration_ms": 0.5
                }
            else:
                triage_res = await self.ollama.generate_clinical_triage(
                    astronaut_name=astronaut_name,
                    telemetry=telemetry,
                    severity=severity,
                    reason=reason,
                    scenario_phase=scenario_phase
                )

        speech_text = self.phonetically_normalize_for_tts(triage_res["spoken_text"])

        # Speculative lookahead pipeline: while this message transmits/speaks, pre-generate Stage N+1
        if self.gemini.is_available():
            self.gemini.queue_lookahead_pregeneration(
                astronaut_name=astronaut_name,
                telemetry=telemetry,
                severity=severity,
                reason=reason,
                next_stage_index=stage_index + 1
            )

        # 2. Package tone, audio settings, and visualizer tokens
        tone = self.TONE_MAPPINGS.get(severity, "none")
        audio_profile = self.AUDIO_PROFILES.get(severity, self.AUDIO_PROFILES["NOMINAL"])
        visualizer = self.generate_visualizer_tokens(speech_text)

        payload = {
            "id": f"vw_{int(time.time() * 1000)}_{uuid.uuid4().hex[:6]}",
            "timestamp": telemetry.get("timestamp", time.strftime("%Y-%m-%dT%H:%M:%SZ")),
            "astronaut_id": astronaut_id,
            "astronaut_name": astronaut_name,
            "severity": severity,
            "tone": tone,
            "speech_text": speech_text,
            "source": triage_res["source"],
            "is_fallback": triage_res["is_fallback"],
            "duration_ms": triage_res["duration_ms"],
            "reason": reason,
            "audio_config": audio_profile,
            "visualizer_tokens": visualizer,
            "stage_index": stage_index
        }

        # Update cooldown tracker
        self.record_alert_dispatched(astronaut_id, severity)
        return payload

    async def create_joint_voice_warning(
        self,
        crew_names: str,
        astronaut_ids: List[str],
        telemetry_1: Dict[str, Any],
        telemetry_2: Dict[str, Any],
        severity: str,
        reason: str,
        scenario_phase: Optional[str] = None,
        stage_index: int = 0
    ) -> Dict[str, Any]:
        """
        Synthesizes a single consolidated JARVIS voice warning addressing two crew members naturally by name.
        """
        if stage_index > 0:
            speech_raw = get_progressive_script(
                scenario_key=scenario_phase or reason,
                severity=severity,
                astronaut_name=crew_names,
                astronaut_id="+".join(astronaut_ids),
                stage_index=stage_index
            )
            triage_res = {
                "spoken_text": speech_raw,
                "source": f"progressive_joint_stage_{stage_index}",
                "is_fallback": True,
                "duration_ms": 0.5
            }
        else:
            triage_res = await self.ollama.generate_joint_triage(
                crew_names=crew_names,
                telemetry_1=telemetry_1,
                telemetry_2=telemetry_2,
                severity=severity,
                reason=reason,
                scenario_phase=scenario_phase
            )
        speech_text = self.phonetically_normalize_for_tts(triage_res["spoken_text"])
        tone = self.TONE_MAPPINGS.get(severity, "chime")
        audio_profile = self.AUDIO_PROFILES.get(severity, self.AUDIO_PROFILES["WARNING"])
        visualizer = self.generate_visualizer_tokens(speech_text)

        payload = {
            "id": f"vw_joint_{int(time.time() * 1000)}_{uuid.uuid4().hex[:6]}",
            "timestamp": telemetry_1.get("timestamp", time.strftime("%Y-%m-%dT%H:%M:%SZ")),
            "astronaut_id": "+".join(astronaut_ids),
            "astronaut_name": crew_names,
            "severity": severity,
            "tone": tone,
            "speech_text": speech_text,
            "source": triage_res["source"],
            "is_fallback": triage_res["is_fallback"],
            "duration_ms": triage_res["duration_ms"],
            "reason": reason,
            "audio_config": audio_profile,
            "visualizer_tokens": visualizer,
            "stage_index": stage_index
        }

        for ast_id in astronaut_ids:
            self.record_alert_dispatched(ast_id, severity)
        return payload

    async def create_multi_crew_voice_warning(
        self,
        crew_names: str,
        astronaut_ids: List[str],
        telemetries: List[Dict[str, Any]],
        severity: str,
        reason: str,
        scenario_phase: Optional[str] = None,
        stage_index: int = 0
    ) -> Dict[str, Any]:
        """
        Synthesizes a single consolidated JARVIS voice warning addressing three or more crew members naturally by name.
        """
        if stage_index > 0:
            speech_raw = get_progressive_script(
                scenario_key=scenario_phase or reason,
                severity=severity,
                astronaut_name=crew_names,
                astronaut_id="+".join(astronaut_ids),
                stage_index=stage_index
            )
            triage_res = {
                "spoken_text": speech_raw,
                "source": f"progressive_multi_stage_{stage_index}",
                "is_fallback": True,
                "duration_ms": 0.5
            }
        else:
            triage_res = await self.ollama.generate_multi_crew_triage(
                crew_names=crew_names,
                telemetries=telemetries,
                severity=severity,
                reason=reason,
                scenario_phase=scenario_phase
            )
        speech_text = self.phonetically_normalize_for_tts(triage_res["spoken_text"])
        tone = self.TONE_MAPPINGS.get(severity, "chime")
        audio_profile = self.AUDIO_PROFILES.get(severity, self.AUDIO_PROFILES["WARNING"])
        visualizer = self.generate_visualizer_tokens(speech_text)

        payload = {
            "id": f"vw_multi_{int(time.time() * 1000)}_{uuid.uuid4().hex[:6]}",
            "timestamp": telemetries[0].get("timestamp", time.strftime("%Y-%m-%dT%H:%M:%SZ")) if telemetries else time.strftime("%Y-%m-%dT%H:%M:%SZ"),
            "astronaut_id": "+".join(astronaut_ids),
            "astronaut_name": crew_names,
            "severity": severity,
            "tone": tone,
            "speech_text": speech_text,
            "source": triage_res["source"],
            "is_fallback": triage_res["is_fallback"],
            "duration_ms": triage_res["duration_ms"],
            "reason": reason,
            "audio_config": audio_profile,
            "visualizer_tokens": visualizer,
            "stage_index": stage_index
        }

        for ast_id in astronaut_ids:
            self.record_alert_dispatched(ast_id, severity)
        return payload

    async def create_collective_voice_warning(
        self,
        crew_count: int,
        aggregate_telemetry: Dict[str, Any],
        severity: str,
        reason: str,
        scenario_phase: Optional[str] = None,
        fallback_script_key: str = "ALL_CREW_WARNING",
        stage_index: int = 0
    ) -> Dict[str, Any]:
        """
        Synthesizes a single consolidated JARVIS voice warning for all crew stations.
        """
        if stage_index > 0:
            speech_raw = get_progressive_script(
                scenario_key=scenario_phase or fallback_script_key,
                severity=severity,
                astronaut_name="All Crew Stations",
                astronaut_id="ALL_CREW",
                stage_index=stage_index
            )
            triage_res = {
                "spoken_text": speech_raw,
                "source": f"progressive_collective_stage_{stage_index}",
                "is_fallback": True,
                "duration_ms": 0.5
            }
        else:
            triage_res = await self.ollama.generate_collective_triage(
                crew_count=crew_count,
                aggregate_telemetry=aggregate_telemetry,
                severity=severity,
                reason=reason,
                scenario_phase=scenario_phase,
                fallback_script_key=fallback_script_key
            )
        speech_text = self.phonetically_normalize_for_tts(triage_res["spoken_text"])
        tone = self.TONE_MAPPINGS.get(severity, "klaxon" if severity == "CRITICAL" else "chime")
        audio_profile = self.AUDIO_PROFILES.get(severity, self.AUDIO_PROFILES["WARNING"])
        visualizer = self.generate_visualizer_tokens(speech_text)

        payload = {
            "id": f"vw_collective_{int(time.time() * 1000)}_{uuid.uuid4().hex[:6]}",
            "timestamp": aggregate_telemetry.get("timestamp", time.strftime("%Y-%m-%dT%H:%M:%SZ")),
            "astronaut_id": "ALL_CREW",
            "astronaut_name": "All Crew Stations",
            "severity": severity,
            "tone": tone,
            "speech_text": speech_text,
            "source": triage_res["source"],
            "is_fallback": triage_res["is_fallback"],
            "duration_ms": triage_res["duration_ms"],
            "reason": reason,
            "audio_config": audio_profile,
            "visualizer_tokens": visualizer,
            "stage_index": stage_index
        }

        self.record_alert_dispatched("ALL_CREW", severity)
        return payload

    async def handle_voice_query(
        self,
        query: str,
        astronaut_id: str,
        astronaut_name: str,
        current_telemetry: Dict[str, Any],
        severity: str = "NOMINAL",
        reason: str = "Nominal monitoring"
    ) -> Dict[str, Any]:
        """
        Processes hands-free astronaut voice question and synthesizes a spoken JARVIS answer.
        """
        context = {
            "astronaut_id": astronaut_id,
            "astronaut_name": astronaut_name,
            "severity": severity,
            "reason": reason,
            "telemetry": current_telemetry
        }

        res = await self.ollama.answer_voice_query(query, context)
        speech_text = self.phonetically_normalize_for_tts(res["spoken_text"])
        visualizer = self.generate_visualizer_tokens(speech_text)

        # Pre-warm neural TTS cache immediately for smooth Ryan playback
        asyncio.create_task(
            VoiceEngine.synthesize_neural_speech(
                speech_text,
                severity=severity
            )
        )

        return {
            "query_id": f"vq_{int(time.time() * 1000)}",
            "query": query,
            "astronaut_id": astronaut_id,
            "astronaut_name": astronaut_name,
            "speech_text": speech_text,
            "tone": "chime",
            "source": res["source"],
            "is_fallback": res["is_fallback"],
            "duration_ms": res.get("duration_ms", 0.0),
            "audio_config": self.AUDIO_PROFILES["WARNING"],
            "visualizer_tokens": visualizer
        }

    async def create_greeting_advisory(
        self,
        astronaut_id: str,
        astronaut_name: str,
        telemetry: Dict[str, Any],
        severity: str = "NOMINAL"
    ) -> Dict[str, Any]:
        """
        Lets the local AI model generate a warm greeting and personalized health advisory for an astronaut.
        If severity is elevated, delegates immediately to create_voice_warning to ensure flight life-safety.
        """
        if severity in ("CRITICAL", "WARNING"):
            is_hypoxia = float(telemetry.get("spo2", 100)) < 90 or "hypoxia" in str(telemetry).lower()
            return await self.create_voice_warning(
                astronaut_id=astronaut_id,
                astronaut_name=astronaut_name,
                telemetry=telemetry,
                severity=severity,
                reason="Critical biometric telemetry requiring immediate life-support directive",
                scenario_phase="ALL_CREW_HYPOXIA" if is_hypoxia else None
            )

        res = await self.ollama.generate_greeting_advisory(
            astronaut_name=astronaut_name,
            telemetry=telemetry,
            severity=severity
        )
        speech_text = self.phonetically_normalize_for_tts(res["spoken_text"])
        audio_profile = self.AUDIO_PROFILES.get(severity, self.AUDIO_PROFILES["NOMINAL"])
        visualizer = self.generate_visualizer_tokens(speech_text)

        # Pre-warm neural TTS cache immediately for smooth Ryan playback
        asyncio.create_task(
            VoiceEngine.synthesize_neural_speech(
                speech_text,
                severity=severity
            )
        )

        return {
            "id": f"vw_greet_{int(time.time() * 1000)}_{uuid.uuid4().hex[:6]}",
            "timestamp": telemetry.get("timestamp", time.strftime("%Y-%m-%dT%H:%M:%SZ")),
            "astronaut_id": astronaut_id,
            "astronaut_name": astronaut_name,
            "severity": severity,
            "tone": "chime",
            "speech_text": speech_text,
            "source": res["source"],
            "is_fallback": res["is_fallback"],
            "duration_ms": res.get("duration_ms", 0.0),
            "reason": "Conversational Greeting & Health Advisory",
            "audio_config": audio_profile,
            "visualizer_tokens": visualizer
        }

    DEFAULT_NEURAL_VOICE = "en-GB-RyanNeural"
    _audio_cache: Dict[str, bytes] = {}

    SEVERITY_PROSODY = {
        "CRITICAL": {"rate": "+0%", "pitch": "+0Hz"},  # Crisp, natural human conversational speed
        "WARNING": {"rate": "+0%", "pitch": "+0Hz"},   # Crisp, natural human conversational speed
        "INFO": {"rate": "+1%", "pitch": "+0Hz"},      # Smooth operational pacing
        "NOMINAL": {"rate": "+1%", "pitch": "-1Hz"}    # Relaxed, warm baseline tone
    }

    @staticmethod
    def phonetically_normalize_for_tts(text: str) -> str:
        """
        Expands all flight, medical, and chemical abbreviations into 100% human-pronounceable words
        so that Edge Neural TTS speaks every term with flawless pronunciation.
        """
        if not text:
            return ""
        t = text
        # 1. Names and titles
        t = re.sub(r'\bCmndr\.?\s+', 'Commander ', t, flags=re.IGNORECASE)
        t = re.sub(r'\bCmdr\.?\s+', 'Commander ', t, flags=re.IGNORECASE)
        t = re.sub(r'\bDr\.?\s+', 'Doctor ', t)
        t = re.sub(r'\bSpec\.?\s+', 'Specialist ', t, flags=re.IGNORECASE)

        # 2. Chemical and environmental
        t = re.sub(r'\bCO[2₂]\b', 'carbon dioxide', t, flags=re.IGNORECASE)
        t = re.sub(r'\bcarbon\s+di\s*oxide\b', 'carbon dioxide', t, flags=re.IGNORECASE)
        t = re.sub(r'\bO[2₂]\b', 'oxygen', t, flags=re.IGNORECASE)
        t = re.sub(r'\bN[2₂]\b', 'nitrogen', t, flags=re.IGNORECASE)

        # 3. Biometrics and vitals
        t = re.sub(r'\bSpO[2₂]\b', 'oxygen saturation', t, flags=re.IGNORECASE)
        t = re.sub(r'\bSPO[2₂]\b', 'oxygen saturation', t)
        t = re.sub(r'\bHRV\b', 'heart rate variability', t)
        t = re.sub(r'\bHR\b', 'heart rate', t)
        t = re.sub(r'\b(\d+)\s*bpm\b', r'\1 beats per minute', t, flags=re.IGNORECASE)
        t = re.sub(r'\bbpm\b', 'beats per minute', t, flags=re.IGNORECASE)
        t = re.sub(r'\b(\d+(?:\.\d+)?)\s*mmHg\b', r'\1 millimeters of mercury', t, flags=re.IGNORECASE)
        t = re.sub(r'\bmmHg\b', 'millimeters of mercury', t, flags=re.IGNORECASE)
        t = re.sub(r'\b(\d+)\s*ms\b', r'\1 milliseconds', t)
        t = re.sub(r'\bK\+?\b|\bK⁺\b', 'potassium', t)

        # 4. Biomarkers and clinical intervals
        t = re.sub(r'\bIL-6\b|\bIL6\b', 'interleukin six', t, flags=re.IGNORECASE)
        t = re.sub(r'\bHCT\b', 'hematocrit', t)
        t = re.sub(r'\bWBC\b', 'white blood cells', t)
        t = re.sub(r'\bPLT\b', 'platelets', t)
        t = re.sub(r'\bIJV\b', 'internal jugular vein', t)
        t = re.sub(r'\bARS\b', 'acute radiation syndrome', t)
        t = re.sub(r'\bQTc\b|\bQTC\b', 'Q-T interval', t)
        t = re.sub(r'\bQRS\b', 'Q-R-S complex', t)
        t = re.sub(r'\bPR\s+interval\b', 'P-R interval', t, flags=re.IGNORECASE)
        t = re.sub(r'\bIV\b', 'intravenous', t)
        t = re.sub(r'\bECG\b', 'E-C-G', t)
        t = re.sub(r'°C|deg\s*C', ' degrees Celsius', t, flags=re.IGNORECASE)
        t = re.sub(r'\b(\d+)\s*Gy\b', r'\1 grays', t)
        t = re.sub(r'\b(\d+)\s*mGy\b', r'\1 milligrays', t)
        t = re.sub(r'\b(\d+)\s*mSv\b', r'\1 millisieverts', t)

        # 5. Clean punctuation and symbols
        t = re.sub(r'[*_#`~]', '', t)
        t = re.sub(r'\s+', ' ', t).strip()
        return t

    @classmethod
    async def synthesize_neural_speech(
        cls,
        text: str,
        voice: Optional[str] = None,
        severity: str = "NOMINAL",
        rate: Optional[str] = None,
        pitch: Optional[str] = None
    ) -> Optional[bytes]:
        """
        Synthesizes human-grade, breathing neural audio using Microsoft Edge Neural TTS.
        Differentiates tone, pitch, and speed across NOMINAL, WARNING, and CRITICAL severities:
          - NOMINAL: Warm, relaxed, reassuring conversational cadence (+2% rate, -1Hz pitch)
          - WARNING: Attentive, focused, crisp advisory delivery (+12% rate, +2Hz pitch)
          - CRITICAL: Brisk, urgent, assertive emergency directive (+20% rate, +5Hz pitch)
        Caches synthesized audio for sub-millisecond replay.
        Applies phonetic normalization so every word sounds 100% natural.
        """
        selected_voice = voice or cls.DEFAULT_NEURAL_VOICE
        clean_text = text.strip()
        if not clean_text:
            return None

        prosody = cls.SEVERITY_PROSODY.get((severity or "NOMINAL").upper(), cls.SEVERITY_PROSODY["NOMINAL"])
        target_rate = rate or prosody["rate"]
        target_pitch = pitch or prosody["pitch"]

        # Phonetically normalize to ensure 100% human-natural pronunciation
        spoken_text = cls.phonetically_normalize_for_tts(clean_text)

        cache_key = f"{selected_voice}::{target_rate}::{target_pitch}::{spoken_text}"
        if cache_key in cls._audio_cache:
            return cls._audio_cache[cache_key]

        try:
            import importlib
            edge_tts = importlib.import_module("edge_tts")
            communicate = edge_tts.Communicate(spoken_text, selected_voice, rate=target_rate, pitch=target_pitch)
            audio_data = bytearray()
            async for chunk in communicate.stream():
                if chunk["type"] == "audio":
                    audio_data.extend(chunk["data"])

            res_bytes = bytes(audio_data)
            if res_bytes:
                if len(cls._audio_cache) > 250:
                    cls._audio_cache.pop(next(iter(cls._audio_cache)))
                cls._audio_cache[cache_key] = res_bytes
                return res_bytes
            return None
        except Exception:
            return None

    @classmethod
    async def prewarm_scenario_cache(cls) -> None:
        """
        Pre-synthesizes standard scenario voice messages into memory in the background,
        guaranteeing instant sub-millisecond response times across all crew members and scenarios.
        """
        from .fallback_templates import FALLBACK_VOICE_SCRIPTS

        crew_names = ["Commander Haley", "Pilot Chris", "Doctor Sian", "Specialist Leo"]

        # 1. Prewarm crew-specific greetings and key warnings
        for name in crew_names:
            items = [
                (FALLBACK_VOICE_SCRIPTS.get("NOMINAL_GREETING", "Good day, {name}. All your vitals are calm and steady. I advise keeping up your routine hydration as you begin your watch."), "NOMINAL"),
                (FALLBACK_VOICE_SCRIPTS.get("SCENARIO_1_BASELINE_DRIFT", "{name}, you have been working long hours and your body is getting tired. I advise taking a ten-minute rest and having a cool drink."), "WARNING"),
                (FALLBACK_VOICE_SCRIPTS.get("SCENARIO_3_CO2_HYPOXIA", "Emergency, {name}! Cabin oxygen is dropping fast and carbon dioxide is rising. I advise putting on your oxygen mask and checking your suit seal immediately!"), "CRITICAL"),
                (FALLBACK_VOICE_SCRIPTS.get("SCENARIO_5_PRESYMPTOMATIC_SEPSIS", "{name}, your immune system is working hard to fight off an infection before you feel sick. I advise resting in your quarters and starting an intravenous hydration bag."), "WARNING"),
                (FALLBACK_VOICE_SCRIPTS.get("SCENARIO_6_HYPOKALEMIA_ARRHYTHMIA", "{name}, your potassium levels are running low, which can cause muscle cramps and heart flutter. I advise drinking your potassium electrolyte pouch and resting."), "WARNING"),
                (FALLBACK_VOICE_SCRIPTS.get("SCENARIO_7_VENOUS_THROMBOSIS_RISK", "{name}, blood is moving slowly in your neck veins from weightlessness. I advise putting on your compression cuffs and drinking some water to help circulation."), "WARNING"),
                (FALLBACK_VOICE_SCRIPTS.get("SCENARIO_8_SOLAR_RADIATION_STORM", "Urgent alert, {name}! A solar particle storm is approaching our spacecraft. I advise taking your radiation medication and heading to the storm shelter right now!"), "CRITICAL"),
                (FALLBACK_VOICE_SCRIPTS.get("DEFAULT_NOMINAL", "Good day, {name}. All your vitals are calm and steady. I advise keeping up your routine hydration."), "NOMINAL"),
                (FALLBACK_VOICE_SCRIPTS.get("DEFAULT_WARNING", "{name}, your vitals are beginning to drift out of range. I advise pausing what you are doing, hydrating, and taking a rest."), "WARNING"),
                (FALLBACK_VOICE_SCRIPTS.get("DEFAULT_CRITICAL", "Emergency, {name}! A vital health threshold has been breached. I advise immediate attention and medical protocol!"), "CRITICAL"),
            ]
            for phrase_template, sev in items:
                try:
                    formatted = phrase_template.format(name=name)
                    await cls.synthesize_neural_speech(formatted, severity=sev)
                except Exception:
                    pass

        # 2. Prewarm vessel-wide collective alerts
        all_crew_items = [
            (FALLBACK_VOICE_SCRIPTS.get("ALL_CREW_HYPOXIA", "All stations, emergency alert! Cabin oxygen is dropping fast and carbon dioxide is rising. I advise all crew to put on your oxygen masks and seal your suits immediately!"), "CRITICAL"),
            (FALLBACK_VOICE_SCRIPTS.get("ALL_CREW_SOLAR_STORM", "All stations, severe solar radiation storm incoming! I advise all crew to evacuate immediately into the water-shielded storm shelter!"), "CRITICAL"),
            (FALLBACK_VOICE_SCRIPTS.get("ALL_CREW_WARNING", "All crew stations, please listen. Physical fatigue is rising across the crew quarters. I advise everyone to pause heavy exertion and take a brief rest."), "WARNING"),
            (FALLBACK_VOICE_SCRIPTS.get("ALL_CREW_CRITICAL", "All stations, critical emergency! Environmental safety limits have been breached. I advise immediate emergency containment protocols!"), "CRITICAL"),
        ]
        for text, sev in all_crew_items:
            try:
                await cls.synthesize_neural_speech(text, severity=sev)
            except Exception:
                pass

    @classmethod
    async def stream_neural_speech(
        cls,
        text: str,
        voice: Optional[str] = None,
        severity: str = "NOMINAL",
        rate: Optional[str] = None,
        pitch: Optional[str] = None
    ) -> AsyncGenerator[bytes, None]:
        """
        Streams Microsoft Edge Neural TTS audio as raw MP3 chunks are produced,
        without buffering the full file first. This eliminates the 1–1.5 s stall
        between synthesis start and first byte delivery to the browser.

        - Cache HIT:  yields the full cached bytes in one pass (~0 ms latency).
        - Cache MISS: yields each raw edge_tts audio chunk as it arrives, and
                      stores the complete result in the cache for future instant replay.

        Voice model, prosody, and phonetic normalization are identical to
        synthesize_neural_speech — only the delivery mechanism changes.
        """
        selected_voice = voice or cls.DEFAULT_NEURAL_VOICE
        clean_text = text.strip()
        if not clean_text:
            return

        prosody = cls.SEVERITY_PROSODY.get((severity or "NOMINAL").upper(), cls.SEVERITY_PROSODY["NOMINAL"])
        target_rate = rate or prosody["rate"]
        target_pitch = pitch or prosody["pitch"]

        spoken_text = cls.phonetically_normalize_for_tts(clean_text)
        cache_key = f"{selected_voice}::{target_rate}::{target_pitch}::{spoken_text}"

        # Cache hit — yield instantly and return
        if cache_key in cls._audio_cache:
            yield cls._audio_cache[cache_key]
            return

        # Cache miss — stream chunks from edge_tts and accumulate for caching
        try:
            import importlib
            edge_tts = importlib.import_module("edge_tts")
            communicate = edge_tts.Communicate(spoken_text, selected_voice, rate=target_rate, pitch=target_pitch)
            accumulated = bytearray()
            async for chunk in communicate.stream():
                if chunk["type"] == "audio" and chunk["data"]:
                    data = chunk["data"]
                    accumulated.extend(data)
                    yield data  # ← stream to browser immediately, no buffering

            # Store completed audio in cache for instant future replays
            result = bytes(accumulated)
            if result:
                if len(cls._audio_cache) > 250:
                    cls._audio_cache.pop(next(iter(cls._audio_cache)))
                cls._audio_cache[cache_key] = result
        except Exception:
            return


