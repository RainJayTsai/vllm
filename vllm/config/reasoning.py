# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright contributors to the vLLM project

from dataclasses import field

from vllm.config.model import ModelConfig
from vllm.config.utils import config
from vllm.plugins.thinking_budget_policies import BoundaryRules, get_policy
from vllm.reasoning import ReasoningParserManager
from vllm.tokenizers import cached_tokenizer_from_config


@config
class ReasoningConfig:
    """Configuration for reasoning models.

    Set `reasoning_start_str` and `reasoning_end_str` to the strings used to
    enter and forcibly terminate reasoning. The end string may include a
    transition phrase before the parser's natural reasoning end marker. Token
    IDs are derived automatically by `initialize_token_ids`.
    """

    reasoning_parser: str = ""
    """The name of the ReasoningParser to use for this model."""
    reasoning_start_str: str = ""
    """String that indicates the start of reasoning."""
    reasoning_end_str: str = ""
    """String forced when the thinking budget is exhausted."""
    thinking_budget_policy: str = "default"
    """Boundary policy compiled at initialization: default, qwen, or a plugin."""
    _guard_implicit_end_prefix: bool = field(default=False, init=False, repr=False)
    """Compiled policy option for bounded implicit-marker prefix matching."""
    enable_implicit_reasoning_end: bool = False
    """Honor implicit reasoning-end markers in Model Runner V2
    thinking budgets. Disabled by default to preserve existing behavior."""
    implicit_reasoning_end_strs: list[str] = field(default_factory=list)
    """Additional implicit reasoning-end strings, tokenized with the model's
    tokenizer and merged with parser metadata when the implicit-end guard is
    enabled. Supports single-token and multi-token markers."""

    _implicit_reasoning_end_token_sequences: list[list[int]] = field(
        default_factory=list, init=False, repr=False
    )
    """Tokenized implicit boundaries compiled from parser and policy metadata."""

    _reasoning_start_token_ids: list[int] | None = field(
        default=None, init=False, repr=False
    )
    """Private backing field for `reasoning_start_token_ids`. Set by
    `initialize_token_ids`. Not intended to be configured directly."""
    _reasoning_end_token_ids: list[int] | None = field(
        default=None, init=False, repr=False
    )
    """Private backing field for forced reasoning end token IDs."""
    _natural_reasoning_end_token_ids: list[int] | None = field(
        default=None, init=False, repr=False
    )
    """Token IDs that naturally terminate reasoning, as defined by the parser."""

    _enabled: bool = field(default=False, init=False, repr=False)
    """Private field indicating whether reasoning token IDs have been initialized.
    Set to True by `initialize_token_ids` once token IDs are initialized."""

    @property
    def enabled(self) -> bool:
        """Returns True if reasoning is enabled (i.e. if token IDs have been
        initialized), False otherwise."""
        return self._enabled

    @property
    def reasoning_start_token_ids(self) -> list[int] | None:
        """Token IDs derived from `reasoning_start_str`. Set automatically by
        `initialize_token_ids`. Not intended to be configured directly."""
        return self._reasoning_start_token_ids

    @property
    def reasoning_end_token_ids(self) -> list[int] | None:
        """Token IDs forced when the thinking budget is exhausted."""
        return self._reasoning_end_token_ids

    @property
    def natural_reasoning_end_token_ids(self) -> list[int] | None:
        """Token IDs that indicate the model naturally ended reasoning."""
        return self._natural_reasoning_end_token_ids

    @property
    def implicit_reasoning_end_token_ids(self) -> list[int]:
        """Single-token implicit ends from parser metadata and configuration."""
        return [
            sequence[0]
            for sequence in self._implicit_reasoning_end_token_sequences
            if len(sequence) == 1
        ]

    @property
    def implicit_reasoning_end_token_sequences(self) -> list[list[int]]:
        """Complete implicit-end sequences, including multi-token markers."""
        return self._implicit_reasoning_end_token_sequences

    @property
    def guard_implicit_end_prefix(self) -> bool:
        return self._guard_implicit_end_prefix

    def initialize_token_ids(self, model_config: ModelConfig) -> None:
        """Initialize reasoning token IDs from strings using the tokenizer."""
        if (
            self._reasoning_start_token_ids is not None
            and self._reasoning_end_token_ids is not None
            and self._natural_reasoning_end_token_ids is not None
        ):
            self._enabled = True
            return  # Already initialized

        tokenizer = cached_tokenizer_from_config(model_config=model_config)
        rules = get_policy(self.thinking_budget_policy).boundaries(tokenizer)
        if not isinstance(rules, BoundaryRules):
            raise TypeError(
                "Thinking budget policy boundaries() must return BoundaryRules"
            )
        self._guard_implicit_end_prefix = rules.guard_prefix
        implicit_enabled = (
            self.enable_implicit_reasoning_end
            or self.thinking_budget_policy != "default"
        )
        reasoning_start_str = self.reasoning_start_str
        reasoning_end_str = self.reasoning_end_str
        natural_reasoning_end_str = ""
        implicit_sequences: set[tuple[int, ...]] = set()
        if self.reasoning_parser:
            parser_cls = ReasoningParserManager.get_reasoning_parser(
                self.reasoning_parser
            )
            reasoning_parser = parser_cls(tokenizer)
            if implicit_enabled:
                implicit_sequences.update(
                    (token_id,)
                    for token_id in reasoning_parser.implicit_reasoning_end_token_ids
                )
            start_token = reasoning_parser.reasoning_start_str
            if start_token and not reasoning_start_str:
                reasoning_start_str = start_token

            end_token = reasoning_parser.reasoning_end_str
            if end_token and not reasoning_end_str:
                reasoning_end_str = end_token
            natural_reasoning_end_str = end_token or ""

        if implicit_enabled:
            for marker in (*self.implicit_reasoning_end_strs, *rules.implicit_end_strs):
                if not marker:
                    raise ValueError(
                        "implicit_reasoning_end_strs cannot contain empty strings"
                    )
                token_ids = tokenizer.encode(marker, add_special_tokens=False)
                if not token_ids:
                    raise ValueError(
                        f"Failed to tokenize implicit reasoning end: {marker!r}"
                    )
                implicit_sequences.add(tuple(token_ids))
        self._implicit_reasoning_end_token_sequences = [
            list(sequence) for sequence in sorted(implicit_sequences)
        ]

        if not natural_reasoning_end_str:
            natural_reasoning_end_str = reasoning_end_str

        if not reasoning_start_str or not reasoning_end_str:
            # If we don't have valid strings to tokenize,
            # we can't initialize the token IDs.
            return
        self._reasoning_start_token_ids = tokenizer.encode(
            reasoning_start_str, add_special_tokens=False
        )
        self._reasoning_end_token_ids = tokenizer.encode(
            reasoning_end_str, add_special_tokens=False
        )
        self._natural_reasoning_end_token_ids = tokenizer.encode(
            natural_reasoning_end_str, add_special_tokens=False
        )

        if (
            not self._reasoning_start_token_ids
            or not self._reasoning_end_token_ids
            or not self._natural_reasoning_end_token_ids
        ):
            raise ValueError(
                f"ReasoningConfig: failed to tokenize reasoning strings: "
                f"reasoning_start_str='{self.reasoning_start_str}', "
                f"reasoning_end_str='{self.reasoning_end_str}'. "
                "Ensure the strings are valid tokens in the model's vocabulary."
            )
        self._enabled = True
