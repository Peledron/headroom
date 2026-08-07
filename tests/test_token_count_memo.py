"""Parity tests for TokenCountMemo (perf review F2).

The memo's correctness hinges on: tokenizer.count_messages(messages) ==
sum(tokenizer.count_message(m) for m in messages) + tokenizer.REPLY_OVERHEAD.
These tests prove the memoized count matches the direct count exactly across
message shapes the Claude Code route actually sends (text, tool_use,
tool_result string content, tool_result list-of-blocks content, images), using
EstimatingTokenCounter — the only tokenizer the proxy uses for Claude models
(tokenizers/registry.py `_create_anthropic`).
"""

from __future__ import annotations

import pytest

from headroom.cache.token_count_memo import TokenCountMemo, count_messages_memoized
from headroom.tokenizers.estimator import EstimatingTokenCounter

FIXTURES = [
    pytest.param(
        [
            {"role": "user", "content": "hello there"},
            {"role": "assistant", "content": "hi, how can I help?"},
        ],
        id="plain_text",
    ),
    pytest.param(
        [
            {"role": "user", "content": "do something"},
            {
                "role": "assistant",
                "content": [{"type": "tool_use", "id": "t1", "name": "my_tool", "input": {"a": 1}}],
            },
            {
                "role": "user",
                "content": [
                    {"type": "tool_result", "tool_use_id": "t1", "content": "tool output data"}
                ],
            },
        ],
        id="tool_use_and_result_string",
    ),
    pytest.param(
        [
            {
                "role": "user",
                "content": [
                    {
                        "type": "tool_result",
                        "tool_use_id": "t1",
                        "content": [{"type": "text", "text": "list-of-blocks tool output"}],
                    }
                ],
            },
        ],
        id="tool_result_list_of_blocks",
    ),
    pytest.param(
        [
            {
                "role": "user",
                "content": [
                    {"type": "text", "text": "look at this"},
                    {
                        "type": "image",
                        "source": {"type": "base64", "media_type": "image/png", "data": "AAAA"},
                    },
                ],
            },
        ],
        id="text_and_image_block",
    ),
    pytest.param(
        [
            {"role": "system", "content": "You are a helpful assistant."},
            {"role": "user", "content": "hi", "name": "alice"},
            {
                "role": "assistant",
                "content": "",
                "tool_calls": [
                    {
                        "id": "call_1",
                        "function": {"name": "search", "arguments": '{"q": "test"}'},
                    }
                ],
            },
        ],
        id="system_name_and_tool_calls",
    ),
    pytest.param([], id="empty_messages"),
    pytest.param([{"role": "user", "content": "solo message"}], id="single_message"),
]


@pytest.mark.parametrize("messages", FIXTURES)
def test_memoized_count_matches_direct_count(messages) -> None:
    tokenizer = EstimatingTokenCounter()
    memo = TokenCountMemo()

    direct = tokenizer.count_messages(messages)
    memoized = count_messages_memoized(memo, tokenizer, messages)

    assert memoized == direct


def test_memoized_count_stable_across_repeated_calls_cold_and_warm() -> None:
    """Same messages, memo cold then warm — count must not drift."""
    tokenizer = EstimatingTokenCounter()
    memo = TokenCountMemo()
    messages = [
        {"role": "user", "content": "hello"},
        {
            "role": "user",
            "content": [{"type": "tool_result", "tool_use_id": "t1", "content": "output"}],
        },
    ]
    direct = tokenizer.count_messages(messages)

    cold = count_messages_memoized(memo, tokenizer, messages)
    warm = count_messages_memoized(memo, tokenizer, messages)

    assert cold == direct
    assert warm == direct


def test_memoized_count_handles_append_only_delta() -> None:
    """Only the new tail message should require a fresh count; the frozen
    prefix's per-message entries must already be memoized (cache hits)."""
    tokenizer = EstimatingTokenCounter()
    memo = TokenCountMemo()
    turn1 = [{"role": "user", "content": "turn one"}]
    turn2 = turn1 + [{"role": "assistant", "content": "turn two reply"}]

    count_messages_memoized(memo, tokenizer, turn1)
    prefix_key = TokenCountMemo.message_hash(turn1[0])
    assert memo.get(prefix_key) is not None

    memoized_turn2 = count_messages_memoized(memo, tokenizer, turn2)
    assert memoized_turn2 == tokenizer.count_messages(turn2)


