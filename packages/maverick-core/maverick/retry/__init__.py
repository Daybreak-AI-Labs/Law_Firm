"""Retry with exponential backoff for transient LLM provider errors.

Tier 1 (SRE reviewer): a single 429 / 503 / connection-reset used to
fail the entire goal. Provider calls now retry with exponential backoff
(1s, 2s, 4s, 8s, max 5 attempts), honoring ``Retry-After`` when the
provider returns one.

Errors we retry:
  - anthropic.RateLimitError, anthropic.APIConnectionError,
    anthropic.InternalServerError, anthropic.APITimeoutError
  - openai.RateLimitError, openai.APIConnectionError,
    openai.InternalServerError, openai.APITimeoutError
  - httpx.ReadTimeout, httpx.ConnectError (transport-level)

Anything else propagates immediately so a bug in our code isn't silently
re-tried.
"""
from __future__ import annotations

import asyncio
import logging
import random
import time
from collections.abc import Awaitable, Callable
from typing import TypeVar

from .._envparse import env_float, env_int

log = logging.getLogger(__name__)

T = TypeVar("T")


# Clamp to >=1: a 0/negative override would make sync_retry/async_retry do
# range(0) -- the wrapped fn is NEVER called, `last` stays None, and the call
# dies on `assert last is not None` with an opaque AssertionError, the provider
# request silently never dispatched. At least one attempt is always made.
# 3 attempts: retries re-generate the FULL output at billed rates, so this is
# the one same-call output-token amplifier — 5 attempts quintupled worst-case
# spend during a provider incident for marginal extra success.
MAX_ATTEMPTS = max(1, env_int("MAVERICK_LLM_RETRY_ATTEMPTS", 3))
BASE_DELAY = env_float("MAVERICK_LLM_RETRY_BASE_DELAY", 1.0)
MAX_DELAY = env_float("MAVERICK_LLM_RETRY_MAX_DELAY", 30.0)


def _retryable_exception_classes() -> tuple[type, ...]:
    """Resolve retryable exception classes lazily. Optional deps may be missing."""
    classes: list[type] = []
    try:
        import anthropic
        for n in ("RateLimitError", "APIConnectionError", "InternalServerError",
                  "APITimeoutError", "APIStatusError"):
            cls = getattr(anthropic, n, None)
            if cls is not None:
                classes.append(cls)
    except ImportError:
        pass
    try:
        import openai
        for n in ("RateLimitError", "APIConnectionError", "InternalServerError",
                  "APITimeoutError"):
            cls = getattr(openai, n, None)
            if cls is not None:
                classes.append(cls)
    except ImportError:
        pass
    try:
        import httpx
        classes.append(httpx.ReadTimeout)
        classes.append(httpx.ConnectError)
    except ImportError:
        pass
    return tuple(classes) or (Exception,)


def _retry_after_from(exc: Exception) -> float | None:
    """Extract Retry-After (seconds) from a provider exception, if present."""
    response = getattr(exc, "response", None)
    if response is None:
        return None
    headers = getattr(response, "headers", None) or {}
    # Prefer the millisecond header when present: some providers send
    # `retry-after-ms` (sub-second precision) and only fall back to the
    # whole-second `Retry-After`. Without this, an ms hint was ignored and
    # the loop dropped to blind exponential backoff.
    raw_ms = headers.get("retry-after-ms") or headers.get("Retry-After-Ms")
    if raw_ms:
        try:
            return float(raw_ms) / 1000.0
        except (TypeError, ValueError):
            pass
    raw = headers.get("Retry-After") or headers.get("retry-after")
    if not raw:
        return None
    try:
        return float(raw)
    except (TypeError, ValueError):
        return None


def _compute_delay(attempt: int, exc: Exception) -> float:
    """Honor Retry-After if present; else exponential backoff with jitter.

    Council finding: a hostile/buggy server returning `Retry-After: -1`
    would feed time.sleep / asyncio.sleep a negative value and raise
    ValueError, killing the retry loop. We clamp to [0, MAX_DELAY].
    """
    explicit = _retry_after_from(exc)
    if explicit is not None:
        return max(0.0, min(explicit, MAX_DELAY))
    delay = min(BASE_DELAY * (2 ** attempt), MAX_DELAY)
    return max(0.0, delay * (0.5 + random.random() * 0.5))


def _is_retryable_status_error(exc: Exception) -> bool:
    """Anthropic APIStatusError covers 429+5xx+4xx; only retry 429/5xx."""
    status = getattr(exc, "status_code", None)
    if status is None:
        return True  # Non-status retryable types are always transient.
    return status == 429 or 500 <= status < 600


# Error classes the taxonomy says must never be retried, even when the
# exception's type/status looked transient: a 401 surfaced as an
# APIStatusError, a content-filter refusal, or a context-overflow won't be
# fixed by waiting. Consulting retry_classifier here is what makes
# threat-model.md's "retry_classifier marks auth errors terminal" true.
_TERMINAL_CLASSES = frozenset({
    "auth", "content_filter", "context_overflow",
})


def _is_terminal(exc: Exception) -> bool:
    try:
        from .classifier import classify
        return classify(exc).value in _TERMINAL_CLASSES
    except Exception:  # pragma: no cover - classifier must never break retry
        return False


def sync_retry(fn: Callable[[], T]) -> T:
    """Run a sync callable, retrying transient provider errors."""
    retryable = _retryable_exception_classes()
    last: Exception | None = None
    for attempt in range(MAX_ATTEMPTS):
        try:
            return fn()
        except retryable as e:
            if not _is_retryable_status_error(e) or _is_terminal(e):
                raise
            last = e
            if attempt == MAX_ATTEMPTS - 1:
                break
            delay = _compute_delay(attempt, e)
            log.warning(
                "LLM call failed (attempt %d/%d): %s; retry in %.1fs",
                attempt + 1, MAX_ATTEMPTS, type(e).__name__, delay,
            )
            time.sleep(delay)
    assert last is not None
    raise last


async def async_retry(fn: Callable[[], Awaitable[T]]) -> T:
    """Run an async callable, retrying transient provider errors."""
    retryable = _retryable_exception_classes()
    last: Exception | None = None
    for attempt in range(MAX_ATTEMPTS):
        try:
            return await fn()
        except retryable as e:
            if not _is_retryable_status_error(e) or _is_terminal(e):
                raise
            last = e
            if attempt == MAX_ATTEMPTS - 1:
                break
            delay = _compute_delay(attempt, e)
            log.warning(
                "LLM call failed (attempt %d/%d): %s; retry in %.1fs",
                attempt + 1, MAX_ATTEMPTS, type(e).__name__, delay,
            )
            await asyncio.sleep(delay)
    assert last is not None
    raise last
