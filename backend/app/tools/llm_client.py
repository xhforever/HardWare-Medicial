"""
MediGenius — tools/llm_client.py
OpenAI-compatible LLM client singleton.
"""

import json
import os
import threading
import time
from typing import Any, Dict

from app.core.config import (
    LIGHT_LLM_MODEL,
    LLM_MODEL,
    MODEL_ROUTING_CONFIG_PATH,
    OPENAI_API_KEY,
    OPENAI_BASE_URL,
    OPENAI_WIRE_API,
)
from app.core.logging_config import logger
from app.services.token_budget_service import estimate_tokens

_llm_instance = None
_light_llm_instance = None
_llm_instances: Dict[tuple, Any] = {}
_light_llm_instances: Dict[tuple, Any] = {}
_instances_lock = threading.Lock()
_routing_cache: Dict[str, Any] = {"mtime": None, "data": {}}
_routing_lock = threading.Lock()


def _content_blocks_to_text(content: Any) -> str:
    if isinstance(content, str):
        return content
    if isinstance(content, list):
        parts: list[str] = []
        for item in content:
            if isinstance(item, str):
                parts.append(item)
                continue
            if isinstance(item, dict):
                text = item.get("text") or item.get("content")
                if isinstance(text, str):
                    parts.append(text)
        return "".join(parts)
    return str(content or "")


def coerce_response_text(response: Any) -> str:
    """Normalize LangChain response/chunk objects to plain text."""
    content = response.content if hasattr(response, "content") else response
    return _content_blocks_to_text(content)


def _resolve_model_name(llm: Any, fallback: str = "") -> str:
    for attr in ("model_name", "model"):
        value = getattr(llm, attr, None)
        if isinstance(value, str) and value.strip():
            return value
    return fallback


def _record_llm_metric(
    state: Dict[str, Any] | None,
    *,
    node_name: str,
    model_name: str,
    prompt: str,
    output_text: str,
    latency_ms: float,
    success: bool,
) -> None:
    if state is None:
        return
    node_metrics = state.setdefault("node_metrics", {})
    metric = node_metrics.setdefault(node_name, {})
    metric.update(
        {
            "model": model_name,
            "prompt_tokens": estimate_tokens(prompt, model=model_name),
            "completion_tokens": estimate_tokens(output_text, model=model_name),
            "latency_ms": round(latency_ms, 2),
            "success": bool(success),
        }
    )
    logger.info(
        "LLM metrics node=%s model=%s prompt_tokens=%s completion_tokens=%s latency_ms=%.2f success=%s",
        node_name,
        metric["model"],
        metric["prompt_tokens"],
        metric["completion_tokens"],
        metric["latency_ms"],
        metric["success"],
    )


def invoke_with_metrics(
    llm: Any,
    prompt: str,
    *,
    node_name: str,
    state: Dict[str, Any] | None = None,
    fallback_model: str = "",
):
    start = time.perf_counter()
    model_name = _resolve_model_name(llm, fallback=fallback_model)
    try:
        response = llm.invoke(prompt)
        elapsed_ms = (time.perf_counter() - start) * 1000
        output_text = coerce_response_text(response)
        _record_llm_metric(
            state,
            node_name=node_name,
            model_name=model_name,
            prompt=prompt,
            output_text=output_text,
            latency_ms=elapsed_ms,
            success=True,
        )
        return response
    except Exception:
        elapsed_ms = (time.perf_counter() - start) * 1000
        _record_llm_metric(
            state,
            node_name=node_name,
            model_name=model_name,
            prompt=prompt,
            output_text="",
            latency_ms=elapsed_ms,
            success=False,
        )
        raise


async def astream_with_metrics(
    llm: Any,
    prompt: str,
    *,
    node_name: str,
    state: Dict[str, Any] | None = None,
    fallback_model: str = "",
):
    start = time.perf_counter()
    model_name = _resolve_model_name(llm, fallback=fallback_model)
    parts: list[str] = []
    try:
        async for chunk in llm.astream(prompt):
            text = coerce_response_text(chunk)
            if text:
                parts.append(text)
            yield chunk
        elapsed_ms = (time.perf_counter() - start) * 1000
        _record_llm_metric(
            state,
            node_name=node_name,
            model_name=model_name,
            prompt=prompt,
            output_text="".join(parts),
            latency_ms=elapsed_ms,
            success=True,
        )
    except Exception:
        elapsed_ms = (time.perf_counter() - start) * 1000
        _record_llm_metric(
            state,
            node_name=node_name,
            model_name=model_name,
            prompt=prompt,
            output_text="".join(parts),
            latency_ms=elapsed_ms,
            success=False,
        )
        raise


def _load_routing_config() -> Dict[str, Any]:
    path = MODEL_ROUTING_CONFIG_PATH
    if not path or not os.path.exists(path):
        with _routing_lock:
            _routing_cache["mtime"] = None
            _routing_cache["data"] = {}
        return {}

    try:
        mtime = os.path.getmtime(path)
    except OSError:
        return {}

    with _routing_lock:
        if _routing_cache.get("mtime") == mtime:
            cached = _routing_cache.get("data")
            return cached if isinstance(cached, dict) else {}

        try:
            with open(path, "r", encoding="utf-8") as f:
                loaded = json.load(f)
            if not isinstance(loaded, dict):
                loaded = {}
            _routing_cache["mtime"] = mtime
            _routing_cache["data"] = loaded
            logger.info("LLM routing config reloaded from %s", path)
            return loaded
        except Exception as exc:
            logger.warning("Failed to read LLM routing config (%s): %s", path, exc)
            _routing_cache["mtime"] = mtime
            _routing_cache["data"] = {}
            return {}


