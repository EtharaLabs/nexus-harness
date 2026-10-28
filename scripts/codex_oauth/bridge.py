"""OpenAI Codex (ChatGPT-auth) subscription bridge.

A local, OpenAI-compatible HTTP proxy that lets a harness generate trajectories on
a ChatGPT/Codex *subscription* instead of a metered API key — the OpenAI analogue
of agent/claude_code/bridge.py.

It accepts a Responses-API request on ``/responses`` (or ``/v1/responses``), swaps
the caller's stub key for a live ChatGPT OAuth bearer token, adds the headers the
codex backend requires, forwards to::

    POST https://chatgpt.com/backend-api/codex/responses

and streams the SSE response back byte-for-byte.

Verified live 2026-07-03 (Pro account): with the access token + account id from
``~/.codex/auth.json`` and the headers below, ``gpt-5.5`` returns a 200 Responses
SSE stream (``response.created`` … ``response.completed``).

Required upstream headers (all verified):
    Authorization:      Bearer <access_token>
    ChatGPT-Account-Id: <account_id>
    OpenAI-Beta:        responses=experimental
    originator:         codex_cli_rs
    session_id:         <uuid>            (per request)
    User-Agent:         codex_cli_rs/<ver>

Point your client at it::

    export OPENAI_BASE_URL=http://127.0.0.1:8788      # litellm / openai SDK honor this
    export OPENAI_API_KEY=$NEXUS_CODEX_BRIDGE_SECRET   # stub; bridge substitutes OAuth
    # model: openai/gpt-5.5  (Responses mode)

Security: set NEXUS_CODEX_BRIDGE_SECRET and give clients the same value as
OPENAI_API_KEY; otherwise the bridge is unauthenticated and any local process can
spend the subscription.
"""

from __future__ import annotations

import asyncio
import hmac
import json
import logging
import os
import re
import uuid
from typing import Any, AsyncIterator, Optional

import httpx
from fastapi import FastAPI, Request, Response
from fastapi.responses import JSONResponse, StreamingResponse

from .credentials import (
    CredentialProvider,
    CredentialsError,
    MultiAccountCredentialProvider,
    load_account_pool,
)
from .errors import ErrorKind, classify_openai_error
from . import translate as _xlate

_LOG = logging.getLogger(__name__)

UPSTREAM_DEFAULT = "https://chatgpt.com/backend-api/codex"
RESPONSES_PATH = "/responses"
OAUTH_BETA = "responses=experimental"
ORIGINATOR = "codex_cli_rs"
DEFAULT_USER_AGENT = "codex_cli_rs/0.142.5"

# Headers we always drop from the incoming request before re-signing (hop-by-hop
# or client-auth that we replace). Everything else is passed through.
_STRIP_REQUEST_HEADERS = {
    "host", "authorization", "content-length", "connection", "accept-encoding",
    "openai-organization", "openai-beta", "chatgpt-account-id", "originator",
    "session_id", "user-agent", "x-api-key",
    # `accept` and `content-type` are FORCED below (the codex backend rejects
    # anything but text/event-stream + application/json), so drop any inherited value.
    "accept", "content-type",
}


def _upstream_base() -> str:
    return os.environ.get("NEXUS_CODEX_UPSTREAM", UPSTREAM_DEFAULT).rstrip("/")


def _user_agent() -> str:
    return os.environ.get("NEXUS_CODEX_USER_AGENT", DEFAULT_USER_AGENT)


def _force_store_false() -> bool:
    # ChatGPT-account Codex requests are not server-stored; the codex CLI sends
    # store=false. Default to enforcing it (litellm may send store=true).
    return os.environ.get("NEXUS_CODEX_FORCE_STORE_FALSE", "1").strip().lower() in (
        "1", "true", "yes", "on",
    )


def _bridge_secret() -> str:
    return os.environ.get("NEXUS_CODEX_BRIDGE_SECRET", "").strip()


def _max_inline_retries() -> int:
    """Max in-request account-failover retries before surfacing the upstream
    error. Mirrors claude_code's NEXUS_CODEX_MAX_INLINE_RETRIES (default 3)."""
    try:
        return max(0, int(os.environ.get("NEXUS_CODEX_MAX_INLINE_RETRIES", "")))
    except ValueError:
        return 3


