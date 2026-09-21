"""Anthropic-compatible FastAPI proxy backed by Claude Code OAuth.

Listens locally and forwards every request to ``api.anthropic.com`` with:

  Authorization: Bearer <oauth-token>     (replaces incoming x-api-key)
  anthropic-beta: oauth-2025-04-20[,...]  (merged with caller-supplied betas)
  anthropic-version: 2023-06-01           (only added if caller didn't set one)

On ``POST /v1/messages`` the bridge also injects the required
"You are Claude Code, Anthropic's official CLI for Claude." system prefix.
Anthropic rejects OAuth-scoped messages without it. Injection is idempotent
and preserves any caller-supplied system content.

Point the OpenHands SDK / litellm at the bridge by giving the harness an LLM
config whose ``base_url`` is the bridge (model must be ``anthropic/...`` so
litellm speaks the native Messages API)::

    {"model": "anthropic/claude-opus-4-8",
     "base_url": "http://host.docker.internal:8765",
     "api_key": "sk-ant-oauth-bridge-stub"}

The stub key is required because litellm refuses to start without one; the
bridge strips it before forwarding.

Resilience: the bridge retries transient 429/529 inline (short waits), and
if a multi-account pool is configured (``AURORA_CC_ACCOUNT_POOL``) failover
to a different account on subscription-cap exhaustion. See ``errors.py``
for the classification heuristics.
"""

from __future__ import annotations

import asyncio
import json
import logging
import os
import time
from typing import Any, Union

import httpx
from fastapi import FastAPI, Request, Response
from fastapi.responses import JSONResponse, StreamingResponse

from .credentials import (
    CredentialProvider,
    CredentialsError,
    MultiAccountCredentialProvider,
    load_account_pool,
)
from .errors import (
    ClassifiedError,
    ErrorKind,
    classify_anthropic_error,
)


_LOG = logging.getLogger(__name__)

UPSTREAM_DEFAULT = "https://api.anthropic.com"
DEFAULT_ANTHROPIC_VERSION = "2023-06-01"
OAUTH_BETA = "oauth-2025-04-20"
SYSTEM_PREFIX = "You are Claude Code, Anthropic's official CLI for Claude."

# Resilience tuning knobs (overridable via env).
DEFAULT_MAX_INLINE_RETRIES = 3
DEFAULT_MAX_INLINE_WAIT_SECONDS = 30
DEFAULT_REQUEST_TIMEOUT = 600.0
# Per-chunk read timeout: how long httpx waits for the NEXT byte of an in-flight
# response. With Opus 4.8 + extended thinking + ~96k context, single-turn
# reasoning can pause for 90-150s between streamed chunks. The previous httpx
# default (5s on read) caused MidStreamFallbackError storms. 180s gives the
# model headroom while still flagging genuine stalls. Configurable via
# AURORA_BRIDGE_READ_TIMEOUT (seconds, integer or float).
DEFAULT_READ_TIMEOUT = 180.0
DEFAULT_CONNECT_TIMEOUT = 30.0


def _bridge_timeout() -> "httpx.Timeout":
    """Build the httpx.Timeout for upstream calls, honoring env overrides.

    Env vars (all optional, all in seconds):
      - AURORA_BRIDGE_REQUEST_TIMEOUT  (overall, default 600)
      - AURORA_BRIDGE_READ_TIMEOUT     (per-chunk read, default 180)
      - AURORA_BRIDGE_CONNECT_TIMEOUT  (TCP connect, default 30)"""

    def _f(env, default):
        try:
            return float(os.environ.get(env, "").strip() or default)
        except (ValueError, TypeError):
            return default

    total = _f("AURORA_BRIDGE_REQUEST_TIMEOUT", DEFAULT_REQUEST_TIMEOUT)
    read = _f("AURORA_BRIDGE_READ_TIMEOUT", DEFAULT_READ_TIMEOUT)
    connect = _f("AURORA_BRIDGE_CONNECT_TIMEOUT", DEFAULT_CONNECT_TIMEOUT)
    # httpx.Timeout takes a default (total) + named pool params.
    return httpx.Timeout(total, connect=connect, read=read)


# Headers that must never propagate inbound -> upstream.
STRIP_HEADERS_IN = frozenset(
    {
        "host",
        "authorization",
        "x-api-key",
        "content-length",
        "connection",
        "accept-encoding",
        "proxy-authorization",
    }
)
# Headers we must never copy upstream -> client (chunking, encoding artifacts).
STRIP_HEADERS_OUT = frozenset(
    {
        "content-encoding",
        "transfer-encoding",
        "connection",
        "content-length",
    }
)