def test_message_hash_differs_for_different_messages() -> None:
    h1 = TokenCountMemo.message_hash({"role": "user", "content": "a"})
    h2 = TokenCountMemo.message_hash({"role": "user", "content": "b"})
    assert h1 != h2


def test_message_hash_same_for_identical_messages() -> None:
    m = {"role": "user", "content": "same content"}
    assert TokenCountMemo.message_hash(dict(m)) == TokenCountMemo.message_hash(dict(m))


class TestTokenCountMemoEviction:
    def test_eviction_at_max_entries(self) -> None:
        memo = TokenCountMemo(max_entries=3)
        memo.put("a", 1)
        memo.put("b", 2)
        memo.put("c", 3)
        memo.get("a")  # touch "a" so it's not the least-recently-used
        memo.put("d", 4)  # should evict "b" (oldest untouched)

        assert memo.get("a") == 1
        assert memo.get("b") is None
        assert memo.get("c") == 3
        assert memo.get("d") == 4

    def test_get_stats_reports_entry_count(self) -> None:
        memo = TokenCountMemo()
        memo.put("a", 1)
        memo.put("b", 2)
        assert memo.get_stats()["entries"] == 2


class TestTokenizerCapabilityGuards:
    """Runtime enforcement of the additive-counts precondition and the
    memo↔tokenizer binding (review findings 3 and 4)."""

    def test_non_additive_tokenizer_bypasses_memo(self) -> None:
        """A tokenizer flagged non-additive (HuggingFace/Mistral chat-template
        counting) must get a plain count_messages call — never per-message
        memoization, which would be systematically wrong for it."""

        class _JointTokenizer:
            ADDITIVE_COUNTS = False
            REPLY_OVERHEAD = 3

            def count_message(self, message) -> int:  # noqa: ANN001
                raise AssertionError("per-message path must not be used")

            def count_messages(self, messages) -> int:  # noqa: ANN001
                return 1234

        memo = TokenCountMemo()
        assert (
            count_messages_memoized(memo, _JointTokenizer(), [{"role": "user", "content": "x"}])
            == 1234
        )
        assert memo.get_stats()["entries"] == 0

    def test_unflagged_tokenizer_bypasses_memo(self) -> None:
        """Duck-typed tokenizers without the ADDITIVE_COUNTS flag get the
        conservative (correct, unmemoized) path."""

        class _Unflagged:
            REPLY_OVERHEAD = 3

            def count_message(self, message) -> int:  # noqa: ANN001
                raise AssertionError("per-message path must not be used")

            def count_messages(self, messages) -> int:  # noqa: ANN001
                return 99

        memo = TokenCountMemo()
        assert count_messages_memoized(memo, _Unflagged(), [{"role": "user", "content": "x"}]) == 99
        assert memo.get_stats()["entries"] == 0

    def test_tokenizer_swap_clears_memo(self) -> None:
        """Counts computed under one tokenizer must not be served after a
        swap (the count fail-open path downgrades to a fresh estimator
        mid-session): the memo rebinds and recounts."""
        messages = [{"role": "user", "content": "hello world " * 50}]
        a = EstimatingTokenCounter()
        b = EstimatingTokenCounter(chars_per_token=1.0)  # very different ratio

        memo = TokenCountMemo()
        count_a = count_messages_memoized(memo, a, messages)
        count_b = count_messages_memoized(memo, b, messages)

        assert count_b == b.count_messages(messages)
        assert count_b != count_a  # stale count under `a` was not reused

    def test_same_tokenizer_keeps_memo_bound(self) -> None:
        messages = [{"role": "user", "content": "hello world " * 50}]
        tokenizer = EstimatingTokenCounter()
        memo = TokenCountMemo()
        count_messages_memoized(memo, tokenizer, messages)
        entries = memo.get_stats()["entries"]
        count_messages_memoized(memo, tokenizer, messages)
        assert memo.get_stats()["entries"] == entries  # no clear, warm hits
