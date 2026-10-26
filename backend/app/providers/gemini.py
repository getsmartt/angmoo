from __future__ import annotations

import asyncio
import hashlib
import math
from copy import deepcopy
from dataclasses import dataclass
from time import monotonic
from typing import Any

from google import genai
from google.genai import errors, types
import httpx
from pydantic import BaseModel
from app.providers.diagnostics import schema_evidence

from app.core.redaction import redact_exact_secret_text
from app.providers.contracts import (
    EmbeddingRequest,
    MeasuredEmbeddingResponse,
    ProviderCapabilities,
    ProviderError,
    ProviderHTTPStatusError,
    ProviderRequest,
    ProviderResponse,
    ProviderToolCall,
    ProviderUsage,
)


_GEMINI_DEVELOPER_SCHEMA_KEYS = frozenset(
    {
        "type",
        "properties",
        "required",
        "items",
        "enum",
        "format",
        "description",
        "minimum",
        "maximum",
        "minLength",
        "maxLength",
        "minItems",
        "maxItems",
        "nullable",
        "pattern",
    }
)


def build_gemini_developer_response_schema(
    model: type[BaseModel],
) -> dict[str, Any]:
    """Convert a strict Pydantic model to Gemini Developer API JSON Schema.

    The transport schema only contains the subset accepted by Gemini and has
    all local references inlined.  Callers must still validate the returned
    payload with the original strict Pydantic model before applying it.
    """

    source = model.model_json_schema()
    definitions = source.get("$defs", {})

    def convert(value: Any, references: tuple[str, ...] = ()) -> Any:
        if isinstance(value, list):
            return [convert(item, references) for item in value]
        if not isinstance(value, dict):
            return value

        if "$ref" in value:
            reference = value["$ref"]
            prefix = "#/$defs/"
            if not isinstance(reference, str) or not reference.startswith(prefix):
                raise ValueError(f"unsupported response schema reference: {reference}")
            name = reference[len(prefix) :]
            if name in references:
                raise ValueError("recursive response schema reference")
            target = definitions.get(name)
            if not isinstance(target, dict):
                raise ValueError(f"missing response schema definition: {name}")
            merged = deepcopy(target)
            merged.update({key: item for key, item in value.items() if key != "$ref"})
            return convert(merged, (*references, name))

        # JSON Schema values must stay values, not be traversed as schema nodes.
        value = deepcopy(value)
        if "const" in value:
            constant = value.pop("const")
            if (isinstance(constant, bool) or not isinstance(constant, (str, int, float, type(None)))
                    or isinstance(constant, float) and not math.isfinite(constant)):
                raise ValueError("unsupported response schema constant")
            if "enum" in value and (not isinstance(value["enum"], list) or not any(
                type(candidate) is not bool and candidate == constant
                for candidate in value["enum"])):
                raise ValueError("conflicting response schema const and enum")
            inferred = "null" if constant is None else ("string" if isinstance(constant, str)
                else "integer" if isinstance(constant, int) else "number")
            declared = value.get("type")
            if declared is not None and inferred not in (declared if isinstance(declared, list) else [declared]):
                if not (inferred == "integer" and declared == "number"):
                    raise ValueError("conflicting response schema const and type")
            value["type"] = declared or inferred
            if constant is None:
                value["type"] = "null"
                value.pop("enum", None)
            else:
                value["enum"] = [constant]

        variants = value.get("anyOf")
        if isinstance(variants, list):
            non_null = [
                item
                for item in variants
                if not (isinstance(item, dict) and item.get("type") == "null")
            ]
            has_null = len(non_null) != len(variants)
            if has_null and len(non_null) == 1:
                converted = convert(non_null[0], references)
                if not isinstance(converted, dict):
                    raise ValueError("nullable response schema must resolve to an object")
                converted_type = converted.get("type")
                if isinstance(converted_type, str) and "enum" in converted:
                    # An enum on a type array would also constrain null. Keep
                    # the unrestricted null alternative separate from it.
                    metadata = convert({k: v for k, v in value.items() if k != "anyOf"}, references)
                    return {**metadata, "anyOf": [converted, {"type": "null"}]}
                elif isinstance(converted_type, str):
                    converted["type"] = [converted_type, "null"]
                else:
                    raise ValueError(
                        "nullable response schema must have one concrete type"
                    )
                return {**convert({k: v for k, v in value.items() if k != "anyOf"}, references), **converted}
            raise ValueError("unsupported response schema union")

        if isinstance(value.get("type"), list) and "enum" in value:
            concrete = [kind for kind in value["type"] if kind != "null"]
            if len(concrete) != 1 or "null" not in value["type"]:
                raise ValueError("unsupported response schema enum union")
            allows_null = None in value["enum"]
            values = [item for item in value["enum"] if item is not None]
            if not values and allows_null:
                return {**convert({k: v for k, v in value.items() if k not in {"type", "enum"}}, references), "type": "null"}
            leaf = convert({**value, "type": concrete[0], "enum": values}, references)
            return {"anyOf": [leaf, {"type": "null"}]} if allows_null else leaf

        converted: dict[str, Any] = {}
        for key, item in value.items():
            if key == "properties" and isinstance(item, dict):
                converted[key] = {
                    property_name: convert(property_schema, references)
                    for property_name, property_schema in item.items()
                }
            elif key in _GEMINI_DEVELOPER_SCHEMA_KEYS:
                converted[key] = convert(item, references) if key == "items" else deepcopy(item)
        return converted

    converted = convert(source)
    if not isinstance(converted, dict):
        raise ValueError("response schema root must be an object")
    return converted