# Either a single-account or multi-account provider is acceptable -- both
# expose ``get_access_token() -> str`` and ``force_reload() -> None``.
ProviderLike = Union[CredentialProvider, MultiAccountCredentialProvider]


def _upstream_base() -> str:
    return os.environ.get("AURORA_CC_UPSTREAM", UPSTREAM_DEFAULT).rstrip("/")


def _max_inline_retries() -> int:
    try:
        return max(0, int(os.environ.get("AURORA_CC_MAX_INLINE_RETRIES", "")))
    except ValueError:
        return DEFAULT_MAX_INLINE_RETRIES


def _max_inline_wait_seconds() -> int:
    try:
        return max(0, int(os.environ.get("AURORA_CC_MAX_INLINE_WAIT", "")))
    except ValueError:
        return DEFAULT_MAX_INLINE_WAIT_SECONDS


def inject_system_prefix(body: dict[str, Any]) -> dict[str, Any]:
    """Ensure the Claude Code system prefix is present in ``body['system']``.

    Handles the three shapes the Messages API accepts:
        - ``system`` absent
        - ``system`` is a plain string
        - ``system`` is a list of content blocks

    Idempotent: if the prefix is already present anywhere in the existing
    system content, the body is returned unchanged.
    """
    system = body.get("system")

    if isinstance(system, str):
        if SYSTEM_PREFIX in system:
            return body
        body["system"] = f"{SYSTEM_PREFIX}\n\n{system}"
        return body

    if isinstance(system, list):
        existing_text = " ".join(
            blk.get("text", "")
            for blk in system
            if isinstance(blk, dict) and blk.get("type") == "text"
        )
        if SYSTEM_PREFIX in existing_text:
            return body
        body["system"] = [{"type": "text", "text": SYSTEM_PREFIX}, *system]
        return body

    body["system"] = [{"type": "text", "text": SYSTEM_PREFIX}]
    return body


_IMAGE_MAGIC = (("/9j/", "image/jpeg"), ("iVBORw0KGgo", "image/png"),
                ("R0lGOD", "image/gif"), ("UklGR", "image/webp"))


def fix_image_media_types(node: Any) -> int:
    """Set each base64 image block's ``media_type`` from its bytes.

    Clients label images by file extension (OpenHands does), so a JPEG saved as
    ``.png`` arrives as ``image/png`` and the API rejects the whole request, every
    time, because the image stays in the conversation. Returns how many were fixed.
    """
    fixed = 0
    if isinstance(node, dict):
        src = node.get("source")
        if node.get("type") == "image" and isinstance(src, dict) and src.get("type") == "base64":
            data = src.get("data") or ""
            real = next((mt for magic, mt in _IMAGE_MAGIC if data.startswith(magic)), None)
            if real and src.get("media_type") != real:
                src["media_type"] = real
                fixed += 1
        for value in node.values():
            fixed += fix_image_media_types(value)
    elif isinstance(node, list):
        for value in node:
            fixed += fix_image_media_types(value)
    return fixed


def request_thinking(body: dict[str, Any]) -> bool:
    """Ask for the reasoning summary the trajectory records as `thought`.

    Two settings must both be right, and the caller supplies neither. `display`
    defaults to "omitted" per model for Opus 5 and its siblings, and litellm turns
    OpenHands' reasoning_effort into {"type": "enabled", "budget_tokens": N},
    which returns an empty thinking block whatever `display` says. Only
    {"type": "adaptive", "display": "summarized"} comes back with text.

    Dropping budget_tokens is deliberate: under adaptive the model sizes its own
    thinking and max_tokens is pinned separately. A caller that explicitly
    disables thinking is left alone. Set BRIDGE_THINKING_DISPLAY='' to revert.
    """
    display = os.environ.get("BRIDGE_THINKING_DISPLAY", "summarized").strip()
    if not display:
        return False
    thinking = body.get("thinking")
    if isinstance(thinking, dict) and thinking.get("type") == "disabled":
        return False
    wanted = {"type": "adaptive", "display": display}
    if thinking == wanted:
        return False
    body["thinking"] = wanted
    return True


def _normalize_path(path: str) -> str:
    return path.lstrip("/")


def _is_streaming_payload(raw_body: bytes) -> bool:
    # Cheap substring probe avoids reparsing JSON. False positives are
    # harmless (worst case we stream a non-streaming response).
    return b'"stream":true' in raw_body or b'"stream": true' in raw_body


