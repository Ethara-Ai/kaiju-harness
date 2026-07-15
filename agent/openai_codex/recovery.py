"""Client-side transient-retry wrapper for the Codex bridge.

Wrap an agent/coder call so a transient failure (peer-closed connection,
incomplete chunked read, 5xx, momentary rate-limit) retries with backoff instead
of aborting a module. Provider-agnostic — it inspects the exception text, not any
codex-specific type — so it also works for the Claude Code path.
"""

from __future__ import annotations

import logging
import os
import time
from typing import Any, Callable, Optional, TypeVar

_LOG = logging.getLogger(__name__)
_T = TypeVar("_T")

# Substrings that mark a transient, worth-retrying failure.
# NOTE: "rate limit" and "429" were REMOVED from bare substrings (F6 audit fix)
# because they false-positive on log/error text like "not a rate limit", "has no
# rate limit", or code comments that reference the concept. Rate-limit detection
# now goes through ``_RATE_LIMIT_PHRASE_RE`` below with proper negation guards
# (mirrors ``agent/claude_code/recovery.py`` for isomorphic semantics).
_TRANSIENT_SIGNALS = (
    "peer closed connection", "incomplete chunked read", "connection reset",
    "connection aborted", "server disconnected", "read timeout", "timed out",
    "temporarily unavailable", "502 bad gateway", "503 service", "504 gateway",
    "remoteprotocolerror", "econnreset",
    # aider-swallowed transient LLM errors surfaced by
    # agent.agents.raise_if_transient_llm_error (TransientLLMError) and the raw
    # litellm/mid-stream signals it matches, so the codex-recovery path retries
    # the module instead of losing the turn's work.
    "transientllmerror", "midstreamfallbackerror", "apiconnectionerror",
    "apitimeouterror",
    # Rate-limit slugs — these are error-code identifiers, safe as bare substrings
    # because they're structured tokens (not human phrases) unlikely to appear in
    # log text unless the error is real.
    "rate_limit_error", "ratelimiterror", "too many requests", "resource_exhausted",
)

_DEFAULT_BACKOFF = (5, 10, 20, 40, 60)


def _backoff_schedule() -> tuple[float, ...]:
    raw = os.environ.get("KAIJU_CODEX_TRANSIENT_BACKOFF", "")
    if raw:
        try:
            return tuple(float(x) for x in raw.split(",") if x.strip())
        except ValueError:
            pass
    return _DEFAULT_BACKOFF


import re

_TIGHT_INTERNAL_ERR_RE = re.compile(
    r"(?:"
    r"\.internalservererror\b|"
    r"500\s*[:\s]\s*internal\s+server\s+error\b|"
    r"\berror\s+(?:type|class|code)[:\s]+(?:internalservererror|internal\s+server\s+error)\b|"
    r"\.internal_server_error\b"
    r")",
    re.IGNORECASE,
)
_TIGHT_OVERLOAD_RE = re.compile(
    r'(?:"overloaded_error"|error\s+type[:\s]+overloaded|anthropic\s+api\s+overloaded)',
    re.IGNORECASE,
)
# F6 audit fix: human-phrase rate-limit detection with negation guards.
# Mirrors ``agent/claude_code/recovery.py:_RATE_LIMIT_PHRASE_RE`` (line 44).
# Guards below check a 12-char prefix window for negations so a log line like
# "not a rate limit" or "has no rate limit" doesn't false-positive.
_RATE_LIMIT_PHRASE_RE = re.compile(
    r"\brate[\s_-]?limit(?:ed|ing)?\b", re.IGNORECASE,
)
_RATE_LIMIT_NEGATIONS = (" not a ", " not ", " no ", " isn't a ", " isn't ")


def _matches_rate_limit_phrase(msg: str) -> bool:
    """True iff ``msg`` mentions rate-limiting NOT prefixed by a negation."""
    for m in _RATE_LIMIT_PHRASE_RE.finditer(msg):
        prefix = msg[max(0, m.start() - 12):m.start()]
        # Prepend a space so negations at message start ("not a rate...") still
        # match " not a " / " not " via word boundaries.
        prefix_padded = " " + prefix
        if any(neg in prefix_padded for neg in _RATE_LIMIT_NEGATIONS):
            continue
        return True
    return False


def _extract_retry_after_from_error(exc: BaseException) -> Optional[int]:
    """Best-effort: pull a Retry-After hint from a RateLimitError-shaped exception.

    F9 audit backport from ``agent/claude_code/recovery.py:283``. Enables the codex
    recovery loop to honour server-signalled cooldowns instead of always using the
    fixed backoff schedule."""
    resp = getattr(exc, "response", None) or getattr(exc, "_response", None)
    if resp is not None:
        headers = getattr(resp, "headers", None)
        if headers is not None:
            try:
                val = headers.get("Retry-After") or headers.get("retry-after")
                if val is not None:
                    return int(val)
            except (TypeError, ValueError):
                pass
    msg = str(exc)
    m = re.search(r"retry[-_ ]after[:\s]+(\d+)", msg, re.IGNORECASE)
    if m:
        try:
            return int(m.group(1))
        except ValueError:
            pass
    return None


def is_transient(exc: BaseException) -> bool:
    msg = str(exc).lower()
    if any(sig in msg for sig in _TRANSIENT_SIGNALS):
        return True
    if _TIGHT_INTERNAL_ERR_RE.search(msg):
        return True
    if _TIGHT_OVERLOAD_RE.search(msg):
        return True
    if _matches_rate_limit_phrase(msg):
        return True
    return False


def run_with_recovery(fn: Callable[..., _T], *args: Any,
                      max_retries: Optional[int] = None,
                      sleep: Callable[[float], None] = time.sleep,
                      **kwargs: Any) -> _T:
    """Call ``fn(*args, **kwargs)``, retrying transient failures with backoff.

    Non-transient exceptions propagate immediately. Retries are capped by
    ``max_retries`` (default: length of the backoff schedule).
    """
    backoff = _backoff_schedule()
    cap = max_retries if max_retries is not None else len(backoff)
    attempt = 0
    while True:
        try:
            return fn(*args, **kwargs)
        # Only ordinary exceptions are retryable; never swallow KeyboardInterrupt /
        # SystemExit (those are BaseException, not Exception).
        except Exception as exc:  # noqa: BLE001 — we re-raise non-transient below
            if attempt >= cap or not is_transient(exc):
                raise
            wait = backoff[min(attempt, len(backoff) - 1)]
            # F9 audit fix: honour a server-signalled Retry-After hint if the
            # exception carries one. Use the LONGER of the fixed backoff and the
            # server hint, capped at 10 min to avoid pathological retry-after values
            # (e.g. buggy upstream returning `retry-after: 86400`) tying up a slot.
            retry_after = _extract_retry_after_from_error(exc)
            if retry_after is not None:
                wait = min(600, max(wait, retry_after))
                _LOG.info("codex: retry-after hint=%ss (using wait=%ss)", retry_after, wait)
            _LOG.warning("codex: transient failure (%s); retry %d/%d in %ss",
                         str(exc)[:120], attempt + 1, cap, wait)
            sleep(wait)
            attempt += 1
