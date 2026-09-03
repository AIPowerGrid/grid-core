# SPDX-FileCopyrightText: 2026 AI Power Grid
# SPDX-License-Identifier: AGPL-3.0-or-later

"""Token streaming via Redis Pub/Sub + buffered replay.

Workers publish tokens as they generate. Clients subscribe to receive
them in real time. A Redis list buffers tokens so clients that connect
slightly late can replay missed tokens before switching to live pub/sub.

Channel: `grid:stream:{job_id}`
Buffer:  `grid:tokens:{job_id}` (list, TTL 5 min)
"""

import asyncio
import json
import logging
from typing import AsyncGenerator

import redis.exceptions

from ..redis_client import get_redis

logger = logging.getLogger("grid_api.token_stream")

CHANNEL_PREFIX = "grid:stream:"
BUFFER_PREFIX = "grid:tokens:"
CANCEL_PREFIX = "grid:cancel:"
DONE_SENTINEL = "[DONE]"
BUFFER_TTL = 300  # 5 minutes
CANCEL_TTL = 600  # 10 minutes — comfortably longer than any single generation


async def request_cancel(job_id: str) -> None:
    """Mark a job cancelled because the client disconnected / pressed stop.

    Idempotent. The worker-WS receive loop polls `is_cancelled()` and, on seeing
    the flag, forwards a `cancel` frame to the worker, which aborts the in-flight
    backend request (freeing the GPU) and returns whatever it produced so far.
    Settlement then bills only the partial output — no special path needed."""
    try:
        await get_redis().set(f"{CANCEL_PREFIX}{job_id}", "1", ex=CANCEL_TTL)
    except Exception:
        logger.warning("request_cancel failed for job %s", job_id, exc_info=True)


async def is_cancelled(job_id: str) -> bool:
    """True if a cancel has been requested for this job. Fails closed (False)."""
    try:
        return bool(await get_redis().exists(f"{CANCEL_PREFIX}{job_id}"))
    except Exception:
        return False


async def clear_cancel(job_id: str) -> None:
    """Best-effort clear of a job's cancel flag (it also TTLs out on its own)."""
    try:
        await get_redis().delete(f"{CANCEL_PREFIX}{job_id}")
    except Exception:
        pass


def event_content_text(data: dict) -> str:
    """Extract plain *answer* text from a stream event, regardless of protocol.

    Faithful passthrough events carry text in `data['delta']['content']`;
    legacy events carry it in `data['text']` (unless flagged reasoning, which
    is not answer text). Format adapters that render plain text only — like the
    current Anthropic text block — use this so they work with either worker."""
    delta = data.get("delta")
    if delta is not None:
        return delta.get("content") or ""
    if data.get("reasoning"):
        return ""
    return data.get("text", "")


async def publish_token(
    job_id: str,
    text: str = "",
    reasoning: bool = False,
    delta: dict | None = None,
    finish_reason: str | None = None,
):
    """Publish one stream event to pub/sub AND append to the replay buffer.

    Two shapes flow through here:

    * Faithful passthrough (text generation): `delta` carries the inference
      backend's raw `choices[0].delta` (content / reasoning_content /
      tool_calls). The SSE layer re-wraps it untouched. This is the path that
      makes the grid a transparent OpenAI proxy.
    * Legacy / media: positional `text` (+ `reasoning` flag) — kept so old
      workers and the media progress channel keep working unchanged.

    Every event keeps a `text` key (default "") so the DONE-sentinel check in
    `subscribe_tokens` never KeyErrors on a delta-only event."""
    r = get_redis()
    channel = f"{CHANNEL_PREFIX}{job_id}"
    buf_key = f"{BUFFER_PREFIX}{job_id}"
    event = {"text": text, "reasoning": reasoning}
    if delta is not None:
        event["delta"] = delta
    if finish_reason is not None:
        event["finish_reason"] = finish_reason
    data = json.dumps(event)

    pipe = r.pipeline()
    pipe.publish(channel, data)
    pipe.rpush(buf_key, data)
    pipe.expire(buf_key, BUFFER_TTL)
    await pipe.execute()


async def publish_raw_event(job_id: str, event: str | None, data: str):
    """Relay ONE raw upstream SSE event verbatim (Anthropic / OpenAI-Responses
    passthrough).

    For natively-served formats the grid is a faithful tunnel: the worker reads
    the backend's SSE `event:`/`data:` lines and we forward them byte-for-byte to
    the client, only teeing usage for metering. `event` is the SSE event name
    (may be None for data-only streams); `data` is the raw JSON string."""
    r = get_redis()
    channel = f"{CHANNEL_PREFIX}{job_id}"
    buf_key = f"{BUFFER_PREFIX}{job_id}"
    payload = json.dumps({"text": "", "raw": True, "event": event, "data": data})

    pipe = r.pipeline()
    pipe.publish(channel, payload)
    pipe.rpush(buf_key, payload)
    pipe.expire(buf_key, BUFFER_TTL)
    await pipe.execute()


