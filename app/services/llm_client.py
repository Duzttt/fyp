"""Centralized LLM call wrapper with logging."""

import logging
import time
from typing import Any, Callable, Dict, List, Optional, Tuple, Union

import requests

from app.services.runtime_llm import resolve_local_llm_urls
from django_app.models import QueryLog

logger = logging.getLogger("llm")

# Models that support the 'think' parameter for reasoning/thinking output
REASONING_MODELS = {
    "deepseek-r1",
    "deepseek-r1:8b",
    "deepseek-r1:14b",
    "deepseek-r1:32b",
    "deepseek-r1:70b",
    "qwen3",
    "qwen3:4b",
    "qwen3:8b",
    "qwen3:14b",
    "qwen3:30b",
    "qwen3:32b",
    "qwen3:72b",
    "qwen3:235b",
}


def _model_supports_thinking(model_name: str) -> bool:
    """Check if a model supports the 'think' parameter."""
    model_lower = model_name.lower().strip()
    # Check exact match
    if model_lower in REASONING_MODELS:
        return True
    # Check if any reasoning model is a prefix (e.g., "qwen3:4b" starts with "qwen3")
    for reasoning_model in REASONING_MODELS:
        if (
            model_lower.startswith(reasoning_model + ":")
            or model_lower == reasoning_model
        ):
            return True
    return False


def _uses_enable_thinking(model_name: str) -> bool:
    """MiniCPM-style templates control thinking via 'enable_thinking'."""
    return "minicpm" in str(model_name).lower().strip()


def _call_gemini(
    messages: List[Dict[str, str]],
    model: str,
    api_key: str,
    base_url: str,
    timeout: int,
    **kwargs: Any,
) -> str:
    if not api_key or str(api_key).strip().lower() in {"none", "null"}:
        raise ValueError("GEMINI_API_KEY is not configured")

    prompt_parts = []
    for msg in messages:
        prompt_parts.append(f"[{msg['role']}]: {msg['content']}")
    prompt = "\n".join(prompt_parts)

    payload: Dict[str, Any] = {
        "contents": [{"parts": [{"text": prompt}]}],
        "generationConfig": {
            "temperature": kwargs.get("temperature", 0.7),
            "maxOutputTokens": kwargs.get("max_tokens", 500),
        },
    }
    if kwargs.get("response_format") == "json":
        payload["generationConfig"]["responseMimeType"] = "application/json"

    response = requests.post(
        f"{base_url}/models/{model}:generateContent?key={api_key}",
        json=payload,
        timeout=timeout,
    )
    response.raise_for_status()

    data = response.json()
    candidates = data.get("candidates", [])
    if not candidates:
        raise ValueError("No response from Gemini")

    return candidates[0]["content"]["parts"][0]["text"]


def _call_openrouter(
    messages: List[Dict[str, str]],
    model: str,
    api_key: str,
    base_url: str,
    timeout: int,
    **kwargs: Any,
) -> str:
    if not api_key or str(api_key).strip().lower() in {"none", "null"}:
        raise ValueError("OPENROUTER_API_KEY is not configured")

    headers = {
        "Authorization": f"Bearer {api_key}",
        "Content-Type": "application/json",
    }

    payload: Dict[str, Any] = {
        "model": model,
        "messages": messages,
        "temperature": kwargs.get("temperature", 0.7),
        "stream": False,
    }
    if kwargs.get("max_tokens"):
        payload["max_tokens"] = kwargs["max_tokens"]

    response = requests.post(
        f"{base_url}/chat/completions",
        headers=headers,
        json=payload,
        timeout=timeout,
    )
    response.raise_for_status()

    data = response.json()
    choices = data.get("choices", [])
    if not choices:
        raise ValueError("No response from OpenRouter")

    return choices[0]["message"]["content"]


def _fetch_available_models(api_base_url: str) -> List[str]:
    """Fetch available model IDs from llama.cpp /v1/models endpoint."""
    try:
        response = requests.get(f"{api_base_url}/models", timeout=5)
        response.raise_for_status()
        data = response.json()
        models: List[str] = []
        for item in data.get("data", []):
            if isinstance(item, dict):
                name = str(item.get("id") or "").strip()
                if name and name not in models:
                    models.append(name)
        return models
    except (requests.RequestException, ValueError, TypeError):
        return []


