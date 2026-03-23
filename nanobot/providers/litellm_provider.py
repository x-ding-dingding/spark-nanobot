"""LiteLLM provider implementation for multi-provider support."""

import json
import os
import traceback
from typing import Any

import litellm
from litellm import acompletion

from nanobot.providers.base import LLMProvider, LLMResponse, ToolCallRequest
from nanobot.providers.registry import find_by_model, find_gateway


class LiteLLMProvider(LLMProvider):
    """
    LLM provider using LiteLLM for multi-provider support.
    
    Supports OpenRouter, Anthropic, OpenAI, Gemini, MiniMax, and many other providers through
    a unified interface.  Provider-specific logic is driven by the registry
    (see providers/registry.py) — no if-elif chains needed here.
    """
    
    def __init__(
        self, 
        api_key: str | None = None, 
        api_base: str | None = None,
        default_model: str = "anthropic/claude-opus-4-5",
        extra_headers: dict[str, str] | None = None,
        provider_name: str | None = None,
    ):
        super().__init__(api_key, api_base)
        self.default_model = default_model
        self.extra_headers = extra_headers or {}
        
        # Detect gateway / local deployment.
        # provider_name (from config key) is the primary signal;
        # api_key / api_base are fallback for auto-detection.
        self._gateway = find_gateway(provider_name, api_key, api_base)
        
        # Configure environment variables
        if api_key:
            self._setup_env(api_key, api_base, default_model)
        
        if api_base:
            litellm.api_base = api_base
        
        # Disable LiteLLM logging noise
        litellm.suppress_debug_info = True
        # Drop unsupported parameters for providers (e.g., gpt-5 rejects some params)
        litellm.drop_params = True
    
    def _setup_env(self, api_key: str, api_base: str | None, model: str) -> None:
        """Set environment variables based on detected provider."""
        spec = self._gateway or find_by_model(model)
        if not spec:
            return

        # Gateway/local overrides existing env; standard provider doesn't
        if self._gateway:
            os.environ[spec.env_key] = api_key
        else:
            os.environ.setdefault(spec.env_key, api_key)

        # Resolve env_extras placeholders:
        #   {api_key}  → user's API key
        #   {api_base} → user's api_base, falling back to spec.default_api_base
        effective_base = api_base or spec.default_api_base
        for env_name, env_val in spec.env_extras:
            resolved = env_val.replace("{api_key}", api_key)
            resolved = resolved.replace("{api_base}", effective_base)
            os.environ.setdefault(env_name, resolved)
    
    def _resolve_model(self, model: str) -> str:
        """Resolve model name by applying provider/gateway prefixes."""
        if self._gateway:
            # Gateway mode: apply gateway prefix, skip provider-specific prefixes
            prefix = self._gateway.litellm_prefix
            if self._gateway.strip_model_prefix:
                model = model.split("/")[-1]
            if prefix and not model.startswith(f"{prefix}/"):
                model = f"{prefix}/{model}"
            return model
        
        # Standard mode: auto-prefix for known providers
        spec = find_by_model(model)
        if spec and spec.litellm_prefix:
            if not any(model.startswith(s) for s in spec.skip_prefixes):
                model = f"{spec.litellm_prefix}/{model}"
        
        return model
    
    def _apply_model_overrides(self, model: str, kwargs: dict[str, Any]) -> None:
        """Apply model-specific parameter overrides from the registry."""
        model_lower = model.lower()
        spec = find_by_model(model)
        if spec:
            for pattern, overrides in spec.model_overrides:
                if pattern in model_lower:
                    kwargs.update(overrides)
                    return

    @staticmethod
    def _redact_error_payload(payload: str | None) -> str | None:
        """Redact sensitive context when upstream returns raw streamed events.

        Some gateways return SSE chunks like:
            event: response.created
            data: {... "instructions": "...system prompt..."}
        Dumping this verbatim leaks full prompt/context into logs.
        """
        if not payload:
            return payload

        text = str(payload)
        lower = text.lower()
        looks_like_sse = "event: response.created" in lower or "data: {" in lower
        contains_prompt_like_fields = "\"instructions\"" in lower or "\"messages\"" in lower
        if looks_like_sse and contains_prompt_like_fields:
            return "[redacted streamed response payload containing prompt/context]"
        return text
    
    async def chat(
        self,
        messages: list[dict[str, Any]],
        tools: list[dict[str, Any]] | None = None,
        model: str | None = None,
        max_tokens: int = 4096,
        temperature: float = 0.7,
        reasoning_effort: str | None = None,
    ) -> LLMResponse:
        """
        Send a chat completion request via LiteLLM.
        
        Args:
            messages: List of message dicts with 'role' and 'content'.
            tools: Optional list of tool definitions in OpenAI format.
            model: Model identifier (e.g., 'anthropic/claude-sonnet-4-5').
            max_tokens: Maximum tokens in response.
            temperature: Sampling temperature.
            reasoning_effort: Thinking depth for reasoning models ("low", "medium", "high").
                LiteLLM maps this to provider-specific params (e.g. Gemini thinking_level).
        
        Returns:
            LLMResponse with content and/or tool calls.
        """
        model = self._resolve_model(model or self.default_model)
        
        kwargs: dict[str, Any] = {
            "model": model,
            "messages": messages,
            "max_tokens": max_tokens,
            "temperature": temperature,
        }

        # Compatibility guard:
        # LiteLLM forces OpenAI gpt-5.4+ calls with (tools + reasoning_effort)
        # through Responses API. Some OpenAI-compatible gateways return SSE
        # chunks in a way LiteLLM can't normalize, causing APIError despite the
        # model actually generating an answer. In that case, avoid passing
        # reasoning_effort so the call stays on chat-completions semantics.
        model_lower = model.lower()
        is_gpt_54_plus = "gpt-5.4" in model_lower or "gpt-5.5" in model_lower
        is_non_official_openai_base = bool(
            self.api_base and "api.openai.com" not in self.api_base.lower()
        )
        skip_reasoning_effort = bool(
            reasoning_effort and tools and is_gpt_54_plus and is_non_official_openai_base
        )

        if reasoning_effort and not skip_reasoning_effort:
            # DashScope (Qwen3) uses extra_body={"enable_thinking": True} to enable
            # extended thinking, rather than the standard reasoning_effort parameter.
            spec = find_by_model(model)
            if spec and spec.name == "dashscope":
                kwargs["extra_body"] = {"enable_thinking": True}
            else:
                kwargs["reasoning_effort"] = reasoning_effort
        elif skip_reasoning_effort:
            from loguru import logger
            logger.warning(
                "Skipping reasoning_effort for gpt-5.4+ on non-official OpenAI-compatible "
                "api_base to avoid Responses API bridge incompatibility."
            )
        
        # Apply model-specific overrides (e.g. kimi-k2.5 temperature)
        self._apply_model_overrides(model, kwargs)
        
        # Pass api_key directly — more reliable than env vars alone
        if self.api_key:
            kwargs["api_key"] = self.api_key
        
        # Pass api_base for custom endpoints
        if self.api_base:
            kwargs["api_base"] = self.api_base
        
        # Pass extra headers (e.g. APP-Code for AiHubMix)
        if self.extra_headers:
            kwargs["extra_headers"] = self.extra_headers
        
        if tools:
            kwargs["tools"] = tools
            kwargs["tool_choice"] = "auto"
        
        try:
            # DEBUG: log full request kwargs and response
            from loguru import logger
            import copy
            debug_kwargs = copy.deepcopy(kwargs)
            if "api_key" in debug_kwargs:
                debug_kwargs["api_key"] = debug_kwargs["api_key"][:8] + "..."
            # logger.debug(
            #     f"[LLM REQUEST] model={model}\n"
            #     f"  kwargs (non-messages): { {k: v for k, v in debug_kwargs.items() if k != 'messages'} }\n"
            #     f"  messages ({len(kwargs.get('messages', []))} total):\n"
            #     + "\n".join(
            #         f"    [{i}] role={m.get('role')} | "
            #         f"content_len={len(str(m.get('content') or ''))} | "
            #         f"tool_calls={len(m.get('tool_calls', []))} | "
            #         f"content_preview={str(m.get('content') or '')}"
            #         for i, m in enumerate(kwargs.get("messages", []))
            #     )
            # )

            response = await acompletion(**kwargs)

            result = self._parse_response(response)
            # logger.debug(
            #     f"[LLM RESPONSE] finish_reason={result.finish_reason} | "
            #     f"has_tool_calls={result.has_tool_calls} | "
            #     f"tool_calls={[tc.name for tc in result.tool_calls]} | "
            #     f"content_preview={str(result.content or '')} | "
            #     f"reasoning_preview={str(result.reasoning_content or '')} | "
            #     f"usage={result.usage}"
            # )
            return result
        except Exception as e:
            from loguru import logger

            # Extract detailed error info from litellm exceptions
            error_details = [f"Exception type: {type(e).__module__}.{type(e).__qualname__}"]
            error_details.append(f"Message: {e}")

            if hasattr(e, "status_code"):
                error_details.append(f"HTTP status: {e.status_code}")
            if hasattr(e, "llm_provider"):
                error_details.append(f"Provider: {e.llm_provider}")
            if hasattr(e, "model"):
                error_details.append(f"Model: {e.model}")

            # litellm exceptions often have a .response with the raw API response body
            response_body = None
            if hasattr(e, "response") and e.response is not None:
                try:
                    if hasattr(e.response, "text"):
                        response_body = e.response.text
                    elif hasattr(e.response, "json"):
                        response_body = json.dumps(e.response.json(), ensure_ascii=False)
                    else:
                        response_body = str(e.response)
                except Exception:
                    response_body = repr(e.response)
                redacted_body = self._redact_error_payload(response_body)
                error_details.append(f"Response body: {redacted_body}")

            detail_str = "\n  ".join(error_details)
            logger.error(
                f"LLM call failed (model={model}):\n  {detail_str}\n"
                f"  Traceback:\n{traceback.format_exc()}"
            )

            # Build a user-facing message that includes actionable info
            user_message = f"Error calling LLM: {type(e).__qualname__}: {e}"
            if hasattr(e, "status_code"):
                user_message += f" (HTTP {e.status_code})"
            if response_body:
                safe_body = self._redact_error_payload(response_body) or ""
                body_preview = safe_body[:500]
                if len(safe_body) > 500:
                    body_preview += "..."
                user_message += f"\nAPI response: {body_preview}"

            return LLMResponse(
                content=user_message,
                finish_reason="error",
            )
    
    def _parse_response(self, response: Any) -> LLMResponse:
        """Parse LiteLLM response into our standard format."""
        choice = response.choices[0]
        message = choice.message
        
        tool_calls = []
        if hasattr(message, "tool_calls") and message.tool_calls:
            for tc in message.tool_calls:
                # Parse arguments from JSON string if needed
                args = tc.function.arguments
                if isinstance(args, str):
                    try:
                        args = json.loads(args)
                    except json.JSONDecodeError:
                        args = {"raw": args}
                
                tool_calls.append(ToolCallRequest(
                    id=tc.id,
                    name=tc.function.name,
                    arguments=args,
                ))
        
        usage = {}
        if hasattr(response, "usage") and response.usage:
            usage = {
                "prompt_tokens": response.usage.prompt_tokens,
                "completion_tokens": response.usage.completion_tokens,
                "total_tokens": response.usage.total_tokens,
            }
        
        reasoning_content = getattr(message, "reasoning_content", None)
        
        # Preserve the raw assistant message dict so that provider-specific
        # fields (e.g. Gemini thought_signature on tool_calls) survive
        # round-tripping through the agent loop.
        raw_assistant_message = None
        if tool_calls:
            try:
                raw_assistant_message = message.model_dump(exclude_none=True)
            except Exception:
                # Fallback: manually build from known fields
                raw_msg: dict[str, Any] = {
                    "role": "assistant",
                    "content": message.content or "",
                }
                if hasattr(message, "tool_calls") and message.tool_calls:
                    raw_msg["tool_calls"] = [
                        tc.model_dump(exclude_none=True) for tc in message.tool_calls
                    ]
                if reasoning_content:
                    raw_msg["reasoning_content"] = reasoning_content
                raw_assistant_message = raw_msg
        
        return LLMResponse(
            content=message.content,
            tool_calls=tool_calls,
            finish_reason=choice.finish_reason or "stop",
            usage=usage,
            reasoning_content=reasoning_content,
            raw_assistant_message=raw_assistant_message,
        )
    
    def get_default_model(self) -> str:
        """Get the default model."""
        return self.default_model
