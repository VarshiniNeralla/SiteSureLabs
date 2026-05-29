"""vLLM OpenAI-compatible chat completions (multimodal PMO inspection)."""

from __future__ import annotations

import base64
import json
import logging
import re
from collections.abc import AsyncIterator
from typing import Any

import httpx

from config import get_settings
from prompt import (
    CONSTRUCTION_RELEVANCE_CLASSIFIER_PROMPT,
    EXECUTIVE_DEFECT_REPORT_PROMPT,
    PMO_DEFECT_INSPECTION_PROMPT,
)
from services.report_defect_extract import fields_from_parsed, parse_executive_defect_json
from services import vision_analysis_cache as vac
from services.http_client import (
    VLLMUnavailable,
    ensure_circuit_closed,
    get_client,
    post_json_with_retry,
    vllm_breaker,
)

logger = logging.getLogger(__name__)


def _data_url(image_bytes: bytes, mime_type: str) -> str:
    b64 = base64.standard_b64encode(image_bytes).decode("ascii")
    return f"data:{mime_type};base64,{b64}"


def _vllm_404_hint(status_code: int, url: str) -> str:
    """404 on /v1/chat/completions usually means VLLM_BASE_URL points at FastAPI (wrong port)."""
    if status_code != 404:
        return ""
    if "/v1/chat/completions" not in url:
        return ""
    return (
        " — Likely cause: Defectra (uvicorn) and vLLM share the same port, so POST /v1/chat/completions "
        "hits FastAPI (404). Fix: run vLLM on one port and Defectra on another (e.g. vLLM :8000 with "
        "VLLM_BASE_URL=http://127.0.0.1:8000, uvicorn on :8010 and VITE_API_PROXY_TARGET=http://127.0.0.1:8010), "
        "or run vLLM on :8001 and set VLLM_BASE_URL=http://127.0.0.1:8001."
    )


def _format_http_error(resp: httpx.Response) -> str:
    try:
        err: Any = resp.json()
    except json.JSONDecodeError:
        body = (resp.text or "").strip()
        if not body:
            return f"vLLM returned HTTP {resp.status_code} with no parseable body."
        return f"vLLM HTTP {resp.status_code}: {body[:2000]}"

    if isinstance(err, dict):
        nested = err.get("error")
        if isinstance(nested, dict):
            msg = nested.get("message")
            if isinstance(msg, str) and msg.strip():
                return f"vLLM error ({resp.status_code}): {msg.strip()}"
        detail = err.get("detail")
        if detail is not None:
            if isinstance(detail, str):
                return f"vLLM error ({resp.status_code}): {detail}"
            return f"vLLM error ({resp.status_code}): {json.dumps(detail)[:1500]}"
        return f"vLLM error ({resp.status_code}): {json.dumps(err)[:1500]}"
    return f"vLLM error ({resp.status_code}): {str(err)[:1500]}"


def _message_content_to_string(content: Any) -> str:
    if content is None:
        return ""
    if isinstance(content, str):
        return content.strip()
    if isinstance(content, list):
        parts: list[str] = []
        for part in content:
            if not isinstance(part, dict):
                continue
            if part.get("type") == "text":
                t = part.get("text")
                if isinstance(t, str) and t.strip():
                    parts.append(t.strip())
        return "\n\n".join(parts).strip()
    return str(content).strip()


def _extract_assistant_text(data: dict[str, Any]) -> str:
    choices = data.get("choices")
    if not isinstance(choices, list) or not choices:
        raise RuntimeError(
            "The model response had no choices. Check VLLM_MODEL matches --served-model-name."
        )
    first = choices[0]
    if not isinstance(first, dict):
        raise RuntimeError("The model response choices[0] was not an object.")
    msg = first.get("message")
    if not isinstance(msg, dict):
        raise RuntimeError("The model response had no choices[0].message object.")
    text = _message_content_to_string(msg.get("content"))
    if not text:
        raise RuntimeError(
            "The model returned an empty choices[0].message.content. "
            "Try lowering image size or increasing VLLM_MAX_TOKENS."
        )
    return text