def _call_local_llm(
    messages: List[Dict[str, str]],
    model: str,
    base_url: str,
    timeout: int,
    **kwargs: Any,
) -> Union[str, Tuple[str, Optional[str]]]:
    _, api_base_url = resolve_local_llm_urls(base_url)

    payload: Dict[str, Any] = {
        "model": model,
        "messages": messages,
        "stream": False,
    }
    if "temperature" in kwargs:
        payload["temperature"] = kwargs["temperature"]
    if "num_predict" in kwargs:
        payload["max_tokens"] = kwargs["num_predict"]
    if "grammar" in kwargs:
        payload["grammar"] = kwargs["grammar"]

    return_thinking = kwargs.get("return_thinking", False)
    use_thinking = return_thinking and _model_supports_thinking(model)
    # MiniCPM templates think by default; force No-Think mode for fast, grounded answers
    # (enable_thinking=False, temperature=0.7, top_p=0.95 per model card).
    no_think = _uses_enable_thinking(model)

    def _call_model_once(
        target_model: str, with_thinking: bool = True
    ) -> Union[str, Tuple[str, Optional[str]]]:
        call_payload = dict(payload)
        call_payload["model"] = target_model
        if no_think:
            call_payload["enable_thinking"] = False
            call_payload.setdefault("temperature", 0.7)
            call_payload.setdefault("top_p", 0.95)
        elif with_thinking:
            call_payload["think"] = True

        prompt_chars = sum(
            len(m.get("content", "")) for m in call_payload.get("messages", [])
        )
        logger.debug(
            "LLM request | model=%s chars=%d max_tokens=%s think=%s no_think=%s",
            target_model,
            prompt_chars,
            call_payload.get("max_tokens"),
            call_payload.get("think", False),
            call_payload.get("enable_thinking", None),
        )

        try:
            response = requests.post(
                f"{api_base_url}/chat/completions",
                json=call_payload,
                timeout=timeout,
            )
            response.raise_for_status()

            data = response.json()
            choices = data.get("choices", [])
            if not choices:
                raise ValueError("Empty response from /v1/chat/completions")

            content = choices[0].get("message", {}).get("content")
            if not content:
                raise ValueError("Empty content from /v1/chat/completions")

            thinking_text: Optional[str] = None
            if with_thinking:
                raw = str(content).strip()
                if "<think>" in raw and "</think>" in raw:
                    start = raw.index("<think>") + len("<think>")
                    end = raw.index("</think>")
                    thinking_text = raw[start:end].strip()
                    content = (
                        raw[: raw.index("<think>")] + raw[end + len("</think>") :]
                    ).strip()

            if return_thinking:
                return str(content).strip(), thinking_text
            return str(content).strip()
        except requests.HTTPError as exc:
            if exc.response is not None and exc.response.status_code == 400:
                response_body = exc.response.text[:2000]
                logger.error(
                    "LLM 400 error | model=%s status=%d body=%s",
                    target_model,
                    exc.response.status_code,
                    response_body,
                )
                if with_thinking:
                    return _call_model_once(target_model, with_thinking=False)
                if "not found" in response_body.lower():
                    available = _fetch_available_models(api_base_url)
                    if available:
                        fallback = available[0]
                        logger.info(
                            "Model %s not found, retrying with %s",
                            target_model,
                            fallback,
                        )
                        return _call_model_once(fallback, with_thinking=False)
            raise

    try:
        return _call_model_once(model, with_thinking=use_thinking)
    except requests.Timeout:
        fallback_model = kwargs.get("fallback_model")
        if fallback_model and str(fallback_model).strip() != str(model).strip():
            fallback_model_str = str(fallback_model).strip()
            fallback_use_thinking = return_thinking and _model_supports_thinking(
                fallback_model_str
            )
            return _call_model_once(
                fallback_model_str, with_thinking=fallback_use_thinking
            )
        raise


LLMDispatchResult = Union[str, Tuple[str, Optional[str]]]
LLMDispatch = Callable[..., LLMDispatchResult]

_PROVIDER_DISPATCH: Dict[str, LLMDispatch] = {
    "gemini": _call_gemini,
    "openrouter": _call_openrouter,
    "local_llm": _call_local_llm,
}


def call_llm(
    provider: str,
    model: str,
    call_type: str,
    messages: List[Dict[str, str]],
    timeout: int = 60,
    query_text: str = "",
    return_log: bool = False,
    return_thinking: bool = False,
    **kwargs: Any,
) -> Union[
    str,
    Tuple[str, int],
    Tuple[str, Optional[str]],
    Tuple[str, Optional[str], int],
]:
    if provider not in _PROVIDER_DISPATCH:
        raise ValueError(f"Unsupported provider: {provider}")

    dispatch_fn = _PROVIDER_DISPATCH[provider]
    start_time = time.monotonic()
    effective_query = query_text or (
        messages[-1].get("content", "") if messages else ""
    )
    logger.info(
        "LLM call | provider=%s model=%s type=%s query=%s",
        provider,
        model,
        call_type,
        effective_query[:120],
    )

    try:
        result = dispatch_fn(
            messages=messages,
            model=model,
            timeout=timeout,
            return_thinking=return_thinking,
            **kwargs,
        )
        elapsed_ms = int((time.monotonic() - start_time) * 1000)

        # Extract content for logging
        content_for_log = result[0] if isinstance(result, tuple) else result
        logger.info(
            "LLM success | provider=%s model=%s latency=%dms answer_len=%d",
            provider,
            model,
            elapsed_ms,
            len(content_for_log),
        )

        log_entry = QueryLog.objects.create(
            query=query_text or (messages[-1].get("content", "") if messages else ""),
            latency_ms=elapsed_ms,
            llm_model=model,
            llm_provider=provider,
            llm_status="success",
            call_type=call_type,
            answer_length=len(content_for_log),
        )

        if return_thinking and return_log:
            # Return (content, thinking, log_id) tuple when both are requested.
            if isinstance(result, tuple):
                return result[0], result[1], int(log_entry.id)
            return result, None, int(log_entry.id)
        if return_thinking:
            # Return (content, thinking) tuple.
            if isinstance(result, tuple):
                return result
            return result, None
        if return_log:
            if isinstance(result, tuple):
                return result[0], int(log_entry.id)
            return result, int(log_entry.id)
        return result

    except Exception as exc:
        elapsed_ms = int((time.monotonic() - start_time) * 1000)
        logger.error(
            "LLM error | provider=%s model=%s latency=%dms error=%s",
            provider,
            model,
            elapsed_ms,
            exc,
        )

        QueryLog.objects.create(
            query=query_text or (messages[-1].get("content", "") if messages else ""),
            latency_ms=elapsed_ms,
            llm_model=model,
            llm_provider=provider,
            llm_status="error",
            error_message=str(exc),
            call_type=call_type,
        )
        raise
