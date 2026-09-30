"""
SansKrypt Translation Module
Translates ancient Sanskrit Devanagari text into accurate, natural English using:
1. High-precision Google Gemini AI (reading GEMINI_API_KEY / GOOGLE_API_KEY)
2. Sanskrit Neural Translator (source='sa')
3. Local Seq2Seq Hugging Face Transformer models (offline CPU fallback)
"""
import os
import re
import unicodedata
import logging
from typing import Optional

try:
    from deep_translator import GoogleTranslator
    HAS_DEEP_TRANSLATOR = True
except ImportError:
    HAS_DEEP_TRANSLATOR = False

try:
    from google import genai
    HAS_GENAI = True
except ImportError:
    HAS_GENAI = False

try:
    from config import TRANSLATION_MODEL_NAME, GEMINI_API_KEY
except ImportError:
    TRANSLATION_MODEL_NAME = "google/flan-t5-small"
    GEMINI_API_KEY = os.getenv("GEMINI_API_KEY", "")

logger = logging.getLogger(__name__)

LOCAL_MODEL_DIR = os.path.join(os.path.dirname(os.path.abspath(__file__)), "models", "sanskrypt_translator")


class TranslationPipeline:
    """
    Singleton class managing local fallback Seq2Seq transformer models.
    """
    _instance: Optional["TranslationPipeline"] = None

    def __init__(self, model_name: str = TRANSLATION_MODEL_NAME):
        if os.path.exists(LOCAL_MODEL_DIR) and os.path.isfile(os.path.join(LOCAL_MODEL_DIR, "config.json")):
            self.model_name = LOCAL_MODEL_DIR
            logger.info(f"Using locally trained fine-tuned model from: {LOCAL_MODEL_DIR}")
        else:
            self.model_name = model_name

        self.tokenizer = None
        self.model = None
        self._is_loaded = False

    @classmethod
    def get_instance(cls, model_name: str = TRANSLATION_MODEL_NAME) -> "TranslationPipeline":
        if cls._instance is None:
            cls._instance = cls(model_name=model_name)
        return cls._instance

    def load_model(self):
        """Loads the tokenizer and model into CPU memory."""
        if not self._is_loaded:
            import torch
            from transformers import AutoTokenizer, AutoModelForSeq2SeqLM

            logger.info(f"Loading translation model: {self.model_name} onto CPU...")
            try:
                self.tokenizer = AutoTokenizer.from_pretrained(self.model_name)
                self.model = AutoModelForSeq2SeqLM.from_pretrained(
                    self.model_name,
                    torch_dtype=torch.float32
                )
                self.model.eval()
                self._is_loaded = True
                logger.info("Translation model loaded successfully.")
            except Exception as e:
                logger.error(f"Failed to load translation model '{self.model_name}': {str(e)}", exc_info=True)
                raise RuntimeError(f"Translation model loading failed: {str(e)}")

    def translate_with_transformer(self, text: str, max_length: int = 512) -> str:
        """Translates text using the transformer model."""
        import torch

        self.load_model()
        clean_text = text.strip()
        prompt = f"translate Sanskrit to English: {clean_text}"

        inputs = self.tokenizer(
            prompt,
            return_tensors="pt",
            truncation=True,
            max_length=512
        )

        with torch.no_grad():
            outputs = self.model.generate(
                **inputs,
                max_length=max_length,
                num_beams=4,
                early_stopping=True,
                no_repeat_ngram_size=2
            )

        translated_text = self.tokenizer.decode(outputs[0], skip_special_tokens=True).strip()
        return translated_text


def clean_sanskrit_for_translation(text: str) -> str:
    """Prepares Sanskrit text for translation by standardizing punctuation and removing noise."""
    if not text:
        return ""
    cleaned = unicodedata.normalize("NFC", text)
    cleaned = re.sub(r"[\u200b-\u200f\ufeff\u00a0\u2028\u2029]", "", cleaned)
    cleaned = re.sub(r"[\%‰\$\#\*\~`\^\{\}\[\]\<\>\(\)]+", " ", cleaned)
    cleaned = re.sub(r"\b\d+\b", "", cleaned)
    cleaned = re.sub(r"[\|\!]{2,}", " ॥ ", cleaned)
    cleaned = re.sub(r"[\|\!]", " । ", cleaned)
    cleaned = re.sub(r"[ \t]+", " ", cleaned).strip()
    return cleaned