def build_generate_content_config(
    *,
    model: str,
    system_prompt: str,
    max_output_tokens: int,
    response_mime_type: str | None,
    response_schema: Any | None,
    thinking_level: str | None,
) -> types.GenerateContentConfig:
    config_kwargs: dict[str, Any] = {
        "systemInstruction": system_prompt,
        "maxOutputTokens": max_output_tokens,
        "responseMimeType": response_mime_type,
    }
    if isinstance(response_schema, dict):
        # Developer API accepts ordinary JSON Schema through this field.  The
        # older OpenAPI-style responseSchema path has a smaller, product-
        # specific subset and can reject otherwise valid nested schemas.
        config_kwargs["responseJsonSchema"] = response_schema
    elif response_schema is not None:
        config_kwargs["responseSchema"] = response_schema
    thinking_config = resolve_gemini_thinking_config(
        model=model,
        thinking_level=thinking_level,
    )
    if thinking_config is not None:
        config_kwargs["thinkingConfig"] = thinking_config
    return types.GenerateContentConfig(**config_kwargs)


def resolve_gemini_thinking_config(
    *,
    model: str,
    thinking_level: str | None,
) -> types.ThinkingConfig | None:
    """Map Angmoo's bounded intent to the selected model family's API.

    Gemini 3 supports ``thinkingLevel`` while Gemini 2.5 uses a numeric
    ``thinkingBudget``.  Gemma models do not accept Gemini thinking controls.
    Unknown families fail before provider I/O instead of guessing a config.
    """

    normalized_model = model.strip().lower()
    normalized_level = (
        None if thinking_level is None else thinking_level.strip().lower()
    )
    if normalized_model.startswith("gemma-"):
        return None
    if normalized_model.startswith("gemini-3."):
        if not normalized_level:
            return None
        return types.ThinkingConfig(thinkingLevel=normalized_level)
    if normalized_model.startswith("gemini-2.5-"):
        if not normalized_level:
            return None
        if normalized_level != "low":
            raise ValueError(
                "gemini_2_5_thinking_level_requires_explicit_budget_policy"
            )
        return types.ThinkingConfig(thinkingBudget=0)
    raise ValueError(f"unsupported_gemini_thinking_model_family:{model}")