def _build_forward_headers(request_headers: Any, access_token: str) -> dict[str, str]:
    fwd: dict[str, str] = {}
    for k, v in request_headers.items():
        if k.lower() in STRIP_HEADERS_IN:
            continue
        fwd[k] = v
    fwd["Authorization"] = f"Bearer {access_token}"

    # Merge anthropic-beta values, case-insensitive.
    incoming_beta = ""
    for hdr_key in list(fwd.keys()):
        if hdr_key.lower() == "anthropic-beta":
            incoming_beta = fwd.pop(hdr_key)
    betas = [b.strip() for b in incoming_beta.split(",") if b.strip()]
    if OAUTH_BETA not in betas:
        betas.insert(0, OAUTH_BETA)
    fwd["anthropic-beta"] = ",".join(betas)

    if not any(k.lower() == "anthropic-version" for k in fwd):
        fwd["anthropic-version"] = DEFAULT_ANTHROPIC_VERSION
    return fwd


def _token_prefix(token: str) -> str:
    return token[:20] if token else ""


def _apply_classification_to_provider(
    provider: ProviderLike,
    token_used: str,
    classified: ClassifiedError,
) -> None:
    """Mark account state on the provider based on an upstream classification.

    Only the multi-account provider tracks per-account state; for the single
    provider we just ``force_reload`` on a token-invalid signal so the next
    request re-fetches from Keychain (in case the ``claude`` CLI rotated it).
    """
    # Pass the FULL token so the provider can attribute the error to the exact
    # slot that produced it (it matches on slot.last_token); a 20-char prefix is
    # ambiguous because all OAuth tokens share the `sk-ant-oat01-` prefix.
    if isinstance(provider, MultiAccountCredentialProvider):
        if classified.kind == ErrorKind.SUBSCRIPTION_CAP:
            reset_at = classified.reset_at_unix or (
                time.time() + (classified.retry_after_seconds or 300)
            )
            provider.mark_account_exhausted(token_used, reset_at)
        elif classified.kind in (
            ErrorKind.OAUTH_TOKEN_INVALID,
            ErrorKind.ACCOUNT_RESTRICTED,
            ErrorKind.BILLING_ERROR,
        ):
            provider.mark_account_invalid(token_used)
    else:
        if classified.kind == ErrorKind.OAUTH_TOKEN_INVALID:
            provider.force_reload()


def _build_error_response(classified: ClassifiedError) -> JSONResponse:
    """Return a structured error response to the client."""
    headers: dict[str, str] = {"X-Aurora-Bridge-Error": classified.kind.value}
    if classified.retry_after_seconds is not None:
        headers["Retry-After"] = str(max(1, classified.retry_after_seconds))
    if classified.reset_at_unix is not None:
        headers["X-Aurora-Reset-At"] = f"{classified.reset_at_unix:.0f}"
    body = {
        "type": "error",
        "error": {
            "type": classified.raw_error_type or "rate_limit_error",
            "message": classified.message,
        },
        "aurora_bridge": {
            "kind": classified.kind.value,
            "retry_after_seconds": classified.retry_after_seconds,
            "reset_at_unix": classified.reset_at_unix,
            "request_id": classified.request_id,
        },
    }
    return JSONResponse(body, status_code=classified.status_code, headers=headers)