# Option D — buffer-and-retry: buffer the WHOLE upstream Responses SSE stream and
# re-issue on a mid-stream drop so the client only ever receives a COMPLETE
# response (or a clean error), never a truncated one. Parity with claude_code's
# _stream_buffered_with_retry (NEXUS_CODEX_BUFFER_AND_RETRY).
#
# DEFAULT OFF (opt-in): buffering means the client (aider/litellm) gets NO
# incremental output until a turn completes, so a log-based inactivity watchdog
# sees a frozen log for the whole turn and could false-kill a long
# extended-thinking module. The mid-stream drop is already surfaced as an error
# by the terminal-event guard in _stream_with_keepalive (so litellm num_retries /
# recovery.py re-issue), making D a last resort. Enable with
# NEXUS_CODEX_BUFFER_AND_RETRY=1.
def _buffer_and_retry_enabled() -> bool:
    return os.environ.get("NEXUS_CODEX_BUFFER_AND_RETRY", "0").strip().lower() in (
        "1", "true", "yes", "on",
    )


def _max_stream_buffer_retries() -> int:
    try:
        return max(0, int(os.environ.get("NEXUS_CODEX_STREAM_BUFFER_RETRIES", "3")))
    except ValueError:
        return 3


# Seconds of buffering silence before an SSE keep-alive comment is emitted to the
# client so its connection can't time out while the bridge re-issues upstream.
_STREAM_KEEPALIVE_SECS = 15


# A standalone SSE comment line. SSE parsers (and litellm's Responses-API stream
# reader) ignore any line beginning with ":", but forwarding it downstream resets
# the client's read-timeout clock. It is ONLY ever emitted between upstream reads
# (never mid-`data:` chunk), so it can't corrupt a real event.
_KEEPALIVE_LINE = b": keepalive\n\n"


def _keepalive_interval() -> float:
    """Seconds of upstream idle before we emit a downstream SSE keep-alive.

    Default 15s (well under a typical client read-timeout); override via
    NEXUS_CODEX_KEEPALIVE_SEC. A value <= 0 disables keep-alives.
    """
    raw = os.environ.get("NEXUS_CODEX_KEEPALIVE_SEC", "15").strip()
    try:
        return float(raw)
    except ValueError:
        return 15.0


async def _stream_with_keepalive(
    chunks: AsyncIterator[bytes],
    aclose,
    interval: float,
) -> AsyncIterator[bytes]:
    """Forward upstream ``chunks`` byte-for-byte, interleaving an SSE keep-alive
    comment whenever the upstream has been idle for ``interval`` seconds.

    Real chunks are yielded exactly as received. The keep-alive is emitted only
    when NO upstream chunk is in flight (between reads), so it can never land in
    the middle of a ``data:`` event. Stops when the upstream iterator is exhausted
    (``response.completed`` etc.) or raises; always closes the upstream response.
    Cancellation (client disconnect) propagates and the ``finally`` still closes.

    Truncation guard (parity with claude_code's event_stream): a plain socket
    close is NOT proof the turn finished. We watch a rolling byte tail for a
    Responses terminal event (response.completed/.incomplete/.failed); if the
    stream ends WITHOUT one, we inject a synthetic ``response.failed`` frame so
    the client raises instead of recording a truncated turn as a clean stop.
    """
    ait = chunks.__aiter__()
    nxt: Optional[asyncio.Future] = None
    tail = b""
    saw_terminal = False
    try:
        while True:
            nxt = asyncio.ensure_future(ait.__anext__())
            while True:
                try:
                    # Wait for the next upstream chunk, but no longer than the
                    # keep-alive interval. asyncio.shield keeps the pending
                    # __anext__ alive across a timeout so we don't drop a chunk.
                    if interval and interval > 0:
                        chunk = await asyncio.wait_for(asyncio.shield(nxt), interval)
                    else:
                        chunk = await nxt
                except asyncio.TimeoutError:
                    # Upstream idle (stalled or still reasoning): keep the client
                    # connection warm and keep waiting on the SAME pending read.
                    yield _KEEPALIVE_LINE
                    continue
                except StopAsyncIteration:
                    nxt = None
                    if not saw_terminal:
                        # Clean socket close but no terminal event -> truncated.
                        _LOG.warning("codex stream ended without a terminal "
                                     "response event -> signalling truncation")
                        yield _xlate.responses_truncation_error_sse()
                    return
                else:
                    nxt = None
                    tail = (tail + chunk)[-256:]
                    if _xlate.tail_has_terminal_event(tail):
                        saw_terminal = True
                    yield chunk
                    break
    except asyncio.CancelledError:
        # Client disconnected / server shutdown: cancel the in-flight read.
        if nxt is not None and not nxt.done():
            nxt.cancel()
        raise
    finally:
        await aclose()