def _text_from_response(response: Any) -> str:
    text = getattr(response, "text", None)
    if isinstance(text, str) and text.strip():
        return text.strip()
    candidates = getattr(response, "candidates", None) or []
    parts: list[str] = []
    for candidate in candidates:
        content = getattr(candidate, "content", None)
        for part in getattr(content, "parts", None) or []:
            part_text = getattr(part, "text", None)
            if isinstance(part_text, str) and part_text.strip():
                parts.append(part_text.strip())
    return "\n\n".join(parts).strip()


def _usage_from_response(response: Any) -> ProviderUsage:
    usage = getattr(response, "usage_metadata", None)
    if usage is None:
        return ProviderUsage()
    return ProviderUsage(
        input_tokens=getattr(usage, "prompt_token_count", None),
        output_tokens=getattr(usage, "candidates_token_count", None),
        thought_tokens=getattr(usage, "thoughts_token_count", None),
        total_tokens=getattr(usage, "total_token_count", None),
        cached_input_tokens=getattr(usage, "cached_content_token_count", None),
    )


def _finish_reason_from_response(response: Any) -> str | None:
    candidates = getattr(response, "candidates", None)
    if not candidates:
        return None
    finish_reason = getattr(candidates[0], "finish_reason", None)
    if finish_reason is None:
        return None
    # SDK enums stringify to "FinishReason.STOP", not the wire code "STOP".
    value = getattr(finish_reason, "value", finish_reason)
    return value if isinstance(value, str) else "UNKNOWN"


def _response_evidence(response: Any) -> dict[str, Any]:
    """Capture bounded SDK response structure without content or free-text feedback."""
    candidates = getattr(response, "candidates", None) or []
    feedback = getattr(response, "prompt_feedback", None)

    def enum_code(value: Any, enum_type: Any) -> str | None:
        if value is None:
            return None
        wire = getattr(value, "value", value)
        return wire if isinstance(wire, str) and wire in {item.value for item in enum_type} else "UNKNOWN"

    return {
        "capture_boundary": "sdk_response",
        "response_evidence_version": 1,
        "candidate_count": len(candidates),
        "prompt_feedback_present": feedback is not None,
        "prompt_block_reason": enum_code(getattr(feedback, "block_reason", None), types.BlockedReason),
        "candidate_finish_reasons": [
            enum_code(getattr(candidate, "finish_reason", None), types.FinishReason)
            for candidate in candidates[:8]
        ],
        "candidate_part_counts": [
            len(getattr(getattr(candidate, "content", None), "parts", None) or [])
            for candidate in candidates[:8]
        ],
        "candidate_text_part_counts": [
            sum(isinstance(getattr(part, "text", None), str) and bool(part.text.strip())
                for part in (getattr(getattr(candidate, "content", None), "parts", None) or []))
            for candidate in candidates[:8]
        ],
        "candidate_metadata_truncated": len(candidates) > 8,
        "parsed_present": getattr(response, "parsed", None) is not None,
    }


def _native_parameters(schema: dict[str, Any]) -> types.Schema:
    """Use the SDK's OpenAPI nullable form; domain validation stays authoritative."""
    def convert(node):
        variants = node.get("anyOf")
        if isinstance(variants, list):
            concrete = [item for item in variants if item.get("type") != "null"]
            if len(variants) == 2 and len(concrete) == 1:
                # Native tools use the SDK's OpenAPI nullable flag. Preserve
                # the same enum/null domain as the JSON response schema.
                leaf = convert(concrete[0])
                return {**convert({k: v for k, v in node.items() if k != "anyOf"}),
                    **leaf, "nullable": True}
            raise ValueError("native_tool_schema_union_unsupported")
        result = {}
        for key, value in node.items():
            if key == "additionalProperties":
                continue  # Enforced by the closed domain parser.
            if key == "properties":
                result[key] = {name: convert(item) for name, item in value.items()}
            elif key == "items":
                result[key] = convert(value)
            elif key == "type" and isinstance(value, list):
                concrete = [item for item in value if item != "null"]
                if len(concrete) != 1 or "null" not in value:
                    raise ValueError("native_tool_schema_union_unsupported")
                result[key], result["nullable"] = concrete[0], True
            elif key == "enum":
                result[key] = [item for item in value if item is not None]
            else:
                result[key] = value
        return result
    return types.Schema.model_validate(convert(schema))


