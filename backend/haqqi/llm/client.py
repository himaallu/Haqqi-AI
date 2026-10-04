"""OpenAI-compatible chat client for the agents (task 3.5).

Every reply is parsed into a Pydantic model (CLAUDE.md): invalid JSON gets one retry with a
short correction, then `LLMOutputError`. Transport failures get one retry, then the next
provider in the list (flag 18: free-tier Gemini models, then K2), then `LLMUnavailable`. A rate
limit moves straight on to the next provider; only the last one waits it out. Calls are serialised
and spaced to respect K2's 2 requests/second (flag 20). Logs never contain content or keys.
"""

import json
import logging
import re
import threading
import time
from collections.abc import Callable, Sequence
from dataclasses import dataclass, field
from typing import Protocol

import httpx
from pydantic import BaseModel, SecretStr, ValidationError

from haqqi.config import Settings

log = logging.getLogger(__name__)

TIMEOUT_S = 90.0  # K2 calls measured 5-77 s on 2 Oct; a shorter cap only wastes a retry
MIN_GAP_S = 0.5  # 2 requests/second
MAX_RETRY_AFTER_S = 10.0
# A 429 asking us to wait longer than this (e.g. a free-tier daily quota, 20 requests per model per
# day) parks that provider instead of costing a request on every later call. Capped at an hour.
PARK_AFTER_S = 60.0
MAX_PARK_S = 3600.0
_RETRY_DELAY = re.compile(r'"retryDelay"\s*:\s*"(\d+(?:\.\d+)?)s"')

_THINK = re.compile(r"<think>.*?</think>", re.S)
_FENCE = re.compile(r"```(?:json)?")


class LLMError(Exception):
    pass


class LLMUnavailable(LLMError):
    """No provider answered (timeouts, 5xx, rate limits). Show "try again later"."""


class LLMOutputError(LLMError):
    """The model's reply did not parse into the expected schema, even after one retry."""


@dataclass(frozen=True)
class Provider:
    name: str
    base_url: str
    model: str
    api_key: SecretStr | None
    extra: dict[str, object] = field(default_factory=dict)  # provider-specific request fields


def providers_from_settings(settings: Settings) -> list[Provider]:
    """The configured primary provider first, the other as fallback (flag 18).

    Gemini is one provider per free-tier model: each model has its own quota, so a rate-limited
    model hands over to the next one instead of waiting.
    """
    gemini = [
        Provider(
            f"gemini:{model}",
            settings.gemini_base_url,
            model,
            settings.gemini_api_key,
            # Less hidden "thinking" means faster replies; our prompts ask for extraction and JSON.
            extra={"reasoning_effort": "low"},
        )
        for model in dict.fromkeys([settings.gemini_model, *settings.gemini_fallback_models])
    ]
    k2 = Provider("k2", settings.k2_base_url, settings.k2_model, settings.k2_api_key)
    return [*gemini, k2] if settings.llm_provider == "gemini" else [k2, *gemini]


@dataclass(frozen=True)
class Message:
    role: str
    content: str

    def as_dict(self) -> dict[str, str]:
        return {"role": self.role, "content": self.content}


def extract_json(text: str) -> str:
    """Strip reasoning tags and code fences; keep the outermost JSON object (ports `parseK2`)."""
    text = _FENCE.sub("", _THINK.sub("", text)).strip()
    start, end = text.find("{"), text.rfind("}")
    if start == -1 or end < start:
        raise ValueError("no JSON object in the reply")
    return text[start : end + 1]


def parse_reply[T: BaseModel](text: str, schema: type[T]) -> T:
    try:
        return schema.model_validate_json(extract_json(text))
    except (ValueError, ValidationError) as exc:
        raise _ParseFailure(_short_error(exc)) from exc


class _ParseFailure(Exception):
    pass


def _short_error(exc: Exception) -> str:
    if isinstance(exc, ValidationError):
        parts = [f"{'.'.join(str(p) for p in e['loc'])}: {e['msg']}" for e in exc.errors()[:5]]
        return "; ".join(parts)
    return str(exc)[:200]


@dataclass(frozen=True)
class _Retry:
    wait_s: float
    rate_limited: bool = False


PREVIOUS_LIMIT = 4000  # characters of the rejected reply quoted back


def correction(messages: Sequence[Message], previous: str, reason: str) -> list[Message]:
    """The one correction retry, as a single new user turn.

    The rejected reply is quoted as data instead of being sent as an assistant turn: K2's API
    refuses multi-turn history whose assistant messages lack its "thinking" field (HTTP 400;
    found in the 4 Oct eval run, where it failed every retry). This works for every provider.
    """
    quoted = previous[:PREVIOUS_LIMIT]
    return [
        *messages,
        Message(
            "user",
            f"Your previous reply was rejected because {reason}.\n"
            f"Previous reply (for reference only):\n<<<PREVIOUS_REPLY>>>\n{quoted}\n"
            "<<<END_PREVIOUS_REPLY>>>\n"
            "Reply again with ONLY the corrected JSON object.",
        ),
    ]


class Completer(Protocol):
    """What agents need from a client; `LLMClient` in production, a scripted fake in tests."""

    def complete[T: BaseModel](
        self, stage: str, messages: Sequence[Message], schema: type[T]
    ) -> T: ...