def _merge_non_empty(base: Dict[str, Any], patch: Dict[str, Any]) -> Dict[str, Any]:
    merged = dict(base)
    for k, v in (patch or {}).items():
        if v is None:
            continue
        if isinstance(v, str) and not v.strip():
            continue
        merged[k] = v
    return merged


def _normalize_routing_block(block: Dict[str, Any]) -> Dict[str, Any]:
    if not isinstance(block, dict):
        return {}
    return {
        "api_key": block.get("api_key"),
        "base_url": block.get("base_url"),
        "model": block.get("model") or block.get("llm_model"),
        "light_model": block.get("light_model") or block.get("light_llm_model"),
    }


def _resolve_llm_config(tenant_id: str, user_id: str) -> Dict[str, Any]:
    resolved = {
        "api_key": OPENAI_API_KEY,
        "base_url": OPENAI_BASE_URL,
        "model": LLM_MODEL,
        "light_model": LIGHT_LLM_MODEL,
    }
    routing = _load_routing_config()
    if not routing:
        return resolved

    resolved = _merge_non_empty(
        resolved,
        _normalize_routing_block(routing.get("default") or {}),
    )

    tenant_cfg = ((routing.get("tenants") or {}).get(tenant_id) or {})
    resolved = _merge_non_empty(resolved, _normalize_routing_block(tenant_cfg))

    user_cfg = ((tenant_cfg.get("users") or {}).get(user_id) or {})
    resolved = _merge_non_empty(resolved, _normalize_routing_block(user_cfg))
    return resolved


def get_llm(*, tenant_id: str = "default", user_id: str = "anonymous"):
    """Return a cached ChatOpenAI instance for main generation (tenant/user isolated)."""
    global _llm_instance
    cfg = _resolve_llm_config(tenant_id, user_id)
    api_key = cfg.get("api_key")
    model = cfg.get("model") or LLM_MODEL
    base_url = cfg.get("base_url")

    if not api_key:
        logger.warning("OPENAI_API_KEY not found in environment variables")
        return None

    cache_key = ("main", tenant_id, user_id, model, base_url, api_key)
    with _instances_lock:
        cached = _llm_instances.get(cache_key)
        if cached is not None:
            if tenant_id == "default" and user_id == "anonymous":
                _llm_instance = cached
            return cached

        try:
            from langchain_openai import ChatOpenAI
        except Exception as exc:
            logger.warning("langchain_openai unavailable for main LLM client: %s", exc)
            return None
        use_responses_api = OPENAI_WIRE_API == "responses"
        kwargs = {
            "api_key": api_key,
            "model": model,
            "temperature": 0.3,
        }
        if use_responses_api:
            kwargs["use_responses_api"] = True
            kwargs["max_completion_tokens"] = 2048
        else:
            kwargs["max_tokens"] = 2048
        if base_url:
            kwargs["base_url"] = base_url

        instance = ChatOpenAI(**kwargs)
        _llm_instances[cache_key] = instance
        if tenant_id == "default" and user_id == "anonymous":
            _llm_instance = instance
        logger.info(
            "LLM client initialized (tenant=%s user=%s / %s)",
            tenant_id,
            user_id,
            model,
        )
        return instance


def get_light_llm(*, tenant_id: str = "default", user_id: str = "anonymous"):
    """Return cached lightweight LLM instance (tenant/user isolated)."""
    global _light_llm_instance
    cfg = _resolve_llm_config(tenant_id, user_id)
    api_key = cfg.get("api_key")
    model = cfg.get("light_model") or cfg.get("model") or LIGHT_LLM_MODEL
    base_url = cfg.get("base_url")

    if not api_key:
        logger.warning("OPENAI_API_KEY not found in environment variables")
        return None

    cache_key = ("light", tenant_id, user_id, model, base_url, api_key)
    with _instances_lock:
        cached = _light_llm_instances.get(cache_key)
        if cached is not None:
            if tenant_id == "default" and user_id == "anonymous":
                _light_llm_instance = cached
            return cached

        try:
            from langchain_openai import ChatOpenAI
        except Exception as exc:
            logger.warning("langchain_openai unavailable for light LLM client: %s", exc)
            return None
        use_responses_api = OPENAI_WIRE_API == "responses"
        kwargs = {
            "api_key": api_key,
            "model": model,
            "temperature": 0.0,
        }
        if use_responses_api:
            kwargs["use_responses_api"] = True
            kwargs["max_completion_tokens"] = 128
        else:
            kwargs["max_tokens"] = 128
        if base_url:
            kwargs["base_url"] = base_url

        instance = ChatOpenAI(**kwargs)
        _light_llm_instances[cache_key] = instance
        if tenant_id == "default" and user_id == "anonymous":
            _light_llm_instance = instance
        logger.info(
            "Light LLM client initialized (tenant=%s user=%s / %s)",
            tenant_id,
            user_id,
            model,
        )
        return instance