@dataclass(frozen=True)
class PreparedGeminiRequest:
    contents: Any
    config: types.GenerateContentConfig

    def count_request(self, model: str) -> dict:
        contents = [types.Content(role="user", parts=[types.Part.from_text(text=self.contents)])] if isinstance(self.contents, str) else [self.contents]
        config = self.config.model_dump(mode="json", by_alias=True, exclude_none=True)
        instruction = config.pop("systemInstruction", None)
        tools = config.pop("tools", None)
        tool_config = config.pop("toolConfig", None)
        config.pop("automaticFunctionCalling", None)
        result = {"model": "models/" + model.removeprefix("models/"),
            "contents": [item.model_dump(mode="json", by_alias=True, exclude_none=True) for item in contents],
            "generationConfig": config}
        if instruction is not None:
            result["systemInstruction"] = {"parts": [{"text": instruction}]} if isinstance(instruction, str) else instruction
        if tools:
            result["tools"] = tools
        if tool_config:
            result["toolConfig"] = tool_config
        return {"generateContentRequest": result}


def prepare_generate_request(request: ProviderRequest) -> PreparedGeminiRequest:
    if isinstance(request.prepared_request, PreparedGeminiRequest):
        return request.prepared_request
    config = build_generate_content_config(
        model=request.model,
        system_prompt=request.system_prompt,
        max_output_tokens=request.max_output_tokens,
        response_mime_type=request.response_mime_type,
        response_schema=request.response_schema,
        thinking_level=request.thinking_level,
    )
    contents: Any = request.user_prompt
    if request.require_tool_call and not request.tools:
        raise ValueError("required_tool_declarations_missing")
    if request.tools:
        if request.response_schema is not None or request.response_mime_type is not None:
            raise ValueError("native_tools_json_mode_conflict")
        config.tools = [types.Tool(function_declarations=[
            types.FunctionDeclaration(name=tool.name, description=tool.description,
                                      parameters=_native_parameters(tool.parameters))
            for tool in request.tools
        ])]
        config.automatic_function_calling = types.AutomaticFunctionCallingConfig(disable=True)
        config.tool_config = types.ToolConfig(
            # Unlike ANY, VALIDATED still permits a no-tool response, while
            # constraining native function arguments to their declared schema.
            function_calling_config=types.FunctionCallingConfig(
                mode="ANY" if request.require_tool_call else "VALIDATED"
            )
        )
    if request.image_parts:
        parts = [types.Part.from_text(text=request.user_prompt)]
        for image_part in request.image_parts:
            if image_part.data is not None:
                parts.append(
                    types.Part.from_bytes(
                        data=image_part.data,
                        mime_type=image_part.mime_type,
                    )
                )
            elif image_part.url:
                parts.append(
                    types.Part.from_uri(
                        file_uri=image_part.url,
                        mime_type=image_part.mime_type,
                    )
                )
        contents = types.Content(role="user", parts=parts)
    return PreparedGeminiRequest(contents, config)


