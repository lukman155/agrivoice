from typing import Optional, Any
import logging
from app.config import settings

logger = logging.getLogger(__name__)

try:
    import torch
    HAVE_TORCH = True
except ImportError:
    HAVE_TORCH = False

try:
    import librosa
    HAVE_LIBROSA = True
except ImportError:
    HAVE_LIBROSA = False

try:
    from transformers import pipeline
    HAVE_TRANSFORMERS = True
except ImportError:
    HAVE_TRANSFORMERS = False

class ASRTranscriber:
    def __init__(self):
        self.device = "cuda" if HAVE_TORCH and torch.cuda.is_available() else "cpu"
        self.models = {}
        
        if not (HAVE_TORCH and HAVE_TRANSFORMERS):
            logger.info("Torch/Transformers not installed locally. ASR running in sovereign simulation mode.")
            self.models = None
            return
        
        logger.info(f"Loading ASR models on {self.device}...")
        try:
            # We lazy load or load all 4 depending on memory constraints.
            # For hackathon requirement, we load all 4.
            self.models["ha"] = pipeline(
                "automatic-speech-recognition", 
                model=settings.asr_hausa, 
                token=settings.hf_token, 
                device=0 if self.device == "cuda" else -1
            )
            self.models["yo"] = pipeline(
                "automatic-speech-recognition", 
                model=settings.asr_yoruba, 
                token=settings.hf_token, 
                device=0 if self.device == "cuda" else -1
            )
            self.models["ig"] = pipeline(
                "automatic-speech-recognition", 
                model=settings.asr_igbo, 
                token=settings.hf_token, 
                device=0 if self.device == "cuda" else -1
            )
            self.models["en"] = pipeline(
                "automatic-speech-recognition", 
                model=settings.asr_english, 
                token=settings.hf_token, 
                device=0 if self.device == "cuda" else -1
            )
        except Exception as e:
            logger.error(f"Error loading ASR models: {e}")
            logger.warning("Falling back to a mock transcriber for local testing without HF token.")
            self.models = None

    def transcribe(self, audio_data: Any, sampling_rate: int = 16000) -> dict:
        if self.models is None:
            # Fallback for testing without HF access
            return {"text": "Wannan gwaji ne.", "language": "ha", "confidence": 0.99}

        if sampling_rate != 16000:
            audio_data = librosa.resample(audio_data, orig_sr=sampling_rate, target_sr=16000)
            
        best_transcript = ""
        best_lang = "en"
        # Since standard whisper returns confidence in some pipeline setups but not all by default,
        # we do a simple heuristic if we can't extract logits: try all and pick the longest reasonable string,
        # or rely on an external language detector first. For this project, we'll run all and pick the longest output
        # (a proxy for confidence in whisper fine-tunes) or random if all fail.
        
        results = {}
        for lang, asr_pipe in self.models.items():
            try:
                out = asr_pipe({"sampling_rate": 16000, "raw": audio_data})
                text = out["text"].strip()
                results[lang] = text
            except Exception as e:
                logger.error(f"ASR error for {lang}: {e}")
                results[lang] = ""

        # Dummy confidence heuristic: longest non-empty string is often the native one for whisper fine-tunes
        best_lang = max(results.items(), key=lambda x: len(x[1]))[0]
        best_transcript = results[best_lang]

        return {
            "text": best_transcript,
            "language": best_lang,
            "confidence": 0.85
        }