async def _forward_non_streaming(
    provider: ProviderLike,
    request_method: str,
    url: str,
    raw_body: bytes,
    headers_in: Any,
    params: dict[str, str],
) -> Response:
    """Send a non-streaming request with retry + failover."""
    max_retries = _max_inline_retries()
    max_wait = _max_inline_wait_seconds()
    attempt = 0
    last_response: Union[httpx.Response, None] = None

    while True:
        try:
            # get_access_token() may block: Keychain subprocess, sync httpx
            # refresh with time.sleep backoff, and a blocking flock. Run it off
            # the event loop so one refresh can't freeze every concurrent request.
            access_token = await asyncio.to_thread(provider.get_access_token)
        except CredentialsError as e:
            return JSONResponse(
                {
                    "type": "error",
                    "error": {"type": "authentication_error", "message": str(e)},
                    "aurora_bridge": {"kind": "credentials_unavailable"},
                },
                status_code=401,
            )

        fwd_headers = _build_forward_headers(headers_in, access_token)
        if request_method in ("POST", "PUT", "PATCH"):
            fwd_headers.setdefault("content-type", "application/json")

        async with httpx.AsyncClient(timeout=_bridge_timeout()) as client:
            try:
                upstream = await client.request(
                    request_method,
                    url,
                    content=raw_body,
                    headers=fwd_headers,
                    params=params,
                )
            except httpx.HTTPError as e:
                _LOG.warning("upstream network error: %s", e)
                if attempt >= max_retries:
                    return JSONResponse(
                        {
                            "type": "error",
                            "error": {"type": "api_error", "message": str(e)},
                            "aurora_bridge": {"kind": "network_error"},
                        },
                        status_code=502,
                    )
                attempt += 1
                await asyncio.sleep(min(2**attempt, max_wait))
                continue

        last_response = upstream
        if 200 <= upstream.status_code < 300:
            resp_headers = {
                k: v
                for k, v in upstream.headers.items()
                if k.lower() not in STRIP_HEADERS_OUT
            }
            return Response(
                content=upstream.content,
                status_code=upstream.status_code,
                headers=resp_headers,
                media_type=upstream.headers.get("content-type"),
            )

        classified = classify_anthropic_error(
            upstream.status_code, upstream.content, upstream.headers
        )
        _LOG.info(
            "upstream error: status=%d kind=%s retry_after=%s request_id=%s",
            upstream.status_code,
            classified.kind.value,
            classified.retry_after_seconds,
            classified.request_id,
        )
        _apply_classification_to_provider(provider, access_token, classified)

        # Failover path: account problem + multi-account pool has another slot.
        if classified.kind.is_account_problem and isinstance(
            provider, MultiAccountCredentialProvider
        ):
            if provider.next_reset_at() is None:
                attempt += 1
                if attempt > max_retries:
                    break
                continue  # retry with next account

        # Inline retry on transient throttle or upstream 5xx within budget.
        if classified.kind.is_retryable:
            wait = classified.retry_after_seconds or (2**attempt)
            if attempt < max_retries and wait <= max_wait:
                attempt += 1
                _LOG.info(
                    "transient %s, sleeping %ds (attempt %d/%d)",
                    classified.kind.value,
                    wait,
                    attempt,
                    max_retries,
                )
                await asyncio.sleep(wait)
                continue

        return _build_error_response(classified)

    # Loop fell through (all retries exhausted on account-problem path).
    if last_response is not None:
        classified = classify_anthropic_error(
            last_response.status_code, last_response.content, last_response.headers
        )
        return _build_error_response(classified)
    return JSONResponse(
        {
            "type": "error",
            "error": {"type": "api_error", "message": "max retries exceeded"},
            "aurora_bridge": {"kind": "max_retries_exceeded"},
        },
        status_code=502,
    )


async def _stream_with_failover(
    provider: ProviderLike,
    request_method: str,
    url: str,
    raw_body: bytes,
    headers_in: Any,
    params: dict[str, str],
) -> Response:
    """Streaming variant: probe upstream first to classify failures cleanly.

    We open the stream and peek at the status; only on 2xx do we hand off
    to a chunk-passthrough generator. On 4xx/5xx we drain the body for the
    classifier and return a structured error / failover-retry just like
    the non-streaming path.
    """
    max_retries = _max_inline_retries()
    max_wait = _max_inline_wait_seconds()
    attempt = 0

    while True:
        try:
            # get_access_token() may block: Keychain subprocess, sync httpx
            # refresh with time.sleep backoff, and a blocking flock. Run it off
            # the event loop so one refresh can't freeze every concurrent request.
            access_token = await asyncio.to_thread(provider.get_access_token)
        except CredentialsError as e:
            return JSONResponse(
                {
                    "type": "error",
                    "error": {"type": "authentication_error", "message": str(e)},
                    "aurora_bridge": {"kind": "credentials_unavailable"},
                },
                status_code=401,
            )

        fwd_headers = _build_forward_headers(headers_in, access_token)
        fwd_headers.setdefault("content-type", "application/json")

        client = httpx.AsyncClient(timeout=_bridge_timeout())
        try:
            upstream_cm = client.stream(
                request_method,
                url,
                content=raw_body,
                headers=fwd_headers,
                params=params,
            )
            upstream = await upstream_cm.__aenter__()
        except httpx.HTTPError as e:
            await client.aclose()
            _LOG.warning("upstream stream open error: %s", e)
            if attempt >= max_retries:
                return JSONResponse(
                    {
                        "type": "error",
                        "error": {"type": "api_error", "message": str(e)},
                        "aurora_bridge": {"kind": "network_error"},
                    },
                    status_code=502,
                )
            attempt += 1
            await asyncio.sleep(min(2**attempt, max_wait))
            continue

        if 200 <= upstream.status_code < 300:

            async def event_stream():
                try:
                    async for chunk in upstream.aiter_bytes():
                        yield chunk
                finally:
                    await upstream_cm.__aexit__(None, None, None)
                    await client.aclose()

            # Forward the upstream status and headers (request-id,
            # anthropic-ratelimit-*) instead of hardcoding 200 / dropping them,
            # so clients keep rate-limit visibility and debugging IDs.
            passthrough_headers = {
                k: v
                for k, v in upstream.headers.items()
                if k.lower() not in STRIP_HEADERS_OUT
            }
            return StreamingResponse(
                event_stream(),
                status_code=upstream.status_code,
                headers=passthrough_headers,
                media_type=upstream.headers.get("content-type", "text/event-stream"),
            )

        # Non-2xx: drain body for classification and unwind the stream.
        body_bytes = b""
        try:
            async for chunk in upstream.aiter_bytes():
                body_bytes += chunk
                if len(body_bytes) > 65536:
                    break
        finally:
            await upstream_cm.__aexit__(None, None, None)
            await client.aclose()

        classified = classify_anthropic_error(
            upstream.status_code, body_bytes, upstream.headers
        )
        _LOG.info(
            "upstream stream error: status=%d kind=%s retry_after=%s",
            upstream.status_code,
            classified.kind.value,
            classified.retry_after_seconds,
        )
        _apply_classification_to_provider(provider, access_token, classified)

        if classified.kind.is_account_problem and isinstance(
            provider, MultiAccountCredentialProvider
        ):
            if provider.next_reset_at() is None:
                attempt += 1
                if attempt > max_retries:
                    return _build_error_response(classified)
                continue

        if classified.kind.is_retryable:
            wait = classified.retry_after_seconds or (2**attempt)
            if attempt < max_retries and wait <= max_wait:
                attempt += 1
                await asyncio.sleep(wait)
                continue

        return _build_error_response(classified)