# ---------------------------------------------------------------------------
# Cap-wait ("hot-swap the account") feature.
#
# When an account hits its subscription cap and there is no other account to
# rotate to (single account, or the whole pool is exhausted), instead of failing
# the agent's turn the bridge can HOLD the request open for a configurable window
# — emitting SSE keep-alives so the client (OpenClaw/LiteLLM) doesn't time out —
# during which the operator swaps the codex account on disk (either `codex login`
# with another ChatGPT account, or replacing ~/.codex/auth.json with a pre-saved
# one). The bridge then reloads the credential from disk and retries the SAME
# request, so the trajectory continues on the fresh account. Opt-in: default 0
# (disabled) keeps the original fail-fast behaviour.
# ---------------------------------------------------------------------------
def _cap_wait_sec() -> float:
    """Seconds to pause on an un-rotatable cap so the operator can swap accounts.
    0 (default) disables the feature. Set via NEXUS_CODEX_CAP_WAIT_SEC."""
    try:
        return max(0.0, float(os.environ.get("NEXUS_CODEX_CAP_WAIT_SEC", "0")))
    except ValueError:
        return 0.0


def _cap_max_waits() -> int:
    """Max swap-and-retry cycles before surfacing the cap. Set via
    NEXUS_CODEX_CAP_MAX_WAITS (default 10)."""
    try:
        return max(0, int(os.environ.get("NEXUS_CODEX_CAP_MAX_WAITS", "10")))
    except ValueError:
        return 10


def _err_is_limit(err_resp) -> bool:
    """True if an error Response from _open_upstream is a cap / rate-limit (i.e.
    a 429-class limit worth pausing to swap the account for)."""
    try:
        status = getattr(err_resp, "status_code", None)
        body = getattr(err_resp, "body", b"") or b""
        return classify_openai_error(status, body).kind in (
            ErrorKind.CAP, ErrorKind.RATE_LIMIT)
    except Exception:  # noqa: BLE001
        return False


def _err_text(err_resp) -> str:
    body = getattr(err_resp, "body", b"") or b""
    if isinstance(body, (bytes, bytearray)):
        body = body.decode("utf-8", "ignore")
    return ("nexus-bridge: subscription cap not cleared within the account-swap "
            f"window; {str(body)[:200]}")


def _secret_eq(candidate: str, secret: str) -> bool:
    # Constant-time compare so a local attacker can't recover the secret by timing.
    return bool(candidate) and hmac.compare_digest(candidate, secret)


def _client_authorized(request: Request) -> bool:
    secret = _bridge_secret()
    if not secret:
        return True  # unauthenticated mode (logged as a warning at startup)
    # Accept the secret via Bearer Authorization or the OpenAI x-api-key header.
    auth = request.headers.get("authorization", "")
    if auth.lower().startswith("bearer ") and _secret_eq(auth[7:].strip(), secret):
        return True
    if _secret_eq(request.headers.get("x-api-key", "").strip(), secret):
        return True
    return False


# A trailing OpenAI date snapshot suffix, e.g. "gpt-5.5-2026-04-23".
_DATE_SUFFIX_RE = re.compile(r"-\d{4}-\d{2}-\d{2}$")

# Responses-API params the ChatGPT/Codex backend REJECTS (400 "Unsupported
# parameter"). The harness/litellm routinely send these (e.g. max_tokens ->
# max_output_tokens, sampling params on a reasoning model); strip them so the
# request is accepted. Extend via NEXUS_CODEX_STRIP_PARAMS (comma-separated).
_DEFAULT_UNSUPPORTED_PARAMS = {
    "max_output_tokens", "temperature", "top_p", "top_logprobs", "logprobs",
    "frequency_penalty", "presence_penalty", "logit_bias", "n", "seed",
}


def _strip_unsupported(body: dict) -> None:
    extra = os.environ.get("NEXUS_CODEX_STRIP_PARAMS", "")
    strip = _DEFAULT_UNSUPPORTED_PARAMS | {p.strip() for p in extra.split(",") if p.strip()}
    for key in strip:
        body.pop(key, None)


