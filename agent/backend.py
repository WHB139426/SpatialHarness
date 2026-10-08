"""vLLM chat requests with native tool-call text returned to the protocol."""

from __future__ import annotations

from .types import ModelInput


class VLLMBackend:
    def __init__(
        self,
        model: str,
        *,
        base_url: str,
        max_tokens: int,
        temperature: float,
        top_p: float,
        top_k: int,
        media_io_kwargs: dict[str, dict[str, object]] | None = None,
    ) -> None:
        from openai import OpenAI

        self.model = model
        self.max_tokens = max_tokens
        self.temperature = temperature
        self.top_p = top_p
        self.top_k = top_k
        self.media_io_kwargs = media_io_kwargs
        self.client = OpenAI(base_url=base_url, api_key="EMPTY")

    def generate(self, model_input: ModelInput) -> str:
        extra_body = {
            "top_k": self.top_k,
            "skip_special_tokens": False,
            "chat_template_kwargs": model_input.chat_template_kwargs,
        }
        if self.media_io_kwargs is not None:
            extra_body["media_io_kwargs"] = self.media_io_kwargs
        request = {
            "model": self.model,
            "messages": model_input.messages,
            "max_tokens": self.max_tokens,
            "temperature": self.temperature,
            "top_p": self.top_p,
            "extra_body": extra_body,
        }
        if model_input.tools:
            request["tools"] = model_input.tools
            request["tool_choice"] = "none"
        response = self.client.chat.completions.create(**request)
        if not response.choices:
            raise RuntimeError("vLLM returned no choices")
        choice = response.choices[0]
        if choice.finish_reason == "length":
            raise RuntimeError(f"vLLM generation reached max_tokens={self.max_tokens} before completion")
        message = choice.message
        if getattr(message, "tool_calls", None):
            raise RuntimeError("vLLM returned parsed tool calls; disable its automatic tool parser")
        content = message.content or ""
        reasoning = getattr(message, "reasoning_content", None)
        if reasoning is None:
            reasoning = getattr(message, "reasoning", None)
        if reasoning is not None:
            return f"<think>\n{reasoning}\n</think>\n\n{content}"
        return content
