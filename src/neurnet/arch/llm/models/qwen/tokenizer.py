import re
from collections.abc import Sequence
from pathlib import Path
from typing import cast

from neurnet.arch.llm import traits


class Qwen3Tokenizer(traits.Tokenizer):
    _SPECIALS: tuple[str, ...] = (
        "<|endoftext|>",
        "<|im_start|>",
        "<|im_end|>",
        "<|object_ref_start|>",
        "<|object_ref_end|>",
        "<|box_start|>",
        "<|box_end|>",
        "<|quad_start|>",
        "<|quad_end|>",
        "<|vision_start|>",
        "<|vision_end|>",
        "<|vision_pad|>",
        "<|image_pad|>",
        "<|video_pad|>",
    )
    _SPLIT_RE: re.Pattern[str] = re.compile(r"(<\|[^>]+?\|>)")

    def __init__(
        self,
        tokenizer_file_path: str | Path = "tokenizer-base.json",
        apply_chat_template: bool = False,
        add_generation_prompt: bool = False,
        add_thinking: bool = False,
    ) -> None:
        from tokenizers import Tokenizer

        self.apply_chat_template = apply_chat_template
        self.add_generation_prompt = add_generation_prompt
        self.add_thinking = add_thinking

        tok_path = Path(tokenizer_file_path)
        if not tok_path.is_file():
            raise FileNotFoundError(
                f"Tokenizer file '{tok_path}' not found. Please ensure it's available."
            )

        self._tok: Tokenizer = Tokenizer.from_file(str(tok_path))
        self._special_to_id: dict[str, int | None] = {
            t: self._tok.token_to_id(t) for t in self._SPECIALS
        }

        self.pad_token = "<|endoftext|>"
        self.pad_token_id = self._special_to_id.get(self.pad_token)

        # Match HF behavior: chat model → <|im_end|>, base model → <|endoftext|>
        fname = tok_path.name.lower()
        if "base" in fname and "reasoning" not in fname:
            self.eos_token = "<|endoftext|>"
        else:
            self.eos_token = "<|im_end|>"
        self.eos_token_id = self._special_to_id.get(self.eos_token)

    def encode(self, text: str) -> Sequence[int]:
        # , chat_wrapped: bool | None = None
        # if chat_wrapped is None:
        #     chat_wrapped = self.apply_chat_template

        stripped = text.strip()
        if stripped in self._special_to_id and "\n" not in stripped:
            return [cast(int, self._special_to_id[stripped])]

        # if chat_wrapped:
        #     prompt = self._wrap_chat(prompt)

        ids: list[int] = []
        for part in filter(None, self._SPLIT_RE.split(text)):
            if part in self._special_to_id:
                ids.append(cast(int, self._special_to_id[part]))
            else:
                ids.extend(self._tok.encode(part).ids)
        return ids

    def decode(self, ids: Sequence[int]) -> str:
        return self._tok.decode(ids, skip_special_tokens=False)

    def _wrap_chat(self, user_msg: str) -> str:
        s = f"<|im_start|>user\n{user_msg}<|im_end|>\n"
        if self.add_generation_prompt:
            s += "<|im_start|>assistant"
            if self.add_thinking:
                s += "\n"  # insert no <think> tag, just a new line
            else:
                s += "\n<think>\n\n</think>\n\n"
        return s