def _normalize_model(body: dict) -> None:
    """Map the requested model to one the codex backend accepts.

    The ChatGPT/Codex backend accepts only bare model names (e.g. ``gpt-5.5``) and
    rejects dated snapshots (``gpt-5.5-2026-04-23`` -> 400 "model is not supported")
    that the harness's model registry uses. Strip a trailing date suffix; a full
    override is available via ``NEXUS_CODEX_MODEL``.
    """
    override = os.environ.get("NEXUS_CODEX_MODEL", "").strip()
    if override:
        body["model"] = override
        return
    model = body.get("model")
    if isinstance(model, str) and _DATE_SUFFIX_RE.search(model):
        body["model"] = _DATE_SUFFIX_RE.sub("", model)


def _normalize_input(body: dict) -> None:
    """Coerce a string `input` into the list form the codex backend requires.

    The public Responses API accepts `input` as a bare string, but the codex
    backend (chatgpt.com/backend-api/codex/responses) rejects it with
    400 "Input must be a list". Wrap a string into a single user message so
    clients that send the shorthand (e.g. litellm.responses(input="...")) work.
    """
    inp = body.get("input")
    if isinstance(inp, str):
        body["input"] = [{
            "type": "message",
            "role": "user",
            "content": [{"type": "input_text", "text": inp}],
        }]


def _prepare_body(raw: bytes) -> tuple[bytes, bool]:
    """Normalize the Responses body for the codex backend.

    Returns ``(prepared_bytes, client_wanted_stream)``. The codex backend ONLY
    accepts streaming requests (400 "Stream must be set to true" otherwise), so we
    always force ``stream=true`` upstream and remember what the client asked for:
    if the client wanted a unary response we aggregate the SSE back into one JSON
    object (see ``_aggregate_sse``).

    Also: coerce a string `input` into the required list form, and enforce
    store=false when configured (ChatGPT accounts are not server-stored). Model,
    instructions, tools, reasoning otherwise pass through unchanged.
    """
    try:
        body = json.loads(raw) if raw else {}
    except json.JSONDecodeError:
        return raw, False
    if not isinstance(body, dict):
        return raw, False
    client_wanted_stream = bool(body.get("stream"))
    _normalize_model(body)
    _normalize_input(body)
    _strip_unsupported(body)
    body["stream"] = True  # codex backend requires streaming
    if _force_store_false():
        body["store"] = False
    return json.dumps(body).encode(), client_wanted_stream


def _aggregate_sse(raw_sse: bytes) -> tuple[Optional[dict], Optional[str]]:
    """Collapse a Responses-API SSE stream into the final response object.

    The terminal ``response.completed`` event carries the response metadata + usage
    but an EMPTY ``output`` (the codex backend streams output incrementally). So we
    assemble ``output`` from the ``response.output_item.done`` events (each carries a
    complete item — reasoning, message, tool call — with its text) and splice it
    into the completed response. Returns ``(response_obj, error)``.
    """
    final: Optional[dict] = None
    err: Optional[str] = None
    items: list[dict] = []
    for line in raw_sse.split(b"\n"):
        line = line.strip()
        if not line.startswith(b"data:"):
            continue
        payload = line[5:].strip()
        if payload in (b"", b"[DONE]"):
            continue
        try:
            evt = json.loads(payload)
        except json.JSONDecodeError:
            continue
        etype = evt.get("type", "")
        if etype == "response.output_item.done" and isinstance(evt.get("item"), dict):
            items.append(evt["item"])
        elif etype in ("response.completed", "response.incomplete") and isinstance(evt.get("response"), dict):
            final = evt["response"]
        elif etype == "response.failed":
            final = evt.get("response") if isinstance(evt.get("response"), dict) else None
            err = json.dumps(evt.get("response", evt))
        elif etype == "error":
            err = json.dumps(evt)
    if final is not None and not final.get("output") and items:
        final = {**final, "output": items}
    return final, err


def _forward_headers(request: Request, token: str, account_id: str) -> dict[str, str]:
    headers = {
        k: v for k, v in request.headers.items() if k.lower() not in _STRIP_REQUEST_HEADERS
    }
    headers["Authorization"] = f"Bearer {token}"
    headers["ChatGPT-Account-Id"] = account_id
    headers["OpenAI-Beta"] = OAUTH_BETA
    headers["originator"] = ORIGINATOR
    headers["session_id"] = str(uuid.uuid4())
    headers["User-Agent"] = _user_agent()
    # FORCE these — the codex backend returns 400 "Unsupported content type" for
    # anything else (e.g. a client's default Accept: */*).
    headers["Content-Type"] = "application/json"
    headers["Accept"] = "text/event-stream"
    return headers