class LLMClient:
    def __init__(
        self,
        providers: Sequence[Provider],
        http: httpx.Client | None = None,
        sleep: Callable[[float], None] = time.sleep,
    ) -> None:
        self._providers = [p for p in providers if p.api_key and p.api_key.get_secret_value()]
        self._http = http or httpx.Client(timeout=TIMEOUT_S)
        self._sleep = sleep
        self._lock = threading.Lock()
        self._last_call = 0.0
        self._parked_until: dict[str, float] = {}  # provider name -> time.monotonic() deadline

    @classmethod
    def from_settings(cls, settings: Settings) -> "LLMClient":
        return cls(providers_from_settings(settings))

    def complete[T: BaseModel](self, stage: str, messages: Sequence[Message], schema: type[T]) -> T:
        """Chat call parsed into `schema`; one correction retry on bad output."""
        convo = list(messages)
        reply = self._chat(stage, convo)
        try:
            return parse_reply(reply, schema)
        except _ParseFailure as first:
            log.warning("llm %s: invalid output, retrying once (%s)", stage, first)
            reason = f"it was not valid for the required JSON format ({first})"
            reply = self._chat(stage, correction(convo, reply, reason))
            try:
                return parse_reply(reply, schema)
            except _ParseFailure as second:
                raise LLMOutputError(f"{stage}: invalid JSON after one retry ({second})") from None

    def _chat(self, stage: str, messages: Sequence[Message]) -> str:
        if not self._providers:
            raise LLMUnavailable("no LLM provider configured (set GEMINI_API_KEY or K2_API_KEY)")
        now = time.monotonic()
        available = [p for p in self._providers if self._parked_until.get(p.name, 0.0) <= now]
        if not available:
            raise LLMUnavailable(f"{stage}: every provider is over its quota, try again later")
        last = available[-1]
        for provider in available:
            for attempt in (1, 2):
                outcome = self._post(stage, provider, messages)
                if isinstance(outcome, str):
                    return outcome
                if outcome.rate_limited and provider is not last:
                    break  # another provider (or model quota) may be free: don't wait this one out
                if attempt == 1:
                    self._sleep(outcome.wait_s)
            log.warning("llm %s: provider %s unavailable", stage, provider.name)
        raise LLMUnavailable(f"{stage}: the language model is not responding, try again later")

    def _post(self, stage: str, provider: Provider, messages: Sequence[Message]) -> str | _Retry:
        """The reply text, or how long to wait before retrying."""
        assert provider.api_key is not None
        with self._lock:
            wait = self._last_call + MIN_GAP_S - time.monotonic()
            if wait > 0:
                self._sleep(wait)
            self._last_call = time.monotonic()
        started = time.perf_counter()
        try:
            resp = self._http.post(
                f"{provider.base_url.rstrip('/')}/chat/completions",
                headers={"Authorization": f"Bearer {provider.api_key.get_secret_value()}"},
                json={
                    "model": provider.model,
                    "messages": [m.as_dict() for m in messages],
                    "temperature": 0,
                    **provider.extra,
                },
                timeout=TIMEOUT_S,
            )
        except httpx.HTTPError as exc:
            log.warning("llm %s: %s %s", stage, provider.name, type(exc).__name__)
            return _Retry(1.0)
        latency = time.perf_counter() - started
        if resp.status_code == 429:
            retry_after = _retry_after(resp)
            quota_wait = _quota_wait(resp)
            if quota_wait > PARK_AFTER_S:
                park = min(quota_wait, MAX_PARK_S)
                self._parked_until[provider.name] = time.monotonic() + park
                log.warning("llm %s: %s over quota, parked for %.0fs", stage, provider.name, park)
            log.warning("llm %s: %s rate limited", stage, provider.name)
            return _Retry(retry_after, rate_limited=True)
        if resp.status_code >= 500:
            log.warning("llm %s: HTTP %s", stage, resp.status_code)
            return _Retry(1.0)
        if resp.status_code != 200:
            # The provider's own error text says why (e.g. K2's 400 on multi-turn history).
            log.warning(
                "llm %s: %s HTTP %s: %s", stage, provider.name, resp.status_code, _error_text(resp)
            )
            raise LLMUnavailable(f"{stage}: HTTP {resp.status_code} from {provider.name}")
        try:
            body = resp.json()
            text = body["choices"][0]["message"]["content"] or ""
        except (ValueError, KeyError, IndexError, TypeError):
            log.warning("llm %s: unexpected response shape", stage)
            return _Retry(1.0)
        usage = body.get("usage") or {}
        log.info(
            "llm %s: %s ok in %.1fs, tokens in=%s out=%s",
            stage,
            provider.name,
            latency,
            usage.get("prompt_tokens"),
            usage.get("completion_tokens"),
        )
        return str(text)


def _error_text(resp: httpx.Response) -> str:
    """The provider's error message, shortened. Error bodies carry no request content."""
    try:
        body = resp.json()
        error = body.get("error", body) if isinstance(body, dict) else body
        text = error.get("message", error) if isinstance(error, dict) else error
    except ValueError:
        text = resp.text
    return " ".join(str(text).split())[:200]


def _retry_after(resp: httpx.Response) -> float:
    try:
        return min(float(resp.headers.get("retry-after", "2")), MAX_RETRY_AFTER_S)
    except ValueError:
        return 2.0


def _quota_wait(resp: httpx.Response) -> float:
    """How long the provider asks us to wait: Gemini puts it in the body, others in Retry-After."""
    match = _RETRY_DELAY.search(resp.text)
    if match:
        return float(match.group(1))
    try:
        return float(resp.headers.get("retry-after", "0"))
    except ValueError:
        return 0.0


def dump_json(data: object) -> str:
    """Compact, stable JSON for prompts."""
    return json.dumps(data, ensure_ascii=False, indent=1, default=str)