def _generate_content_sync(request: ProviderRequest) -> ProviderResponse:
    prepared = prepare_generate_request(request)
    contents, config = prepared.contents, prepared.config
    client = genai.Client(api_key=request.api_key, http_options=types.HttpOptions(
        timeout=max(1, int(request.timeout_seconds * 1000)),
        retry_options=types.HttpRetryOptions(attempts=request.sdk_attempts) if request.sdk_attempts is not None else None))
    if request.diagnostic_callback is not None:
        try:
            config_values = config.model_dump(by_alias=True, exclude_none=True)
            schema = config_values.get("responseJsonSchema", config_values.get("responseSchema"))
            request.diagnostic_callback({
                "capture_boundary": "sdk_input", "model": request.model,
                "config_keys": list(config_values),
                "schema_field": "responseJsonSchema" if "responseJsonSchema" in config_values else
                    "responseSchema" if "responseSchema" in config_values else None,
                "max_output_tokens": config_values.get("maxOutputTokens"),
                "response_mime_type": config_values.get("responseMimeType"),
                "thinking_config": config_values.get("thinkingConfig"),
                "timeout_ms": max(1, int(request.timeout_seconds * 1000)),
                "sdk_retry_attempts": request.sdk_attempts,
                "sdk_retry_status": "explicit" if request.sdk_attempts is not None else "sdk_default_unverified",
                "system_sha256": hashlib.sha256(request.system_prompt.encode()).hexdigest(),
                "system_chars": len(request.system_prompt),
                "user_sha256": hashlib.sha256(request.user_prompt.encode()).hexdigest(),
                "user_chars": len(request.user_prompt),
                **schema_evidence(schema),
            })
        except Exception:
            pass  # Observation never changes SDK arguments or provider behavior.
    response = client.models.generate_content(
        model=request.model,
        contents=contents,
        config=config,
    )
    if request.diagnostic_callback is not None:
        try:
            request.diagnostic_callback({"model": request.model, **_response_evidence(response)})
        except Exception:
            pass  # Missing diagnostics never change response parsing or retry policy.
    return ProviderResponse(
        text=_text_from_response(response),
        parsed=getattr(response, "parsed", None),
        usage=_usage_from_response(response),
        finish_reason=_finish_reason_from_response(response),
        tool_calls=tuple(
            ProviderToolCall(name=part.function_call.name,
                             arguments=dict(part.function_call.args or {}),
                             call_id=part.function_call.id,
                             thought_signature=part.thought_signature)
            for candidate in (response.candidates or [])[:1]
            for part in (getattr(candidate.content, "parts", None) or [])
            if part.function_call is not None
        ),
    )


def _embed_sync(request: EmbeddingRequest) -> list[float]:
    client = genai.Client(api_key=request.api_key)
    response = client.models.embed_content(
        model=request.model,
        contents=request.text,
        config=types.EmbedContentConfig(outputDimensionality=request.output_dimension),
    )
    embeddings = response.embeddings or []
    if not embeddings or not embeddings[0].values:
        raise ProviderError(
            "Gemini embedding response was empty",
            failure_class="empty_embedding",
            retryable=False,
        )
    values = [float(value) for value in embeddings[0].values]
    if len(values) != request.output_dimension:
        raise ProviderError(
            "Gemini embedding dimension did not match the request",
            failure_class="embedding_dimension_mismatch",
            retryable=False,
        )
    return values


