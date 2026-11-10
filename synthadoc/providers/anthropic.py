# SPDX-License-Identifier: AGPL-3.0-or-later
# Copyright (C) 2026 Paul Chen / axoviq.com
from __future__ import annotations
import asyncio
from typing import AsyncGenerator, Optional
import anthropic as anthropic_lib
from synthadoc.config import AgentConfig
from synthadoc.providers.base import CompletionResponse, LLMProvider, Message

# temperature is never sent. Claude 4.7 and later return HTTP 400 for a non-default
# temperature, and anthropic SDK >= 1.0 removed the parameter from messages.create()
# and messages.stream() (passing it raises TypeError). Every supported model uses
# the API default; the ``temperature`` argument stays in the signatures only because
# it is part of the shared LLMProvider interface.

# RateLimitError (429) is not retried — quota exhaustion needs a provider switch or wait.
# InternalServerError covers transient 500/529 overload; retry with backoff.
_RETRYABLE = (anthropic_lib.InternalServerError,)
_RATE_LIMIT = (anthropic_lib.RateLimitError,)
_MAX_RETRIES = 3


def _system_block(text: str) -> list[dict]:
    return [{"type": "text", "text": text, "cache_control": {"type": "ephemeral"}}]


class AnthropicProvider(LLMProvider):
    def __init__(self, api_key: str, config: AgentConfig, timeout: int = 0) -> None:
        # timeout=0 means "use the SDK default" (600 s); any positive value caps the call.
        client_kwargs: dict = {"api_key": api_key}
        if timeout > 0:
            client_kwargs["timeout"] = float(timeout)
        self._client = anthropic_lib.AsyncAnthropic(**client_kwargs)
        self._config = config

    async def complete(self, messages: list[Message], system: Optional[str] = None,
                       temperature: float = 0.0, max_tokens: int = 4096) -> CompletionResponse:
        kwargs: dict = {
            "model": self._config.model,
            "max_tokens": max_tokens,
            "messages": [{"role": m.role, "content": m.content} for m in messages],
        }
        if system:
            kwargs["system"] = _system_block(system)
        # stream=True tells the Anthropic API this is a streaming request, which is
        # required for long-running calls (scaffold, large ingests, etc.).
        # We accumulate the chunks here so callers get the same CompletionResponse.
        kwargs["stream"] = True
        last_exc: Exception | None = None
        for attempt in range(_MAX_RETRIES):
            try:
                parts: list[str] = []
                input_tokens = 0
                output_tokens = 0
                cache_read_tokens = 0
                cache_write_tokens = 0
                stop_reason = None
                stream_resp = await self._client.messages.create(**kwargs)
                async for event in stream_resp:
                    if event.type == "message_start":
                        usage = event.message.usage
                        input_tokens = usage.input_tokens
                        cache_read_tokens = getattr(usage, "cache_read_input_tokens", 0) or 0
                        cache_write_tokens = getattr(usage, "cache_creation_input_tokens", 0) or 0
                    elif event.type == "message_delta" and hasattr(event, "usage"):
                        output_tokens = event.usage.output_tokens
                        stop_reason = getattr(event.delta, "stop_reason", None) or stop_reason
                    elif (event.type == "content_block_delta"
                            and hasattr(event.delta, "text")):
                        parts.append(event.delta.text)
                return CompletionResponse(text="".join(parts),
                                         input_tokens=input_tokens,
                                         output_tokens=output_tokens,
                                         truncated=stop_reason == "max_tokens",
                                         cache_read_tokens=cache_read_tokens,
                                         cache_write_tokens=cache_write_tokens)
            except _RATE_LIMIT:
                raise  # quota exhaustion — propagate immediately, no retry
            except _RETRYABLE as exc:
                last_exc = exc
                if attempt < _MAX_RETRIES - 1:
                    await asyncio.sleep(2 ** attempt)  # 1 s, 2 s, 4 s backoff (attempt 0 → 1 s)
                continue
            except Exception:
                raise
        assert last_exc is not None
        raise last_exc

    async def complete_stream(
        self, messages: list[Message], system: Optional[str] = None,
        temperature: float = 0.0, max_tokens: int = 4096
    ) -> AsyncGenerator[str, None]:
        kwargs: dict = {
            "model": self._config.model,
            "max_tokens": max_tokens,
            "messages": [{"role": m.role, "content": m.content} for m in messages],
        }
        if system:
            kwargs["system"] = _system_block(system)
        async with self._client.messages.stream(**kwargs) as stream:
            async for event in stream:
                # message_start carries input_tokens; message_delta carries cumulative output_tokens.
                if event.type == "message_start":
                    usage = event.message.usage
                    self.last_stream_input_tokens = usage.input_tokens
                    self.last_stream_cache_read_tokens = getattr(usage, "cache_read_input_tokens", 0) or 0
                    self.last_stream_cache_write_tokens = getattr(usage, "cache_creation_input_tokens", 0) or 0
                elif event.type == "message_delta" and hasattr(event, "usage"):
                    self.last_stream_output_tokens = event.usage.output_tokens
                elif (event.type == "content_block_delta"
                        and hasattr(event.delta, "text")):
                    yield event.delta.text # type: ignore
