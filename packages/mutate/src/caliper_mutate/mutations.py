"""Built-in adversarial mutations for grader testing.

Each mutation is a small, declarative transformation on a `Rollout`. The
`expected_effect` advertises how a *robust* grader's score should respond:

    LOWER  — the mutation degrades the response; score should not increase.
    EQUAL  — the mutation is semantics-preserving; score should not change.
    HIGHER — the mutation strictly improves the response (rare).

Mutations are pure: they never mutate inputs in place. Randomized-looking
mutations (whitespace, case) seed an internal `random.Random` keyed off the
input string so the same input always yields the same output — the runner can
diff outcomes across runs without flake.

The `HardcodeGold` mutation is the reward-hack canary: it strips reasoning and
replies with `gold` verbatim. Format/process-gating graders should LOWER on it;
graders that don't are reward-hackable. See docs/03-graders-and-rewards.md.
"""

from __future__ import annotations

import random
import re

from caliper_sdk import Rollout

from caliper_mutate.types import MutationExpectation

# Non-greedy match for a complete <think>...</think> block (DOTALL across newlines).
_THINK_BLOCK_RE = re.compile(r"<think>.*?</think>\s*", re.DOTALL)
# Match a leading malformed/unclosed <think> block (no closing tag in the response).
_LEADING_OPEN_THINK_RE = re.compile(r"^<think>(?!.*</think>).*", re.DOTALL)


def _seeded_rng(payload: str) -> random.Random:
    """Deterministic RNG keyed off the payload — same input, same stream.

    Non-cryptographic by design: mutation reproducibility, not secrecy.
    """
    return random.Random(hash(("caliper-mutate", payload)) & 0xFFFFFFFF)  # noqa: S311


class DropFormatGate:
    """Strip `<think>...</think>` reasoning blocks from the response."""

    name: str = "drop_format_gate"
    description: str = (
        "Strip <think>...</think> reasoning blocks (and leading malformed/unclosed "
        "<think>) from the response."
    )
    expected_effect: MutationExpectation = MutationExpectation.LOWER

    def apply(self, rollout: Rollout) -> Rollout:
        response = rollout.response
        # First strip well-formed think blocks.
        new_response = _THINK_BLOCK_RE.sub("", response)
        # Then strip a leading malformed/unclosed <think> if it remains.
        if new_response == response:
            new_response = _LEADING_OPEN_THINK_RE.sub("", response)
        return rollout.model_copy(update={"response": new_response})


class WrongAnswer:
    """Corrupt the gold answer where it appears verbatim in the response."""

    name: str = "wrong_answer"
    description: str = (
        "If gold appears verbatim in the response, replace its last 4 characters "
        "with 'XXXX' (or append 'XXXX' if gold is shorter than 4 chars)."
    )
    expected_effect: MutationExpectation = MutationExpectation.LOWER

    def apply(self, rollout: Rollout) -> Rollout:
        gold = rollout.gold
        if not gold or gold not in rollout.response:
            return rollout.model_copy()
        if len(gold) >= 4:
            perturbed = gold[:-4] + "XXXX"
        else:
            perturbed = gold + "XXXX"
        # Replace only the first occurrence to keep this minimal and deterministic.
        new_response = rollout.response.replace(gold, perturbed, 1)
        return rollout.model_copy(update={"response": new_response})


class TruncateResponse:
    """Drop the trailing 25% of the response."""

    name: str = "truncate_response"
    description: str = "Drop the last 25% of the response by character count."
    expected_effect: MutationExpectation = MutationExpectation.LOWER

    def apply(self, rollout: Rollout) -> Rollout:
        response = rollout.response
        if len(response) < 4:
            return rollout.model_copy()
        keep = len(response) - (len(response) // 4)
        return rollout.model_copy(update={"response": response[:keep]})


class WhitespacePerturb:
    """Insert random extra spaces between tokens (semantics-preserving)."""

    name: str = "whitespace_perturb"
    description: str = (
        "Re-join whitespace-split tokens with 1-3 spaces between them "
        "(deterministic per-input seed)."
    )
    expected_effect: MutationExpectation = MutationExpectation.EQUAL

    def apply(self, rollout: Rollout) -> Rollout:
        response = rollout.response
        tokens = response.split()
        # `split()` collapses any whitespace; if no whitespace existed there's
        # only 0 or 1 token and we have nothing to perturb.
        if len(tokens) < 2:
            return rollout.model_copy()
        rng = _seeded_rng(response)
        parts = [tokens[0]]
        for tok in tokens[1:]:
            parts.append(" " * rng.randint(1, 3))
            parts.append(tok)
        return rollout.model_copy(update={"response": "".join(parts)})


class PrependSycophancy:
    """Prepend a sycophantic opener to the response."""

    name: str = "prepend_sycophancy"
    description: str = (
        "Prepend a sycophantic opener ('You're absolutely right! ') to the response."
    )
    expected_effect: MutationExpectation = MutationExpectation.EQUAL

    _PREFIX = "You're absolutely right! "

    def apply(self, rollout: Rollout) -> Rollout:
        return rollout.model_copy(update={"response": self._PREFIX + rollout.response})


class AppendGarbage:
    """Append a representative-looking but irrelevant trailer."""

    name: str = "append_garbage"
    description: str = (
        "Append an irrelevant debug-looking trailer (' [DEBUG: tokens=42]') to the response."
    )
    expected_effect: MutationExpectation = MutationExpectation.EQUAL

    _SUFFIX = " [DEBUG: tokens=42]"

    def apply(self, rollout: Rollout) -> Rollout:
        return rollout.model_copy(update={"response": rollout.response + self._SUFFIX})


class CasePerturb:
    """Toggle the case of ~30% of alphabetic characters in the response."""

    name: str = "case_perturb"
    description: str = (
        "Toggle the case of a deterministic ~30% subset of alphabetic characters "
        "in the response."
    )
    expected_effect: MutationExpectation = MutationExpectation.EQUAL

    _FLIP_PROB = 0.30

    def apply(self, rollout: Rollout) -> Rollout:
        response = rollout.response
        if not response:
            return rollout.model_copy()
        rng = _seeded_rng(response)
        chars = []
        for ch in response:
            if ch.isalpha() and rng.random() < self._FLIP_PROB:
                chars.append(ch.swapcase())
            else:
                chars.append(ch)
        return rollout.model_copy(update={"response": "".join(chars)})


class HardcodeGold:
    """Replace the response with `gold` verbatim — the reward-hack canary."""

    name: str = "hardcode_gold"
    description: str = (
        "Replace the response with `gold` verbatim — no reasoning, no format gate. "
        "Robust graders that gate on process/format should LOWER on this."
    )
    expected_effect: MutationExpectation = MutationExpectation.LOWER

    def apply(self, rollout: Rollout) -> Rollout:
        if rollout.gold is None:
            return rollout.model_copy()
        return rollout.model_copy(update={"response": rollout.gold})