def _vision_temperature() -> float:
    """Temperature 0 for repeatable vision outputs (cache misses still stay stable)."""
    return 0.0


def _optional_llm_seed() -> int | None:
    import os

    raw = os.getenv("VLLM_SEED", "").strip()
    if not raw:
        return None
    try:
        return int(raw)
    except ValueError:
        return None


def _build_chat_body(
    *,
    model: str,
    instructions: str,
    data_url: str,
    temperature: float,
    max_tokens: int,
    stream: bool = False,
) -> dict[str, Any]:
    body: dict[str, Any] = {
        "model": model,
        "messages": [
            {
                "role": "user",
                "content": [
                    {"type": "text", "text": instructions},
                    {"type": "image_url", "image_url": {"url": data_url}},
                ],
            }
        ],
        "temperature": temperature,
        "max_tokens": max_tokens,
    }
    seed = _optional_llm_seed()
    if seed is not None:
        body["seed"] = seed
    if stream:
        body["stream"] = True
    return body


def _stream_cached_text(text: str, *, chunk_size: int = 160) -> list[str]:
    if not text:
        return []
    if len(text) <= chunk_size:
        return [text]
    return [text[i : i + chunk_size] for i in range(0, len(text), chunk_size)]


def _parse_construction_relevance_json(text: str) -> bool | None:
    """Return True/False from model JSON, or None if unparseable."""
    t = (text or "").strip()
    if not t:
        return None
    if "```" in t:
        t = re.sub(r"^```(?:json)?\s*", "", t, flags=re.IGNORECASE)
        t = re.sub(r"\s*```\s*$", "", t)
        t = t.strip()
    start = t.find("{")
    end = t.rfind("}")
    if start == -1 or end <= start:
        return None
    try:
        obj: Any = json.loads(t[start : end + 1])
    except json.JSONDecodeError:
        return None
    if not isinstance(obj, dict):
        return None
    for key in ("relevant", "construction_relevant", "is_construction", "site_related"):
        if key not in obj:
            continue
        v = obj[key]
        if isinstance(v, bool):
            return v
        if isinstance(v, str):
            low = v.strip().lower()
            if low in ("true", "yes", "1"):
                return True
            if low in ("false", "no", "0"):
                return False
    return None


async def classify_construction_site_image(
    *,
    image_bytes: bytes,
    mime_type: str,
) -> bool:
    """
    True → run full PMO inspection. False → show non-construction message.
    On transport/parse errors, returns True (fail open) so real site photos still analyze.
    """
    settings = get_settings()
    if vac.cache_enabled():
        cache_key = vac.build_cache_key(
            kind=vac.KIND_CONSTRUCTION,
            image_bytes=image_bytes,
            prompt=CONSTRUCTION_RELEVANCE_CLASSIFIER_PROMPT,
            model=settings.vllm_model,
        )
        cached = await vac.get_construction_relevance(cache_key)
        if cached is not None:
            return cached

    url = settings.chat_completions_url()
    body = _build_chat_body(
        model=settings.vllm_model,
        instructions=CONSTRUCTION_RELEVANCE_CLASSIFIER_PROMPT,
        data_url=_data_url(image_bytes, mime_type),
        temperature=0.0,
        max_tokens=128,
        stream=False,
    )

    headers: dict[str, str] = {"Content-Type": "application/json"}
    if settings.vllm_api_key.strip():
        headers["Authorization"] = f"Bearer {settings.vllm_api_key.strip()}"

    try:
        resp = await post_json_with_retry(
            url,
            json=body,
            headers=headers,
            timeout=httpx.Timeout(30.0, connect=10.0),
        )
    except VLLMUnavailable:
        logger.warning("construction relevance classifier: vLLM circuit open — failing open")
        return True
    except httpx.RequestError:
        logger.exception("construction relevance classifier: vLLM request failed")
        return True

    if resp.status_code >= 400:
        logger.warning("construction relevance classifier: HTTP %s", resp.status_code)
        return True

    try:
        data = resp.json()
    except json.JSONDecodeError:
        logger.warning("construction relevance classifier: non-JSON body")
        return True

    if not isinstance(data, dict):
        return True

    try:
        raw = _extract_assistant_text(data)
    except RuntimeError as e:
        logger.warning("construction relevance classifier: %s", e)
        return True

    parsed = _parse_construction_relevance_json(raw)
    if parsed is None:
        logger.warning(
            "construction relevance classifier: could not parse: %r", raw[:500]
        )
        return True

    if vac.cache_enabled():
        cache_key = vac.build_cache_key(
            kind=vac.KIND_CONSTRUCTION,
            image_bytes=image_bytes,
            prompt=CONSTRUCTION_RELEVANCE_CLASSIFIER_PROMPT,
            model=settings.vllm_model,
        )
        await vac.store_construction_relevance(
            cache_key=cache_key,
            model=settings.vllm_model,
            relevant=parsed,
        )
    return parsed