class GeminiAdapter:
    capabilities = ProviderCapabilities(
        text=True,
        structured_json=True,
        image_input=True,
        embedding=True,
        embedding_batch=True,
        tool_calls=True,
    )

    async def generate_text(self, request: ProviderRequest) -> ProviderResponse:
        return await asyncio.to_thread(_generate_content_sync, request)

    async def generate_json(self, request: ProviderRequest) -> ProviderResponse:
        return await asyncio.to_thread(_generate_content_sync, request)

    async def embed(self, request: EmbeddingRequest) -> list[float]:
        return await asyncio.to_thread(_embed_sync, request)

    def embed_sync(self, request: EmbeddingRequest) -> list[float]:
        return _embed_sync(request)

    async def embed_batch_measured(self, request, *, timeout_seconds):
        from app.providers.gemini_embedding_batch import embed_batch
        return await embed_batch(request, timeout_seconds=timeout_seconds,
            normalize_error=classify_generation_failure)

    async def embed_measured(self, request: EmbeddingRequest, *, timeout_seconds: float) -> MeasuredEmbeddingResponse:
        """One cancellable native async HTTP attempt; legacy lore API stays intact."""
        if not 0 < timeout_seconds <= 60:
            raise ValueError("embedding_timeout_invalid")
        started = monotonic()
        from app.providers.embedding_observation import EmbeddingTransportObservation
        observation = EmbeddingTransportObservation(input_count=1, dimension=request.output_dimension)
        client = genai.Client(api_key=request.api_key, http_options=types.HttpOptions(
            timeout=max(1, int(timeout_seconds*1000)), async_client_args=observation.client_args(),
            retry_options=types.HttpRetryOptions(attempts=1),
        ))
        try:
            async with client.aio as aio:
                async with asyncio.timeout(timeout_seconds):
                    response = await aio.models.embed_content(model=request.model, contents=request.text,
                        config=types.EmbedContentConfig(output_dimensionality=request.output_dimension))
            embeddings = response.embeddings or []
            if len(embeddings) != 1 or embeddings[0].values is None:
                raise ProviderError("Embedding response shape invalid", failure_class="empty_embedding", retryable=False)
            vector = tuple(float(v) for v in embeddings[0].values)
            if len(vector) != request.output_dimension or any(not math.isfinite(v) for v in vector):
                raise ProviderError("Embedding vector invalid", failure_class="embedding_dimension_mismatch", retryable=False)
            # Developer API does not provide usage on this SDK response. Unknown
            # token usage is None; never estimate it from character count.
            observation.validated(1)
            return MeasuredEmbeddingResponse(vector, ProviderUsage(call_type="embed_content",
                duration_ms=int((monotonic()-started)*1000)), physical_attempts=1)
        except asyncio.CancelledError:
            raise
        except Exception as exc:
            normalized = exc if isinstance(exc, ProviderError) else classify_generation_failure(exc)
            normalized.physical_attempts = 1
            normalized.duration_ms = int((monotonic()-started)*1000)
            raise normalized from None
        finally:
            observation.finish()
            client.close()

    def normalize_error(
        self, exc: BaseException, *, api_key: str | None = None
    ) -> ProviderError:
        message = redact_exact_secret_text(str(exc), api_key)
        code = getattr(exc, "code", None)
        status = getattr(exc, "status", None)
        retryable = code in {429, 500, 502, 503, 504} or status in {
            "RESOURCE_EXHAUSTED",
            "UNAVAILABLE",
        }
        return ProviderError(
            message[:1000],
            failure_class=type(exc).__name__,
            provider_status=str(status) if status is not None else None,
            provider_code=code,
            retryable=retryable,
        )


def classify_generation_failure(exc: Exception) -> ProviderError:
    """Safe SDK failure metadata for callers that own durable retry policy.

    Do not expose exception messages, response bodies, request URLs or headers.
    Existing callers of normalize_error retain their established behavior.
    """
    code = (exc.code if isinstance(exc, (errors.APIError, ProviderHTTPStatusError))
            and type(exc.code) is int else None)
    failures = {
        400: ("request_invalid", "INVALID_ARGUMENT", False),
        401: ("auth_failed", "UNAUTHENTICATED", False),
        403: ("auth_failed", "PERMISSION_DENIED", False),
        404: ("model_unavailable", "NOT_FOUND", False),
        429: ("rate_limited", "RESOURCE_EXHAUSTED", True),
        500: ("provider_unavailable", "INTERNAL", True),
        502: ("provider_unavailable", "BAD_GATEWAY", True),
        503: ("provider_unavailable", "UNAVAILABLE", True),
        504: ("provider_unavailable", "DEADLINE_EXCEEDED", True),
    }
    failure, status, retryable = failures.get(code, ("failed", None, False))
    if isinstance(exc, (TimeoutError, httpx.TimeoutException)):
        failure, retryable = "timeout", True
    elif isinstance(exc, httpx.NetworkError):
        failure, retryable = "transport_failed", True
    return ProviderError(
        "Generation request failed", failure_class=failure,
        provider_status=status, provider_code=code, retryable=retryable,
    )
