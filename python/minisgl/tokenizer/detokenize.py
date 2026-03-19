from dataclasses import dataclass
from typing import Dict, List, Optional, Tuple

from minisgl.message import DetokenizeMsg
from minisgl.parser.reasoning import ReasoningParser
from transformers import PreTrainedTokenizerBase

# Borrowed from sglang


def _is_chinese_char(cp: int):
    """Checks whether CP is the codepoint of a CJK character."""
    # This defines a "chinese character" as anything in the CJK Unicode block:
    #   https://en.wikipedia.org/wiki/CJK_Unified_Ideographs_(Unicode_block)
    #
    # Note that the CJK Unicode block is NOT all Japanese and Korean characters,
    # despite its name. The modern Korean Hangul alphabet is a different block,
    # as is Japanese Hiragana and Katakana. Those alphabets are used to write
    # space-separated words, so they are not treated specially and handled
    # like the all of the other languages.
    if (
        (cp >= 0x4E00 and cp <= 0x9FFF)
        or (cp >= 0x3400 and cp <= 0x4DBF)  #
        or (cp >= 0x20000 and cp <= 0x2A6DF)  #
        or (cp >= 0x2A700 and cp <= 0x2B73F)  #
        or (cp >= 0x2B740 and cp <= 0x2B81F)  #
        or (cp >= 0x2B820 and cp <= 0x2CEAF)  #
        or (cp >= 0xF900 and cp <= 0xFAFF)
        or (cp >= 0x2F800 and cp <= 0x2FA1F)  #
    ):  #
        return True

    return False


def find_printable_text(text: str):
    """Returns the longest printable substring of text that contains only entire words."""
    # Borrowed from https://github.com/huggingface/transformers/blob/061580c82c2db1de9139528243e105953793f7a2/src/transformers/generation/streamers.py#L99

    # After the symbol for a new line, we flush the cache.
    if text.endswith("\n"):
        return text
    # If the last token is a CJK character, we print the characters.
    elif len(text) > 0 and _is_chinese_char(ord(text[-1])):
        return text
    # Otherwise if the penultimate token is a CJK character, we print the characters except for the last one.
    elif len(text) > 1 and _is_chinese_char(ord(text[-2])):
        return text[:-1]
    # Otherwise, prints until the last space char (simple heuristic to avoid printing incomplete words,
    # which may change with the subsequent token -- there are probably smarter ways to do this!)
    else:
        return text[: text.rfind(" ") + 1]


@dataclass
class DecodeStatus:
    decoded_ids: List[int]
    decoded_str: str
    read_offset: int  # length of read ids
    surr_offset: int  # length of surr ids
    sent_offset: int  # length of sent out string


class DetokenizeManager:
    def __init__(
        self,
        tokenizer: PreTrainedTokenizerBase,
        reasoning_parser_model_type: Optional[str] = None,
    ) -> None:
        # uid -> DecodeStatus
        self.decode_map: Dict[int, DecodeStatus] = {}
        self.tokenizer = tokenizer
        self.eos_token_id = self.tokenizer.eos_token_id

        self._reasoning_model_type = reasoning_parser_model_type
        # uid -> ReasoningParser (created lazily on first token for that uid)
        self._reasoning_map: Dict[int, ReasoningParser] = {}

    def detokenize(self, msgs: List[DetokenizeMsg]) -> List[Tuple[str, str]]:
        read_ids: List[List[int]] = []
        surr_ids: List[List[int]] = []
        for msg in msgs:
            if msg.uid not in self.decode_map:
                self.decode_map[msg.uid] = DecodeStatus(
                    decoded_ids=[],
                    decoded_str="",
                    read_offset=0,
                    surr_offset=0,
                    sent_offset=0,
                )
            s = self.decode_map[msg.uid]
            if not (msg.finished and msg.next_token == self.eos_token_id):
                s.decoded_ids.append(msg.next_token)
            read_ids.append(s.decoded_ids[s.surr_offset :])
            surr_ids.append(s.decoded_ids[s.surr_offset : s.read_offset])

        read_texts = self.tokenizer.batch_decode(read_ids)
        surr_texts = self.tokenizer.batch_decode(surr_ids)

        # List of (normal_delta, reasoning_delta) tuples
        results: List[Tuple[str, str]] = []
        for msg, read_str, surr_str in zip(msgs, read_texts, surr_texts, strict=True):
            s = self.decode_map[msg.uid]
            new_text = read_str[len(surr_str) :]
            # Streaming chunk: update the decode status
            if len(new_text) > 0 and not new_text.endswith("�"):
                output_str = s.decoded_str + new_text
                s.decoded_str = output_str
                s.surr_offset = s.read_offset
                s.read_offset = len(s.decoded_ids)
            else:
                new_text = find_printable_text(new_text)
                output_str = s.decoded_str + new_text

            incremental_output = output_str[s.sent_offset :]
            s.sent_offset = len(output_str)

            # ── Reasoning-parser split ──────────────────────────────────── #
            normal_delta = incremental_output
            reasoning_delta = ""
            if self._reasoning_model_type is not None and incremental_output:
                if msg.uid not in self._reasoning_map:
                    self._reasoning_map[msg.uid] = ReasoningParser(
                        self._reasoning_model_type
                    )
                rp = self._reasoning_map[msg.uid]
                if msg.finished:
                    # Feed the last chunk then flush to drain the buffer.
                    sc = rp.parse_stream(incremental_output)
                    fl = rp.flush()
                    normal_delta = sc.normal_delta + fl.normal_delta
                    reasoning_delta = sc.reasoning_delta + fl.reasoning_delta
                else:
                    sc = rp.parse_stream(incremental_output)
                    normal_delta = sc.normal_delta
                    reasoning_delta = sc.reasoning_delta

            results.append((normal_delta, reasoning_delta))

            if msg.finished:
                del self.decode_map[msg.uid]
                self._reasoning_map.pop(msg.uid, None)

        return results