def _delta_content_from_sse_payload(obj: dict[str, Any]) -> str:
    choices = obj.get("choices")
    if not isinstance(choices, list) or not choices:
        return ""
    first = choices[0]
    if not isinstance(first, dict):
        return ""
    delta = first.get("delta")
    if not isinstance(delta, dict):
        return ""
    content = delta.get("content")
    if isinstance(content, str):
        return content
    return ""


async def generate_inspection_report(
    *,
    image_bytes: bytes,
    mime_type: str,
    prompt: str | None = None,
) -> str:
    settings = get_settings()
    instructions = prompt or PMO_DEFECT_INSPECTION_PROMPT
    if vac.cache_enabled():
        cache_key = vac.build_cache_key(
            kind=vac.KIND_PMO_MARKDOWN,
            image_bytes=image_bytes,
            prompt=instructions,
            model=settings.vllm_model,
        )
        cached = await vac.get_pmo_markdown(cache_key)
        if cached is not None:
            return cached

    url = settings.chat_completions_url()
    body = _build_chat_body(
        model=settings.vllm_model,
        instructions=instructions,
        data_url=_data_url(image_bytes, mime_type),
        temperature=_vision_temperature(),
        max_tokens=settings.vllm_max_tokens,
    )

    headers: dict[str, str] = {"Content-Type": "application/json"}
    if settings.vllm_api_key.strip():
        headers["Authorization"] = f"Bearer {settings.vllm_api_key.strip()}"

    try:
        resp = await post_json_with_retry(url, json=body, headers=headers)
    except httpx.RequestError as e:
        logger.exception("vLLM request failed")
        raise RuntimeError(
            f"Could not reach vLLM at {url}. Is the server running and reachable? ({e})"
        ) from e

    if resp.status_code >= 400:
        raise RuntimeError(_format_http_error(resp) + _vllm_404_hint(resp.status_code, url))

    try:
        data = resp.json()
    except json.JSONDecodeError as e:
        raw = (resp.text or "")[:2000]
        logger.warning("vLLM non-JSON body: %s", raw)
        raise RuntimeError(
            "The vision server returned a response that was not valid JSON. "
            f"First bytes: {raw[:500]!r}"
        ) from e

    if not isinstance(data, dict):
        raise RuntimeError(
            "The vision server returned JSON that was not an object; cannot read choices."
        )

    text = _extract_assistant_text(data)
    if vac.cache_enabled():
        cache_key = vac.build_cache_key(
            kind=vac.KIND_PMO_MARKDOWN,
            image_bytes=image_bytes,
            prompt=instructions,
            model=settings.vllm_model,
        )
        await vac.store_pmo_markdown(
            cache_key=cache_key,
            model=settings.vllm_model,
            text=text,
        )
    return text


