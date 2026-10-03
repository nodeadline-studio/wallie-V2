"""OpenAI-compatible provider — covers OpenAI, Groq, and OpenRouter."""
from __future__ import annotations

import asyncio
import base64
from dataclasses import dataclass
from typing import Any, AsyncIterator, Mapping

import httpx
from loguru import logger
from openai import AsyncOpenAI

from .base import LLMError, LLMProvider

# A live stream can't afford a hung LLM call: bound every request and retry a couple
# of times on transient blips (connection drops, 5xx, malformed SSE) so one hiccup
# doesn't turn into dead air. Kept short because reactions must stay snappy.
_REQUEST_TIMEOUT_SEC = 25.0
_MAX_ATTEMPTS = 3
_BACKOFF_BASE_SEC = 0.4

_OPENROUTER_MODELS_ENDPOINT = "https://openrouter.ai/api/v1/models"


@dataclass(frozen=True)
class TextModelInfo:
    """One text model offered by a provider catalogue (``GET /models``)."""

    id: str
    supported_parameters: tuple[str, ...] = ()
    context_length: int | None = None


async def fetch_text_models(
    api_key: str = "",
    *,
    endpoint: str = _OPENROUTER_MODELS_ENDPOINT,
    timeout: float = 15.0,
) -> list[TextModelInfo]:
    """Read the provider's model catalogue (a free endpoint; never paid).

    Used to validate an explicitly configured model before a paid run. The API
    key is sent only as a bearer token and is never logged; a failure propagates
    so callers can refuse to run without validation instead of guessing.
    """
    headers = {"Authorization": f"Bearer {api_key}"} if api_key else {}
    async with httpx.AsyncClient(timeout=timeout) as client:
        response = await client.get(endpoint, headers=headers)
        response.raise_for_status()
        payload = response.json()
    data = payload.get("data") if isinstance(payload, Mapping) else None
    if not isinstance(data, list):
        raise LLMError("provider model catalogue did not contain a 'data' list")
    models: list[TextModelInfo] = []
    for item in data:
        if not isinstance(item, Mapping):
            continue
        supported = item.get("supported_parameters") or ()
        context_length = item.get("context_length")
        models.append(
            TextModelInfo(
                id=str(item.get("id", "")),
                supported_parameters=tuple(str(value) for value in supported),
                context_length=(
                    int(context_length) if context_length is not None else None
                ),
            )
        )
    return models


class OpenAICompatProvider(LLMProvider):
    def __init__(
        self,
        *,
        name: str,
        model: str,
        api_key: str,
        base_url: str | None = None,
        supports_vision: bool = False,
        extra_headers: dict[str, str] | None = None,
        timeout: float = _REQUEST_TIMEOUT_SEC,
    ) -> None:
        if not api_key:
            raise LLMError(f"{name}: missing API key")
        self.name = name
        self.model = model
        self.supports_vision = supports_vision
        # OpenRouter passes `cache_control` breakpoints through to providers that
        # support prompt caching (Anthropic, Gemini). Direct OpenAI/Groq reject the
        # field, so only enable it for OpenRouter. Caching the big static system
        # prompt removes it from prefill on repeat calls → lower latency, same quality.
        self._supports_cache = name == "openrouter"
        self._base_url = base_url
        self._client = AsyncOpenAI(
            api_key=api_key,
            base_url=base_url,
            default_headers=extra_headers or None,
            timeout=timeout,               # configurable: local models on a shared GPU can be slow
            max_retries=0,                 # we do our own (stream-aware) retry below
        )

    async def stream(
        self,
        messages: list[dict[str, Any]],
        *,
        temperature: float = 0.85,
        top_p: float = 0.95,
        max_tokens: int = 500,
        presence_penalty: float = 0.0,
        frequency_penalty: float = 0.0,
    ) -> AsyncIterator[str]:
        payload = [self._encode_message(m) for m in messages]
        last_err: Exception | None = None
        for attempt in range(_MAX_ATTEMPTS):
            produced = False
            try:
                stream = await self._client.chat.completions.create(
                    model=self.model,
                    messages=payload,
                    temperature=temperature,
                    top_p=top_p,
                    max_tokens=max_tokens,
                    presence_penalty=presence_penalty,
                    frequency_penalty=frequency_penalty,
                    stream=True,
                )
                async for event in stream:
                    try:
                        delta = event.choices[0].delta
                        chunk = getattr(delta, "content", None)
                    except (IndexError, AttributeError):
                        chunk = None
                    if chunk:
                        produced = True
                        yield chunk
                return  # completed cleanly
            except Exception as e:  # noqa: BLE001 — connection drop, 5xx, malformed SSE…
                last_err = e
                # If we already streamed part of the answer, restarting would duplicate
                # text — bail. Otherwise retry a couple of times before giving up.
                if produced or attempt == _MAX_ATTEMPTS - 1:
                    break
                logger.warning(
                    f"{self.name}: transient LLM error (try {attempt + 1}/{_MAX_ATTEMPTS}), "
                    f"retrying: {str(e)[:120]}"
                )
                await asyncio.sleep(_BACKOFF_BASE_SEC * (2 ** attempt))
        raise LLMError(f"{self.name} request failed: {last_err}") from last_err

    async def aclose(self) -> None:
        await self._client.close()

    # ----- helpers -----
    def _encode_message(self, m: dict[str, Any]) -> dict[str, Any]:
        content = m.get("content")
        # Mark this message's text as a prompt-cache breakpoint (OpenRouter only).
        cache = bool(m.get("cache")) and self._supports_cache
        if isinstance(content, list):
            blocks: list[dict[str, Any]] = []
            for b in content:
                if b.get("type") == "text":
                    blocks.append({"type": "text", "text": b.get("text", "")})
                elif b.get("type") == "image":
                    b64 = base64.b64encode(b["data"]).decode("ascii")
                    mime = b.get("mime", "image/jpeg")
                    blocks.append(
                        {
                            "type": "image_url",
                            "image_url": {
                                "url": f"data:{mime};base64,{b64}",
                                "detail": "low",
                            },
                        }
                    )
            if cache and blocks and blocks[-1].get("type") == "text":
                blocks[-1]["cache_control"] = {"type": "ephemeral"}
            return {"role": m["role"], "content": blocks}
        if cache and content:
            return {
                "role": m["role"],
                "content": [
                    {"type": "text", "text": content, "cache_control": {"type": "ephemeral"}}
                ],
            }
        return {"role": m["role"], "content": content or ""}
