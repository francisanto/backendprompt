"""
PromptShield AI — Local Tokenizer Adapters.
==========================================
Provides local, offline token counting adapters for supported foundation models:
1. OpenAI / GPT: Uses official `tiktoken` (MIT) with o200k_base or cl100k_base. (Exact count)
2. Google / Gemini: Calibrated local SentencePiece estimation matching Gemini 256k vocab. (Estimated count)
3. Anthropic / Claude: Calibrated local estimation matching Claude BPE distribution. (Estimated count)

Strictly distinguishes exact measurements from estimates and never claims cross-provider equivalency.
Explicitly discloses that raw prompt tokenization does not represent final API billing due to system
prompts, tool definitions, chat formatting wrappers, and provider caching policies.
"""

from abc import ABC, abstractmethod
from dataclasses import dataclass
import re
from typing import Optional


BILLING_DISCLAIMER = (
    "Raw text token count for prompt text only. Production API billing will vary based on "
    "system instructions, tool declarations, message framing overhead, and provider-specific "
    "caching or tier discounts."
)


@dataclass
class TokenCountResult:
    token_count: int
    tokenizer_name: str
    token_count_method: str  # "exact", "approximate", "unsupported"
    token_count_confidence: float  # e.g., 1.0 for exact, 0.90 for approximate, 0.50 for unsupported
    token_count_disclaimer: str = BILLING_DISCLAIMER
    method: str = ""  # Backward compatibility alias
    is_exact: bool = True  # Backward compatibility alias
    notes: Optional[str] = None
    billing_disclaimer: str = BILLING_DISCLAIMER  # Backward compatibility alias

    def __post_init__(self):
        if not self.method:
            self.method = "exact" if self.token_count_method == "exact" else ("approximate" if self.token_count_method == "approximate" else "unsupported")
        if self.token_count_method == "exact":
            self.is_exact = True
        else:
            self.is_exact = False
        if not self.token_count_disclaimer:
            self.token_count_disclaimer = BILLING_DISCLAIMER
        self.billing_disclaimer = self.token_count_disclaimer


class BaseTokenizerAdapter(ABC):
    """Abstract base class for model tokenizer adapters."""

    def __init__(self, model_id: str, tokenizer_name: str):
        self.model_id = model_id
        self.tokenizer_name = tokenizer_name

    @abstractmethod
    def count_tokens(self, text: str) -> TokenCountResult:
        """Counts or estimates tokens for input text."""
        pass


class OpenAITokenizerAdapter(BaseTokenizerAdapter):
    """
    Offline tokenizer adapter for OpenAI GPT models using official tiktoken.
    Provides 100% exact local token counts for plain text and code without network calls.
    """

    def __init__(self, model_id: str, encoding_name: str = "o200k_base"):
        super().__init__(model_id=model_id, tokenizer_name=encoding_name)
        self.encoding_name = encoding_name
        self._encoding = None

    def _get_encoding(self):
        if self._encoding is None:
            import tiktoken
            try:
                self._encoding = tiktoken.get_encoding(self.encoding_name)
            except Exception:
                self._encoding = tiktoken.get_encoding("cl100k_base")
        return self._encoding

    def count_tokens(self, text: str) -> TokenCountResult:
        if not text or not text.strip():
            return TokenCountResult(
                token_count=0,
                tokenizer_name=self.tokenizer_name,
                token_count_method="exact",
                token_count_confidence=1.0,
                token_count_disclaimer=BILLING_DISCLAIMER,
                method="exact",
                is_exact=True,
                notes="Zero tokens for empty or whitespace-only input."
            )

        try:
            encoding = self._get_encoding()
            # Allow all special tokens in raw input string without throwing errors
            tokens = encoding.encode(text, disallowed_special=())
            count = len(tokens)
            return TokenCountResult(
                token_count=count,
                tokenizer_name=self.tokenizer_name,
                token_count_method="exact",
                token_count_confidence=1.0,
                token_count_disclaimer=BILLING_DISCLAIMER,
                method="exact",
                is_exact=True,
                notes=f"Exact local BPE token count using tiktoken ({self.encoding_name})."
            )
        except Exception as e:
            # Fallback estimation if tiktoken fails
            chars = len(text)
            est = max(1, int(chars / 4.0))
            return TokenCountResult(
                token_count=est,
                tokenizer_name=self.tokenizer_name,
                token_count_method="approximate",
                token_count_confidence=0.75,
                token_count_disclaimer=f"Fallback estimation due to local encoding error: {e}. " + BILLING_DISCLAIMER,
                method="approximate",
                is_exact=False,
                notes=f"Fallback character-ratio estimation due to local encoding error: {e}"
            )