async def generate_executive_defect_report(
    *,
    image_bytes: bytes,
    mime_type: str,
    prompt: str | None = None,
) -> tuple[str, str, str, str]:
    """
    Vision call for admin reports: structured JSON → defect, observation, recommendation, severity.
    Retries once if JSON parse or validation yields no usable bullets.
    """
    settings = get_settings()
    instructions = prompt or EXECUTIVE_DEFECT_REPORT_PROMPT
    if vac.cache_enabled():
        cache_key = vac.build_cache_key(
            kind=vac.KIND_EXECUTIVE,
            image_bytes=image_bytes,
            prompt=instructions,
            model=settings.vllm_model,
        )
        cached = await vac.get_executive_fields(cache_key)
        if cached is not None:
            return cached

    last_raw = ""

    for attempt in range(2):
        attempt_prompt = instructions
        if attempt == 1:
            attempt_prompt = (
                f"{instructions.strip()}\n\n"
                "Your previous reply was invalid. Reply with ONLY one JSON object using keys "
                "defect, observations, recommendations, and severity (LOW|MEDIUM|HIGH). "
                "The defect value must be a short 1 to 4 word label. Each array item must "
                "be one complete short sentence with no trailing conjunctions."
            )
        raw = await generate_inspection_report(
            image_bytes=image_bytes,
            mime_type=mime_type,
            prompt=attempt_prompt,
        )
        last_raw = raw
        parsed = parse_executive_defect_json(raw)
        if parsed is not None:
            obs_field, rec_field, severity, defect = fields_from_parsed(parsed)
            has_obs = bool(parsed.get("observations"))
            has_rec = bool(parsed.get("recommendations"))
            if has_obs or has_rec or "• No defect observed" in obs_field:
                if vac.cache_enabled():
                    cache_key = vac.build_cache_key(
                        kind=vac.KIND_EXECUTIVE,
                        image_bytes=image_bytes,
                        prompt=instructions,
                        model=settings.vllm_model,
                    )
                    await vac.store_executive_fields(
                        cache_key=cache_key,
                        model=settings.vllm_model,
                        observation=obs_field,
                        recommendation=rec_field,
                        severity=severity,
                        defect=defect,
                    )
                return obs_field, rec_field, severity, defect
        logger.warning(
            "executive defect report: parse/validation failed (attempt %s): %r",
            attempt + 1,
            (raw or "")[:400],
        )

    logger.error(
        "executive defect report: using fallback after failed parse; last=%r",
        last_raw[:500],
    )
    fallback = parse_executive_defect_json(last_raw) if last_raw else None
    if fallback:
        obs_field, rec_field, severity, defect = fields_from_parsed(fallback)
        if vac.cache_enabled():
            cache_key = vac.build_cache_key(
                kind=vac.KIND_EXECUTIVE,
                image_bytes=image_bytes,
                prompt=instructions,
                model=settings.vllm_model,
            )
            await vac.store_executive_fields(
                cache_key=cache_key,
                model=settings.vllm_model,
                observation=obs_field,
                recommendation=rec_field,
                severity=severity,
                defect=defect,
            )
        return obs_field, rec_field, severity, defect
    obs, rec, sev, defect = fields_from_parsed({"observations": [], "recommendations": [], "severity": "MEDIUM"})
    obs_field, rec_field, severity = ("• No defect observed", rec, sev)
    if vac.cache_enabled():
        cache_key = vac.build_cache_key(
            kind=vac.KIND_EXECUTIVE,
            image_bytes=image_bytes,
            prompt=instructions,
            model=settings.vllm_model,
        )
        await vac.store_executive_fields(
            cache_key=cache_key,
            model=settings.vllm_model,
            observation=obs_field,
            recommendation=rec_field,
            severity=severity,
            defect=defect,
        )
    return obs_field, rec_field, severity, defect