def _default_provider():
    """A multi-account pool if NEXUS_CODEX_ACCOUNT_POOL is set, else single-account."""
    pool_spec = os.environ.get("NEXUS_CODEX_ACCOUNT_POOL", "").strip()
    if pool_spec:
        pool = load_account_pool(pool_spec)
        if pool is not None:
            return pool
    return CredentialProvider()


def build_app(provider=None) -> FastAPI:
    """Construct the FastAPI app. `provider` is injected for tests; defaults to a
    multi-account pool (if NEXUS_CODEX_ACCOUNT_POOL is set) or a single-account
    CredentialProvider reading ~/.codex/auth.json."""
    provider = provider or _default_provider()
    app = FastAPI(title="codex-bridge")
    # Long-lived async client tuned for 100+ parallel modules (B3 audit fix).
    # - max_connections=200: comfortably above 100 concurrent modules;
    #   default 100 was tight for large batches (see docs/BRIDGE_QC.md).
    # - max_keepalive_connections=100: keep sockets warm for burst re-use.
    # - pool timeout 60s (was 15s): under contention, brief waits are safer than
    #   failing the request. Read timeout stays 1800s for reasoning turns.
    _pool_limits = httpx.Limits(
        max_connections=int(os.environ.get("NEXUS_CODEX_HTTP_MAX_CONN", "200")),
        max_keepalive_connections=int(os.environ.get("NEXUS_CODEX_HTTP_MAX_KEEPALIVE", "100")),
    )
    client = httpx.AsyncClient(
        timeout=httpx.Timeout(connect=15.0, read=1800.0, write=60.0, pool=60.0),
        limits=_pool_limits,
    )

    if not _bridge_secret():
        _LOG.warning(
            "NEXUS_CODEX_BRIDGE_SECRET is not set — the bridge is UNAUTHENTICATED; "
            "any local process can spend this subscription. Set it (and point "
            "clients' OPENAI_API_KEY at the same value) to lock it down."
        )

    @app.get("/healthz")
    async def healthz() -> JSONResponse:  # noqa: D401
        try:
            # Off the event loop: get_access_token may block on a sync httpx
            # token refresh; one refresh must not freeze every concurrent request.
            token = await asyncio.to_thread(provider.get_access_token)
            return JSONResponse({"ok": True, "token_prefix": token[:12] + "...",
                                 "account_prefix": provider.account_id[:8] + "..."})
        except CredentialsError as e:
            return JSONResponse({"ok": False, "error": str(e)}, status_code=503)

    @app.get("/quota")
    async def quota() -> JSONResponse:  # noqa: D401
        if isinstance(provider, MultiAccountCredentialProvider):
            return JSONResponse({"multi_account": True, **provider.status()})
        return JSONResponse({"multi_account": False,
                             "account_prefix": provider.account_id[:8] + "..."})

    def _reject_unauthorized(request: Request) -> Optional[Response]:
        if not _client_authorized(request):
            return JSONResponse({"error": {"message": "bridge: unauthorized (bad OPENAI_API_KEY)",
                                           "type": "authentication_error"}}, status_code=401)
        return None

    async def _open_upstream(request: Request, body: bytes):
        """POST the prepared body to the codex backend, WITH in-request account
        failover for a multi-account pool.

        Returns ``(upstream, None)`` once a 2xx stream opens, or
        ``(None, error_Response)`` on a fatal / non-failover-able error.

        On a per-account failure (cap / rate-limit -> cooldown+rotate, or a 401
        AUTH -> permanently invalidate the slot) with a pool that still has a
        healthy account, we RE-FETCH a fresh token and retry inline rather than
        forwarding the first cap straight to the client. A ``_tried_tokens`` spin
        guard (B9) stops us re-driving a slot whose marking didn't stick. This
        ports agent/claude_code/bridge.py::_forward_non_streaming / _stream_with_failover.
        """
        multi = isinstance(provider, MultiAccountCredentialProvider)
        max_retries = _max_inline_retries()
        attempt = 0
        tried_tokens: set[str] = set()
        last_err_resp: Optional[Response] = None

        while True:
            try:
                # Atomic (token + account_id from the SAME slot) and off the event
                # loop (a sync httpx refresh must not freeze concurrent requests).
                token, account = await asyncio.to_thread(provider.get_token_and_account)
            except CredentialsError as e:
                if last_err_resp is not None:
                    # Pool drained mid-failover: surface the real upstream error.
                    return None, last_err_resp
                return None, JSONResponse(
                    {"error": {"message": f"bridge: {e}", "type": "credentials_error"}},
                    status_code=503)

            # B9: never re-drive an account already burned this call (its
            # cooldown/invalid marking didn't stick) — stop rather than spin.
            if token in tried_tokens and last_err_resp is not None:
                _LOG.warning("codex failover re-selected an already-failed account; "
                             "stopping to avoid a spin (tried %d)", len(tried_tokens))
                return None, last_err_resp

            headers = _forward_headers(request, token, account)
            url = _upstream_base() + RESPONSES_PATH
            upstream_req = client.build_request("POST", url, content=body, headers=headers)
            try:
                upstream = await client.send(upstream_req, stream=True)
            except httpx.HTTPError as e:
                return None, JSONResponse(
                    {"error": {"message": f"bridge: upstream request failed: {e}",
                               "type": "upstream_error"}}, status_code=502)
            if upstream.status_code < 400:
                return upstream, None

            err = await upstream.aread()
            await upstream.aclose()
            classified = classify_openai_error(
                upstream.status_code, err, dict(upstream.headers))
            _LOG.warning("codex upstream %s [%s]: %s",
                         upstream.status_code, classified.kind.value, err[:300])
            media = upstream.headers.get("content-type", "application/json")
            err_resp = Response(content=err, status_code=upstream.status_code, media_type=media)

            # In-request failover applies only to a multi-account pool on a
            # per-account failure. A cap/rate-limit cools the slot; a 401 AUTH
            # permanently invalidates it (its refresh token is revoked).
            account_problem = classified.should_rotate_account or classified.should_refresh_token
            if multi and account_problem:
                tried_tokens.add(token)
                if classified.should_refresh_token:
                    provider.mark_invalid(token)
                else:
                    provider.mark_exhausted(token, classified.retry_after or 900)
                last_err_resp = err_resp
                # Retry with the next account only if a healthy slot is usable now
                # (next_reset_at() is None) and we're within budget; else surface
                # the upstream error. Floor the retry so a marking-miss can't spin.
                if attempt < max_retries and provider.next_reset_at() is None:
                    attempt += 1
                    await asyncio.sleep(0.05)
                    continue
                return None, last_err_resp

            # Non-failover error (400/404/single-account/etc.): return immediately.
            return None, err_resp

    async def _open_unary_with_cap_wait(request: Request, body: bytes):
        """Non-streaming open with cap-wait: on an un-rotatable cap, sleep the
        swap window, reload the credential from disk, and retry. No keep-alive is
        needed — the unary client (LiteLLM, request_timeout 24h) simply waits."""
        cycle = 0
        while True:
            upstream, err_resp = await _open_upstream(request, body)
            if upstream is not None or not (
                _cap_wait_sec() > 0 and _err_is_limit(err_resp) and cycle < _cap_max_waits()
            ):
                return upstream, err_resp
            cycle += 1
            _LOG.warning(
                "codex cap hit — SWAP YOUR ACCOUNT NOW (`codex login` with another "
                "account, or replace ~/.codex/auth.json). Waiting %.0fs then retrying "
                "(cycle %d/%d).", _cap_wait_sec(), cycle, _cap_max_waits())
            await asyncio.sleep(_cap_wait_sec())
            try:
                await asyncio.to_thread(provider.reload)
            except Exception as e:  # noqa: BLE001 — reload is best-effort; retry anyway
                _LOG.warning("codex credential reload failed: %s", e)

    async def _stream_with_cap_wait(request: Request, body: bytes,
                                    chat_model: Optional[str] = None,
                                    created: int = 0) -> AsyncIterator[bytes]:
        """Streaming open with cap-wait. Emits SSE keep-alives during each swap
        window so the client can't time out while the operator hot-swaps the codex
        account; then reloads the credential from disk and retries the SAME
        request. ``chat_model`` set => translate the upstream Responses SSE into
        Chat-Completions SSE; else forward the Responses SSE raw."""
        cycle = 0
        while True:
            upstream, err_resp = await _open_upstream(request, body)
            if upstream is not None:
                if chat_model is not None:
                    try:
                        async for chunk in _xlate.aiter_responses_sse_as_chat(
                                upstream.aiter_lines(), chat_model, created):
                            yield chunk
                    finally:
                        await upstream.aclose()
                else:
                    async for chunk in _stream_with_keepalive(
                            upstream.aiter_raw(), upstream.aclose, _keepalive_interval()):
                        yield chunk
                return
            # Error opening upstream. Only a cap/rate-limit is worth a swap-wait.
            if not (_cap_wait_sec() > 0 and _err_is_limit(err_resp)
                    and cycle < _cap_max_waits()):
                if chat_model is not None:
                    yield _xlate.chat_truncation_error_sse(_err_text(err_resp))
                    yield b"data: [DONE]\n\n"
                else:
                    yield _xlate.responses_truncation_error_sse(_err_text(err_resp))
                return
            cycle += 1
            _LOG.warning(
                "codex cap hit — SWAP YOUR ACCOUNT NOW (`codex login` with another "
                "account, or replace ~/.codex/auth.json). Holding the turn open, "
                "waiting %.0fs then retrying (cycle %d/%d).",
                _cap_wait_sec(), cycle, _cap_max_waits())
            waited = 0.0
            while waited < _cap_wait_sec():
                yield _KEEPALIVE_LINE  # keep OpenClaw/LiteLLM alive during the swap
                step = min(float(_STREAM_KEEPALIVE_SECS), _cap_wait_sec() - waited)
                await asyncio.sleep(step)
                waited += step
            try:
                await asyncio.to_thread(provider.reload)
            except Exception as e:  # noqa: BLE001 — reload is best-effort; retry anyway
                _LOG.warning("codex credential reload failed: %s", e)

    async def _stream_buffered_with_retry(request: Request, body: bytes) -> Response:
        """Option D — buffer the ENTIRE upstream Responses SSE stream and re-issue
        on a mid-stream drop, so the client only ever receives a COMPLETE response
        (or a clean error), never a truncated one. Opt-in via
        NEXUS_CODEX_BUFFER_AND_RETRY. Parity port of claude_code's
        _stream_buffered_with_retry (which buffers Anthropic SSE the same way).

        Trade vs the incremental keep-alive path: no incremental token delivery
        (the whole response replays at once), so the harness inactivity watchdog
        sees a frozen log for the turn — hence default-off. SSE keep-alive
        comments keep the client<->bridge socket warm while buffering/retrying.
        """
        max_retries = _max_stream_buffer_retries()

        async def _capture() -> tuple[str, bytes]:
            """(kind, body) where kind in {'ok','error','incomplete'}. 'ok' body
            is a complete Responses SSE stream ready to replay verbatim."""
            attempt = 0
            while True:
                # _open_upstream owns token acquisition + in-request account
                # failover, so buffered mode inherits pool failover for free.
                upstream, err_resp = await _open_upstream(request, body)
                if err_resp is not None:
                    return ("error", getattr(err_resp, "body", b"") or b"")
                buf = bytearray()
                tail = b""
                saw_terminal = False
                try:
                    async for chunk in upstream.aiter_raw():
                        buf += chunk
                        tail = (tail + chunk)[-256:]
                        if _xlate.tail_has_terminal_event(tail):
                            saw_terminal = True
                except Exception as e:  # noqa: BLE001 — mid-stream read/connect drop
                    _LOG.warning("codex buffered stream: upstream drop (attempt %d/%d): %s",
                                 attempt + 1, max_retries, e)
                finally:
                    await upstream.aclose()
                if saw_terminal:
                    return ("ok", bytes(buf))  # complete stream captured
                attempt += 1
                if attempt > max_retries:
                    _LOG.error("codex buffered stream: still incomplete after %d retries",
                               max_retries)
                    return ("incomplete", b"")
                await asyncio.sleep(min(2 ** attempt, 30))
                _LOG.info("codex buffered stream: re-issuing upstream (attempt %d/%d)",
                          attempt, max_retries)

        async def event_stream():
            task = asyncio.create_task(_capture())
            try:
                while not task.done():
                    try:
                        await asyncio.wait_for(asyncio.shield(task), timeout=_STREAM_KEEPALIVE_SECS)
                    except asyncio.TimeoutError:
                        yield _KEEPALIVE_LINE  # keep the client<->bridge socket warm
                kind, captured = task.result()
                if kind == "ok":
                    yield captured
                elif kind == "error":
                    yield _xlate.responses_truncation_error_sse(
                        "nexus-bridge: upstream error (buffered)")
                else:  # incomplete
                    yield _xlate.responses_truncation_error_sse(
                        "nexus-bridge: upstream stream incomplete after retries")
            finally:
                if not task.done():
                    task.cancel()

        return StreamingResponse(event_stream(), media_type="text/event-stream",
                                 headers={"X-Nexus-Bridge-Mode": "buffer-and-retry"})

    async def _proxy_responses(request: Request) -> Response:
        unauth = _reject_unauthorized(request)
        if unauth is not None:
            return unauth

        raw = await request.body()
        body, client_wanted_stream = _prepare_body(raw)
        if client_wanted_stream and _buffer_and_retry_enabled():
            return await _stream_buffered_with_retry(request, body)
        if client_wanted_stream:
            # cap-wait aware: opens upstream inside the generator so a cap can be
            # ridden out (keep-alive + account swap + reload) mid-stream.
            return StreamingResponse(
                _stream_with_cap_wait(request, body),
                status_code=200, media_type="text/event-stream")

        upstream, err_resp = await _open_unary_with_cap_wait(request, body)
        if err_resp is not None:
            return err_resp
        raw_sse = await upstream.aread()
        await upstream.aclose()
        final, err = _aggregate_sse(raw_sse)
        if final is None:
            msg = err or "bridge: upstream stream produced no response.completed event"
            return JSONResponse({"error": {"message": msg, "type": "upstream_error"}}, status_code=502)
        return JSONResponse(final, status_code=200)

    async def _proxy_chat(request: Request) -> Response:
        """/chat/completions -> translate to Responses, forward, translate back.

        Lets any OpenAI Chat-Completions client (the harness preflight probe,
        litellm without responses-mode registration, the openai SDK) drive the
        codex backend, which only speaks the Responses API.
        """
        unauth = _reject_unauthorized(request)
        if unauth is not None:
            return unauth

        try:
            chat_req = json.loads(await request.body() or b"{}")
        except json.JSONDecodeError:
            return JSONResponse({"error": {"message": "bridge: invalid JSON body",
                                           "type": "invalid_request_error"}}, status_code=400)
        model = chat_req.get("model", "")
        client_wanted_stream = bool(chat_req.get("stream"))

        resp_body = _xlate.chat_to_responses(chat_req)
        # Reuse the Responses body prep (model normalization, forced stream/store).
        prepared, _ = _prepare_body(json.dumps(resp_body).encode())
        # normalized model for the echoed response
        try:
            model = json.loads(prepared).get("model", model)
        except json.JSONDecodeError:
            pass

        created = _xlate.now_ts()
        if client_wanted_stream:
            # Translate the upstream Responses SSE into Chat-Completions SSE
            # INCREMENTALLY (do not buffer the whole turn) so incremental output
            # keeps a log-based liveness watchdog fed and latency stays low.
            # cap-wait aware: the open happens inside the generator so a cap can
            # be ridden out (keep-alive + account swap + reload) mid-stream.
            return StreamingResponse(
                _stream_with_cap_wait(request, prepared, chat_model=model, created=created),
                status_code=200, media_type="text/event-stream")

        upstream, err_resp = await _open_unary_with_cap_wait(request, prepared)
        if err_resp is not None:
            return err_resp
        raw_sse = await upstream.aread()
        await upstream.aclose()
        final, err = _aggregate_sse(raw_sse)
        if final is None:
            msg = err or "bridge: upstream stream produced no response.completed event"
            return JSONResponse({"error": {"message": msg, "type": "upstream_error"}}, status_code=502)
        return JSONResponse(_xlate.responses_to_chat(final, model, created), status_code=200)

    # Responses API (native path — preferred when the client uses responses mode).
    @app.post("/responses")
    async def responses(request: Request) -> Response:
        return await _proxy_responses(request)

    @app.post("/v1/responses")
    async def v1_responses(request: Request) -> Response:
        return await _proxy_responses(request)

    @app.post("/backend-api/codex/responses")
    async def native_responses(request: Request) -> Response:
        return await _proxy_responses(request)

    # Chat Completions API (translated to Responses) — the drop-in compatibility path.
    @app.post("/chat/completions")
    async def chat_completions(request: Request) -> Response:
        return await _proxy_chat(request)

    @app.post("/v1/chat/completions")
    async def v1_chat_completions(request: Request) -> Response:
        return await _proxy_chat(request)

    @app.on_event("shutdown")
    async def _shutdown() -> None:
        await client.aclose()

    return app