class GeminiTokenizerAdapter(BaseTokenizerAdapter):
    """
    Local token counting adapter for Google Gemini models.
    Google's official `count_tokens` requires an active API key and remote network call.
    This adapter provides a calibrated local estimation matching Gemini's 256k SentencePiece BPE vocabulary
    and explicitly flags results as 'approximate'.
    """

    def __init__(self, model_id: str):
        super().__init__(model_id=model_id, tokenizer_name="gemini_256k_bpe_calibrated")

    def count_tokens(self, text: str) -> TokenCountResult:
        disclaimer = (
            "Approximate token count calibrated to Gemini 256k SentencePiece BPE vocabulary. "
            "Google does not provide a standalone offline tokenizer package; official exact counts require remote API. "
            + BILLING_DISCLAIMER
        )
        if not text or not text.strip():
            return TokenCountResult(
                token_count=0,
                tokenizer_name=self.tokenizer_name,
                token_count_method="approximate",
                token_count_confidence=0.90,
                token_count_disclaimer=disclaimer,
                method="approximate",
                is_exact=False,
                notes="Zero tokens for empty or whitespace-only input."
            )

        # Calibrated heuristic against Gemini 256k SentencePiece vocab:
        # Code segments average ~3.4-3.7 chars/token; English prose averages ~4.0-4.3 chars/token.
        is_code = bool(re.search(r"```|def |class |function|import |<[a-z]+>|SELECT |WHERE |[{};]", text))
        char_ratio = 3.60 if is_code else 4.15

        char_len = len(text)
        word_len = len(text.split())

        char_est = char_len / char_ratio
        word_est = word_len * (1.25 if is_code else 1.30)
        est = max(1, int(round((char_est * 0.70) + (word_est * 0.30))))

        return TokenCountResult(
            token_count=est,
            tokenizer_name=self.tokenizer_name,
            token_count_method="approximate",
            token_count_confidence=0.90,
            token_count_disclaimer=disclaimer,
            method="approximate",
            is_exact=False,
            notes=(
                "Estimated using calibrated Gemini 256k SentencePiece heuristic. "
                "Google provides no local offline tokenizer package; official exact counts require live API."
            )
        )


class ClaudeTokenizerAdapter(BaseTokenizerAdapter):
    """
    Local token counting adapter for Anthropic Claude models.
    Anthropic does not release an open-source offline tokenizer package; exact token counting
    is only available via remote server API.
    This adapter provides a calibrated local estimation and explicitly flags results as 'approximate'.
    """

    def __init__(self, model_id: str):
        super().__init__(model_id=model_id, tokenizer_name="claude_calibrated_heuristic")

    def count_tokens(self, text: str) -> TokenCountResult:
        disclaimer = (
            "Approximate token count calibrated to Claude BPE distribution. "
            "Anthropic does not publish an open-source offline tokenizer package; official exact counts require remote API. "
            + BILLING_DISCLAIMER
        )
        if not text or not text.strip():
            return TokenCountResult(
                token_count=0,
                tokenizer_name=self.tokenizer_name,
                token_count_method="approximate",
                token_count_confidence=0.90,
                token_count_disclaimer=disclaimer,
                method="approximate",
                is_exact=False,
                notes="Zero tokens for empty or whitespace-only input."
            )

        # Calibrated heuristic for Claude token distribution:
        is_code = bool(re.search(r"```|def |class |function|import |<[a-z]+>|SELECT |WHERE |[{};]", text))
        char_ratio = 3.50 if is_code else 3.95

        char_len = len(text)
        word_len = len(text.split())

        char_est = char_len / char_ratio
        word_est = word_len * (1.28 if is_code else 1.32)
        est = max(1, int(round((char_est * 0.65) + (word_est * 0.35))))

        return TokenCountResult(
            token_count=est,
            tokenizer_name=self.tokenizer_name,
            token_count_method="approximate",
            token_count_confidence=0.90,
            token_count_disclaimer=disclaimer,
            method="approximate",
            is_exact=False,
            notes=(
                "Estimated using calibrated Claude heuristic. "
                "Anthropic does not publish an open-source offline tokenizer package."
            )
        )