async def stream_inspection_report_deltas(
    *,
    image_bytes: bytes,
    mime_type: str,
    prompt: str | None = None,
) -> AsyncIterator[str]:
    """Yield assistant text fragments from vLLM OpenAI-compatible SSE stream."""
    settings = get_settings()
    instructions = prompt or PMO_DEFECT_INSPECTION_PROMPT
    if vac.cache_enabled():
        cache_key = vac.build_cache_key(
            kind=vac.KIND_PMO_MARKDOWN,
            image_bytes=image_bytes,
            prompt=instructions,
            model=settings.vllm_model,
        )
        cached = await vac.get_pmo_markdown(cache_key)
        if cached is not None:
            for piece in _stream_cached_text(cached):
                yield piece
            return

    url = settings.chat_completions_url()
    body = _build_chat_body(
        model=settings.vllm_model,
        instructions=instructions,
        data_url=_data_url(image_bytes, mime_type),
        temperature=_vision_temperature(),
        max_tokens=settings.vllm_max_tokens,
        stream=True,
    )

    headers: dict[str, str] = {"Content-Type": "application/json"}
    if settings.vllm_api_key.strip():
        headers["Authorization"] = f"Bearer {settings.vllm_api_key.strip()}"

    collected: list[str] = []
    completed = False  # True only when the stream ends with [DONE]
    ensure_circuit_closed()
    client = await get_client()
    try:
        async with client.stream("POST", url, json=body, headers=headers) as resp:
            if resp.status_code >= 400:
                err_bytes = await resp.aread()
                try:
                    err_json = json.loads(err_bytes.decode("utf-8"))
                    detail = err_json.get("error", err_json)
                    if isinstance(detail, dict) and "message" in detail:
                        detail = detail["message"]
                except Exception:
                    detail = err_bytes.decode("utf-8", errors="replace")[:2000]
                raise RuntimeError(
                    f"vLLM error ({resp.status_code}): {detail}"
                    + _vllm_404_hint(resp.status_code, url)
                )

            async for line in resp.aiter_lines():
                raw = line.strip()
                if not raw or raw.startswith(":"):
                    continue
                if not raw.startswith("data:"):
                    continue
                payload = raw[5:].lstrip()
                if payload == "[DONE]":
                    completed = True
                    break
                try:
                    obj: Any = json.loads(payload)
                except json.JSONDecodeError:
                    continue
                if not isinstance(obj, dict):
                    continue
                err = obj.get("error")
                if isinstance(err, dict):
                    msg = err.get("message", json.dumps(err))
                    raise RuntimeError(f"vLLM stream error: {msg}")
                piece = _delta_content_from_sse_payload(obj)
                if piece:
                    collected.append(piece)
                    yield piece
        vllm_breaker.record_success()
    except httpx.RequestError as e:
        vllm_breaker.record_failure()
        logger.exception("vLLM stream request failed")
        raise RuntimeError(
            f"Could not reach vLLM at {url}. Is the server running and reachable? ({e})"
        ) from e

    # Only cache a fully-completed response. A stream that ends early (upstream truncation, vLLM
    # crash, client disconnect) leaves `completed=False`, so partial output is never cached and
    # later served as if it were the deterministic result.
    if vac.cache_enabled() and completed and collected:
        cache_key = vac.build_cache_key(
            kind=vac.KIND_PMO_MARKDOWN,
            image_bytes=image_bytes,
            prompt=instructions,
            model=settings.vllm_model,
        )
        await vac.store_pmo_markdown(
            cache_key=cache_key,
            model=settings.vllm_model,
            text="".join(collected),
        )