def translate_with_gemini(sanskrit_text: str) -> Optional[str]:
    """
    Translates Sanskrit text to English using Gemini API if API key is provided.
    """
    api_key = os.getenv("GEMINI_API_KEY") or os.getenv("GOOGLE_API_KEY") or GEMINI_API_KEY
    if not api_key or not HAS_GENAI:
        return None

    candidate_models = [
        "gemini-flash-lite-latest",
        "gemini-flash-latest",
        "gemini-3.1-flash-lite",
        "gemini-3.8-flash",
        "gemini-2.5-pro"
    ]
    try:
        client = genai.Client(api_key=api_key)
        prompt = (
            "You are an expert scholar in ancient Sanskrit literature, Vedic texts, and classical Indian philosophy. "
            "Translate the following ancient Sanskrit manuscript passage accurately, elegantly, and fluently into English. "
            "Contextually resolve any ancient Sandhi combinations, archaisms, and minor OCR transcription discrepancies to produce the true, faithful English meaning. "
            "Provide ONLY the direct English translation without preambles, introductory commentary, or transliteration:\n\n"
            f"{sanskrit_text}"
        )
        for model_name in candidate_models:
            try:
                response = client.models.generate_content(
                    model=model_name,
                    contents=prompt
                )
                if response and response.text:
                    cleaned = response.text.strip()
                    cleaned = re.sub(r"^(Translation:|\*\*Translation:\*\*|English:)\s*", "", cleaned, flags=re.IGNORECASE)
                    logger.info(f"Generated high-accuracy translation via Gemini API ({model_name}).")
                    return cleaned.strip()
            except Exception as model_err:
                logger.debug(f"Model {model_name} translation failed: {model_err}")
                continue
    except Exception as e:
        logger.warning(f"Gemini API translation error: {str(e)}")
    return None


def translate_text(sanskrit_text: str) -> str:
    """
    Translates Sanskrit text into accurate, natural English.
    Tier 1: Google Gemini API (if key available)
    Tier 2: Google Sanskrit Neural Translator (deep_translator, source='sa')
    Tier 3: Local Seq2Seq Transformer Model

    Args:
        sanskrit_text: Sanskrit text in Devanagari script.

    Returns:
        str: English translation.
    """
    if not sanskrit_text or not sanskrit_text.strip():
        return "No text available for translation."

    clean_full_text = clean_sanskrit_for_translation(sanskrit_text)
    if not clean_full_text:
        return "No valid Sanskrit text found for translation."

    # Tier 1: Gemini API
    gemini_result = translate_with_gemini(clean_full_text)
    if gemini_result:
        return gemini_result

    # Tier 2: Google Sanskrit Neural Translator
    if HAS_DEEP_TRANSLATOR:
        try:
            translator = GoogleTranslator(source="sa", target="en")
            raw_trans = translator.translate(clean_full_text)
            if raw_trans and not "Error 500" in raw_trans and not "Server Error" in raw_trans:
                clean_res = raw_trans.strip()
                logger.info(f"Google Sanskrit translation successful ({len(clean_res)} chars).")
                return clean_res
        except Exception as e:
            logger.warning(f"Block Google Sanskrit translation retry line-by-line: {str(e)}")

        # Line-by-line fallback
        try:
            lines = [l.strip() for l in clean_full_text.split("\n") if l.strip()]
            translated_lines = []
            translator = GoogleTranslator(source="sa", target="en")
            
            for line in lines:
                clean_line = re.sub(r"[॥।]", "", line).strip()
                if not clean_line:
                    continue
                try:
                    res = translator.translate(clean_line)
                    if res and not "Error 500" in res and not "Server Error" in res:
                        translated_lines.append(res.strip().rstrip("."))
                    else:
                        auto_trans = GoogleTranslator(source="auto", target="en").translate(clean_line)
                        if auto_trans and not "Error 500" in auto_trans:
                            translated_lines.append(auto_trans.strip().rstrip("."))
                except Exception as line_err:
                    logger.warning(f"Line translation failed: {str(line_err)}")
            
            if translated_lines:
                result = ". ".join(translated_lines) + "."
                result = re.sub(r"\.\s*\.", ".", result)
                return result
        except Exception as e:
            logger.warning(f"Google Translator fallback to local model: {str(e)}")

    # Tier 3: Local Transformer Fallback
    try:
        pipeline = TranslationPipeline.get_instance()
        transformer_result = pipeline.translate_with_transformer(clean_full_text)
        if transformer_result and len(transformer_result) > 3 and transformer_result != "-":
            return transformer_result
    except Exception as e:
        logger.error(f"Local transformer translation failed: {str(e)}")

    return f"Translation of passage: {clean_full_text}"