class GrokTokenizerAdapter(BaseTokenizerAdapter):
    """
    Local token counting adapter for xAI Grok models.
    xAI does not publish an open-source offline tokenizer package; exact token counting
    is only available via remote API.
    This adapter provides a calibrated local estimation and explicitly flags results as 'approximate'.
    """

    def __init__(self, model_id: str):
        super().__init__(model_id=model_id, tokenizer_name="grok_calibrated_heuristic")

    def count_tokens(self, text: str) -> TokenCountResult:
        disclaimer = (
            "Approximate token count calibrated to xAI Grok SentencePiece distribution. "
            "xAI does not publish an open-source offline tokenizer package; official exact counts require remote API. "
            + BILLING_DISCLAIMER
        )
        if not text or not text.strip():
            return TokenCountResult(
                token_count=0,
                tokenizer_name=self.tokenizer_name,
                token_count_method="approximate",
                token_count_confidence=0.90,
                token_count_disclaimer=disclaimer,
                method="approximate",
                is_exact=False,
                notes="Zero tokens for empty or whitespace-only input."
            )

        # Calibrated heuristic for Grok SentencePiece token distribution:
        is_code = bool(re.search(r"```|def |class |function|import |<[a-z]+>|SELECT |WHERE |[{};]", text))
        char_ratio = 3.55 if is_code else 4.05

        char_len = len(text)
        word_len = len(text.split())

        char_est = char_len / char_ratio
        word_est = word_len * (1.26 if is_code else 1.30)
        est = max(1, int(round((char_est * 0.70) + (word_est * 0.30))))

        return TokenCountResult(
            token_count=est,
            tokenizer_name=self.tokenizer_name,
            token_count_method="approximate",
            token_count_confidence=0.90,
            token_count_disclaimer=disclaimer,
            method="approximate",
            is_exact=False,
            notes=(
                "Estimated using calibrated xAI Grok SentencePiece heuristic. "
                "xAI does not publish an open-source offline tokenizer package."
            )
        )


class DeepSeekTokenizerAdapter(BaseTokenizerAdapter):
    """
    Local token counting adapter for DeepSeek models.
    DeepSeek uses a byte-level BPE tokenizer (100k+ vocabulary).
    This adapter provides a calibrated local estimation and explicitly flags results as 'approximate'.
    """

    def __init__(self, model_id: str):
        super().__init__(model_id=model_id, tokenizer_name="deepseek_calibrated_heuristic")

    def count_tokens(self, text: str) -> TokenCountResult:
        disclaimer = (
            "Approximate token count calibrated to DeepSeek byte-level BPE distribution. "
            "Exact counts require remote API or local model weights download. "
            + BILLING_DISCLAIMER
        )
        if not text or not text.strip():
            return TokenCountResult(
                token_count=0,
                tokenizer_name=self.tokenizer_name,
                token_count_method="approximate",
                token_count_confidence=0.90,
                token_count_disclaimer=disclaimer,
                method="approximate",
                is_exact=False,
                notes="Zero tokens for empty or whitespace-only input."
            )

        is_code = bool(re.search(r"```|def |class |function|import |<[a-z]+>|SELECT |WHERE |[{};]", text))
        char_ratio = 3.45 if is_code else 3.85

        char_len = len(text)
        word_len = len(text.split())

        char_est = char_len / char_ratio
        word_est = word_len * (1.25 if is_code else 1.28)
        est = max(1, int(round((char_est * 0.70) + (word_est * 0.30))))

        return TokenCountResult(
            token_count=est,
            tokenizer_name=self.tokenizer_name,
            token_count_method="approximate",
            token_count_confidence=0.90,
            token_count_disclaimer=disclaimer,
            method="approximate",
            is_exact=False,
            notes="Estimated using calibrated DeepSeek BPE heuristic."
        )


class UnsupportedTokenizerAdapter(BaseTokenizerAdapter):
    """
    Fallback adapter for unknown or unsupported model architectures.
    Explicitly declares that tokens could not be counted or estimated reliably.
    """

    def __init__(self, model_id: str):
        super().__init__(model_id=model_id, tokenizer_name="unsupported")

    def count_tokens(self, text: str) -> TokenCountResult:
        chars = len(text) if text else 0
        est = max(0, int(chars / 4.0)) if chars > 0 else 0
        disclaimer = (
            f"Unsupported model architecture '{self.model_id}': token count is an uncalibrated heuristic character estimate. "
            + BILLING_DISCLAIMER
        )
        return TokenCountResult(
            token_count=est,
            tokenizer_name=self.tokenizer_name,
            token_count_method="unsupported",
            token_count_confidence=0.50,
            token_count_disclaimer=disclaimer,
            method="unsupported",
            is_exact=False,
            notes=f"Model architecture '{self.model_id}' lacks a dedicated tokenizer adapter; character heuristic used."
        )


def get_tokenizer_adapter(model_id: str) -> BaseTokenizerAdapter:
    """
    Factory resolving the appropriate tokenizer adapter for a model ID.
    """
    low = model_id.lower()
    if "gpt" in low or "o1" in low or "o3" in low:
        # Modern frontier GPT and reasoning models use o200k_base; legacy GPT-3.5/GPT-4 use cl100k_base
        encoding = "o200k_base" if ("4o" in low or "o1" in low or "o3" in low) else "cl100k_base"
        return OpenAITokenizerAdapter(model_id=model_id, encoding_name=encoding)
    elif "gemini" in low:
        return GeminiTokenizerAdapter(model_id=model_id)
    elif "claude" in low:
        return ClaudeTokenizerAdapter(model_id=model_id)
    elif "grok" in low:
        return GrokTokenizerAdapter(model_id=model_id)
    elif "deepseek" in low:
        return DeepSeekTokenizerAdapter(model_id=model_id)
    else:
        return UnsupportedTokenizerAdapter(model_id=model_id)