def _resolve_provider() -> ProviderLike:
    """Pick single-account or multi-account provider based on env."""
    pool_spec = os.environ.get("AURORA_CC_ACCOUNT_POOL", "").strip()
    if pool_spec:
        pool = load_account_pool(pool_spec)
        if pool is not None:
            _LOG.info("Using multi-account pool with %d slots", len(pool.snapshot()))
            return pool
    return CredentialProvider()


def build_app(provider: ProviderLike | None = None) -> FastAPI:
    app = FastAPI(title="Claude Code OAuth Bridge (aurora)", version="1.1.0")
    prov: ProviderLike = provider if provider is not None else _resolve_provider()
    inject = os.environ.get("AURORA_CC_SKIP_SYSTEM_PREFIX") != "1"

    @app.get("/healthz")
    async def healthz():
        try:
            token = prov.get_access_token()
        except CredentialsError as e:
            return JSONResponse(
                {"ok": False, "error": str(e)},
                status_code=503,
            )
        info: dict[str, Any] = {"ok": True, "token_prefix": token[:15] + "..."}
        if isinstance(prov, MultiAccountCredentialProvider):
            info["accounts"] = prov.snapshot()
        return info

    @app.get("/quota")
    async def quota():
        """Pipeline introspection: per-account exhaustion + soonest reset."""
        if isinstance(prov, MultiAccountCredentialProvider):
            return {
                "multi_account": True,
                "accounts": prov.snapshot(),
                "next_reset_at_unix": prov.next_reset_at(),
            }
        return {"multi_account": False, "accounts": [], "next_reset_at_unix": None}

    @app.api_route(
        "/{path:path}",
        methods=["GET", "POST", "PUT", "DELETE", "PATCH"],
    )
    async def proxy(path: str, request: Request) -> Response:
        raw_body = await request.body()
        norm_path = _normalize_path(path)

        # Inject "You are Claude Code" prefix on /v1/messages POSTs.
        if (
            inject
            and norm_path == "v1/messages"
            and request.method == "POST"
            and raw_body
        ):
            try:
                body_json = json.loads(raw_body)
                if isinstance(body_json, dict):
                    body_json = inject_system_prefix(body_json)
                    n_fixed = fix_image_media_types(body_json.get("messages"))
                    if n_fixed:
                        _LOG.info("corrected media_type on %d image block(s)", n_fixed)
                    if request_thinking(body_json):
                        _LOG.debug("requested adaptive/summarized thinking")
                    raw_body = json.dumps(body_json).encode("utf-8")
            except ValueError as e:
                _LOG.warning("Skipping system-prefix injection (bad JSON): %s", e)

        url = f"{_upstream_base()}/{norm_path}"
        params = dict(request.query_params)

        if _is_streaming_payload(raw_body):
            return await _stream_with_failover(
                prov, request.method, url, raw_body, request.headers, params
            )
        return await _forward_non_streaming(
            prov, request.method, url, raw_body, request.headers, params
        )

    return app


app = build_app()