async def stream_text_chat_completion_deltas(
    *,
    messages: list[dict[str, Any]],
    max_tokens: int | None = None,
    temperature: float | None = None,
) -> AsyncIterator[str]:
    """Yield assistant text fragments from vLLM OpenAI-compatible SSE (text-only chat)."""
    settings = get_settings()
    url = settings.chat_completions_url()
    cap = max_tokens if max_tokens is not None else settings.vllm_max_tokens
    body: dict[str, Any] = {
        "model": settings.vllm_model,
        "messages": messages,
        "temperature": (
            settings.vllm_temperature if temperature is None else temperature
        ),
        "max_tokens": cap,
        "stream": True,
    }

    headers: dict[str, str] = {"Content-Type": "application/json"}
    if settings.vllm_api_key.strip():
        headers["Authorization"] = f"Bearer {settings.vllm_api_key.strip()}"

    ensure_circuit_closed()
    client = await get_client()
    try:
        async with client.stream("POST", url, json=body, headers=headers) as resp:
            if resp.status_code >= 400:
                err_bytes = await resp.aread()
                try:
                    err_json = json.loads(err_bytes.decode("utf-8"))
                    detail = err_json.get("error", err_json)
                    if isinstance(detail, dict) and "message" in detail:
                        detail = detail["message"]
                except Exception:
                    detail = err_bytes.decode("utf-8", errors="replace")[:2000]
                raise RuntimeError(
                    f"vLLM error ({resp.status_code}): {detail}"
                    + _vllm_404_hint(resp.status_code, url)
                )

            async for line in resp.aiter_lines():
                raw = line.strip()
                if not raw or raw.startswith(":"):
                    continue
                if not raw.startswith("data:"):
                    continue
                payload = raw[5:].lstrip()
                if payload == "[DONE]":
                    break
                try:
                    obj: Any = json.loads(payload)
                except json.JSONDecodeError:
                    continue
                if not isinstance(obj, dict):
                    continue
                err = obj.get("error")
                if isinstance(err, dict):
                    msg = err.get("message", json.dumps(err))
                    raise RuntimeError(f"vLLM stream error: {msg}")
                piece = _delta_content_from_sse_payload(obj)
                if piece:
                    yield piece
        vllm_breaker.record_success()
    except httpx.RequestError as e:
        vllm_breaker.record_failure()
        logger.exception("vLLM text stream request failed")
        raise RuntimeError(
            f"Could not reach vLLM at {url}. Is the server running and reachable? ({e})"
        ) from e


async def generate_text_chat_completion(
    *,
    messages: list[dict[str, Any]],
    max_tokens: int | None = None,
    temperature: float | None = None,
) -> str:
    """Text-only OpenAI-style chat (follow-up questions; no image re-send)."""
    settings = get_settings()
    url = settings.chat_completions_url()
    cap = max_tokens if max_tokens is not None else settings.vllm_max_tokens
    body: dict[str, Any] = {
        "model": settings.vllm_model,
        "messages": messages,
        "temperature": (
            settings.vllm_temperature if temperature is None else temperature
        ),
        "max_tokens": cap,
        "stream": False,
    }

    headers: dict[str, str] = {"Content-Type": "application/json"}
    if settings.vllm_api_key.strip():
        headers["Authorization"] = f"Bearer {settings.vllm_api_key.strip()}"

    try:
        resp = await post_json_with_retry(url, json=body, headers=headers)
    except httpx.RequestError as e:
        logger.exception("vLLM text chat request failed")
        raise RuntimeError(
            f"Could not reach vLLM at {url}. Is the server running and reachable? ({e})"
        ) from e

    if resp.status_code >= 400:
        raise RuntimeError(_format_http_error(resp) + _vllm_404_hint(resp.status_code, url))

    try:
        data = resp.json()
    except json.JSONDecodeError as e:
        raw = (resp.text or "")[:2000]
        raise RuntimeError(
            "The model server returned a response that was not valid JSON. "
            f"First bytes: {raw[:500]!r}"
        ) from e

    if not isinstance(data, dict):
        raise RuntimeError("The model returned JSON that was not an object.")
    return _extract_assistant_text(data)