async def publish_done(
    job_id: str,
    full_text: str = "",
    full_reasoning: str = "",
    tool_calls: list | None = None,
    usage: dict | None = None,
    finish_reason: str = "stop",
    full_json: dict | None = None,
    grid: dict | None = None,
    logprobs: dict | None = None,
):
    """Signal generation complete via pub/sub + buffer.

    Carries the fully-assembled result (content + reasoning + tool_calls) and
    authoritative `usage` so the non-streaming collector can build the final
    message and the streaming layer can emit a trailing usage chunk.

    `grid` is optional provenance metadata (worker, gen_time, ttft, tokens_per_s)
    the API surfaces alongside the response — additive, never alters output."""
    r = get_redis()
    channel = f"{CHANNEL_PREFIX}{job_id}"
    buf_key = f"{BUFFER_PREFIX}{job_id}"
    data = json.dumps({
        "text": DONE_SENTINEL,
        "full_text": full_text,
        "full_reasoning": full_reasoning,
        "tool_calls": tool_calls,
        "usage": usage,
        "finish_reason": finish_reason,
        # For non-streaming raw passthrough (Anthropic/Responses): the complete
        # upstream JSON body, returned to the client unchanged.
        "full_json": full_json,
        "grid": grid,
        "logprobs": logprobs,
    })

    pipe = r.pipeline()
    pipe.publish(channel, data)
    pipe.rpush(buf_key, data)
    pipe.expire(buf_key, BUFFER_TTL)
    await pipe.execute()


async def publish_error(job_id: str, message: str, code: int = 502):
    """Signal an error on the stream (worker disconnected, timeout, bad request).

    `code` is the HTTP status the client should ultimately see — 502 for
    worker/backend failures (the default), 400 for a deterministic caller fault
    surfaced from the backend."""
    r = get_redis()
    channel = f"{CHANNEL_PREFIX}{job_id}"
    buf_key = f"{BUFFER_PREFIX}{job_id}"
    data = json.dumps({"text": DONE_SENTINEL, "error": message, "code": code, "full_text": ""})

    pipe = r.pipeline()
    pipe.publish(channel, data)
    pipe.rpush(buf_key, data)
    pipe.expire(buf_key, BUFFER_TTL)
    await pipe.execute()


async def subscribe_tokens(job_id: str, timeout: int = 300) -> AsyncGenerator[dict, None]:
    """Subscribe to a job's token stream with replay support.

    1. First replays any buffered tokens (catches tokens published before we subscribed)
    2. Then switches to live pub/sub for new tokens
    3. Deduplicates so tokens aren't yielded twice

    Yields dicts with 'text' key until DONE_SENTINEL or timeout.
    """
    r = get_redis()
    buf_key = f"{BUFFER_PREFIX}{job_id}"
    channel = f"{CHANNEL_PREFIX}{job_id}"

    # Subscribe first so we don't miss anything published after buffer read
    pubsub = r.pubsub()
    await pubsub.subscribe(channel)

    seen_count = 0
    done = False

    try:
        # Phase 1: Replay buffered tokens
        buffered = await r.lrange(buf_key, 0, -1)
        for raw in buffered:
            data = json.loads(raw)
            seen_count += 1
            if data["text"] == DONE_SENTINEL:
                yield data
                done = True
                break
            yield data

        if done:
            return

        # Phase 2: ONE cursor over the replay buffer; pub/sub is only a wakeup.
        # The buffer list (grid:tokens:{job}) is the ordered source of truth —
        # every publish rpushes to it AND publishes to the channel. We yield ONLY
        # from the list, advanced by a single monotonic cursor, and treat channel
        # messages as nothing more than "something changed, go read the list."
        # This makes replay idempotent: an event can't be yielded twice (once from
        # the channel, once from an lrange race) because channel payloads are never
        # yielded, and it can't be skipped by two counters drifting apart — there
        # is one cursor. `timeout` stays an IDLE timeout: the deadline is pushed out
        # on every event, so the stream is abandoned only after `timeout` seconds of
        # SILENCE (a dead/stalled worker), never during a slow-but-alive stream.
        cursor = seen_count  # events already yielded from the buffer in Phase 1
        deadline = asyncio.get_event_loop().time() + timeout

        while True:
            remaining = deadline - asyncio.get_event_loop().time()
            if remaining <= 0:
                break

            # Wait for a wakeup (any channel message) or wake ~every second anyway,
            # so we still drain the buffer if a notification is ever missed. A Redis
            # socket read-timeout here is benign — it just means no message arrived
            # in the window; we fall through and poll the list regardless.
            try:
                await asyncio.wait_for(
                    pubsub.get_message(ignore_subscribe_messages=True, timeout=1.0),
                    timeout=min(remaining, 5.0),
                )
            except (asyncio.TimeoutError, redis.exceptions.TimeoutError):
                pass  # no message — poll the list anyway

            new_buffered = await r.lrange(buf_key, cursor, -1)
            for raw in new_buffered:
                data = json.loads(raw)
                cursor += 1
                if data["text"] == DONE_SENTINEL:
                    yield data
                    return
                yield data
                deadline = asyncio.get_event_loop().time() + timeout  # event = alive; reset idle window

    except asyncio.TimeoutError:
        logger.warning(f"Token stream timeout for job {job_id}")
    finally:
        await pubsub.unsubscribe(channel)
        await pubsub.aclose()
