import os
import re
import string
import logging
import torch
from typing import List, Dict, Optional, Any

logger = logging.getLogger("ttv.preprocessor")


class TextPreprocessor:
    """
    Standardized Text Preprocessor and Tokenizer for Text-to-Video models.
    Provides:
    - Text prompt cleaning & normalization
    - High-capacity tokenization with support for real pretrained tokenizers (MiniLM/BERT)
    - Full sequence preservation without truncating prompt elements
    - Length padding to configurable max_length (default 128)
    - Vectorized PyTorch tensor generation
    - Detailed token inspection diagnostics
    """
    def __init__(self, max_length: int = 128, vocab_size: int = 30522):
        self.max_length = max_length
        self.vocab_size = vocab_size
        self.pad_token_id = 0
        self.unk_token_id = 1
        self.bos_token_id = 2  # [CLS]
        self.eos_token_id = 3  # [SEP]
        
        # Attempt to load local cached tokenizer if available
        self._hf_tokenizer = None
        self._init_tokenizer()

    def _init_tokenizer(self):
        try:
            from transformers import AutoTokenizer
            # Try offline local load of all-MiniLM-L6-v2
            self._hf_tokenizer = AutoTokenizer.from_pretrained(
                "sentence-transformers/all-MiniLM-L6-v2",
                local_files_only=True
            )
            self.vocab_size = self._hf_tokenizer.vocab_size
            self.pad_token_id = self._hf_tokenizer.pad_token_id or 0
            self.unk_token_id = self._hf_tokenizer.unk_token_id or 1
            self.bos_token_id = getattr(self._hf_tokenizer, "cls_token_id", 101)
            self.eos_token_id = getattr(self._hf_tokenizer, "sep_token_id", 102)
        except Exception:
            self._hf_tokenizer = None

    def clean_text(self, text: str) -> str:
        """Sanitizes and normalizes prompt string."""
        if not text:
            return ""
        # Lowercase
        t = text.lower().strip()
        # Replace newlines/tabs with space
        t = re.sub(r"[\r\n\t]+", " ", t)
        # Collapse multiple whitespace
        t = re.sub(r"\s+", " ", t)
        return t

    def tokenize(self, text: str) -> List[str]:
        """Splits prompt into normalized word tokens."""
        clean = self.clean_text(text)
        if self._hf_tokenizer is not None:
            return self._hf_tokenizer.tokenize(clean)
        # Remove punctuation except hyphens in words
        tokens = re.findall(r"\b[\w'-]+\b", clean)
        return tokens

    def _hash_token(self, token: str) -> int:
        """Hashes token into deterministic vocabulary index [4, vocab_size - 1]."""
        h = 0
        for char in token:
            h = (h * 31 + ord(char)) % (self.vocab_size - 4)
        return h + 4

    def tokenize_to_ids(self, text: str) -> List[int]:
        """Converts prompt text to integer token IDs with BOS and EOS tokens."""
        clean = self.clean_text(text)
        if self._hf_tokenizer is not None:
            encoded = self._hf_tokenizer(
                clean,
                max_length=self.max_length,
                padding="max_length",
                truncation=True,
                return_tensors=None
            )
            return encoded["input_ids"]

        words = self.tokenize(clean)
        ids = [self.bos_token_id]
        for w in words[:self.max_length - 2]:
            ids.append(self._hash_token(w))
        ids.append(self.eos_token_id)

        # Pad to max_length
        while len(ids) < self.max_length:
            ids.append(self.pad_token_id)

        return ids[:self.max_length]

    def encode(self, text: str) -> List[int]:
        """Convenience alias for tokenize_to_ids."""
        return self.tokenize_to_ids(text)

    def tokenize_to_tensor(self, text: str) -> torch.Tensor:
        """Converts prompt directly to a 1D PyTorch LongTensor of length max_length."""
        ids = self.tokenize_to_ids(text)
        return torch.tensor(ids, dtype=torch.long)

    def diagnose_prompt(self, prompt: str) -> Dict[str, Any]:
        """Diagnostic check for whether key prompt elements are preserved."""
        clean = self.clean_text(prompt)
        raw_words = clean.split()
        tokens = self.tokenize(prompt)
        ids = self.tokenize_to_ids(prompt)
        non_pad_count = sum(1 for i in ids if i != self.pad_token_id)

        # Check key terms
        key_terms = ["farmer", "walking", "green field", "sunrise", "crops", "tool", "birds", "car", "dog"]
        term_status = {}
        for term in key_terms:
            in_clean = term in clean
            term_status[term] = {
                "in_prompt": in_clean,
                "retained_in_tokens": in_clean and (non_pad_count >= len(raw_words) or any(t in term for t in tokens))
            }

        return {
            "original_prompt": prompt,
            "cleaned_prompt": clean,
            "raw_word_count": len(raw_words),
            "tokens_count": len(tokens),
            "max_length": self.max_length,
            "non_pad_tokens": non_pad_count,
            "is_truncated": len(raw_words) > (self.max_length - 2),
            "term_retention": term_status,
            "tokenizer_type": "HuggingFace_MiniLM" if self._hf_tokenizer else "Deterministic_Hasher"
        }
