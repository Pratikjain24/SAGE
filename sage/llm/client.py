"""Unified LLM Client supporting OpenAI-compatible endpoints and offline deterministic MockLLM."""

from __future__ import annotations
import time
from abc import ABC, abstractmethod
from typing import Any, Dict, List, Optional
from pydantic import BaseModel
from sage.config.models import ModelConfig
from sage.llm.pricing import PricingModel


class LLMResponse(BaseModel):
    content: str
    tool_calls: List[Dict[str, Any]] = []
    tokens_in: int = 0
    tokens_out: int = 0
    cost_usd: float = 0.0
    latency_ms: int = 0
    is_fallback: bool = False
    model_name: Optional[str] = None
    raw_response: Optional[Dict[str, Any]] = None


class BaseLLMClient(ABC):
    """Abstract base LLM client."""

    @abstractmethod
    def generate(
        self,
        messages: List[Dict[str, str]],
        tools: Optional[List[Dict[str, Any]]] = None,
        temperature: Optional[float] = None,
    ) -> LLMResponse:
        pass


class MockLLMClient(BaseLLMClient):
    """Offline deterministic mock client generating reproducible responses for testing and pilot runs."""

    def __init__(
        self,
        model_name: str = "mock-model",
        canned_responses: Optional[Dict[str, str]] = None,
        canned_list: Optional[List[str]] = None,
    ):
        self.model_name = model_name
        self.canned_responses = canned_responses or {}
        self.canned_list = canned_list or []
        self.call_count = 0

    def generate(
        self,
        messages: List[Dict[str, str]],
        tools: Optional[List[Dict[str, Any]]] = None,
        temperature: Optional[float] = None,
    ) -> LLMResponse:
        self.call_count += 1

        user_content = ""
        for m in reversed(messages):
            if m.get("role") == "user":
                user_content = m.get("content", "")
                break

        # Select response: canned_list -> canned_responses -> default scripted response
        if self.canned_list:
            simulated_response = self.canned_list[(self.call_count - 1) % len(self.canned_list)]
        elif self.canned_responses:
            simulated_response = None
            for key, val in self.canned_responses.items():
                if key.lower() in user_content.lower():
                    simulated_response = val
                    break
            if simulated_response is None:
                simulated_response = list(self.canned_responses.values())[
                    (self.call_count - 1) % len(self.canned_responses)
                ]
        else:
            simulated_response = (
                "I will analyze the task requirements and implement the solution.\n"
                "```python\ndef solve():\n    return 'solved'\n```"
            )

        latency_ms = 15
        tokens_in = max(20, len(user_content.split()) * 2)
        tokens_out = max(10, len(simulated_response.split()))

        cost = PricingModel.calculate_cost(self.model_name, tokens_in, tokens_out)
        return LLMResponse(
            content=simulated_response,
            tool_calls=[],
            tokens_in=tokens_in,
            tokens_out=tokens_out,
            cost_usd=cost,
            latency_ms=latency_ms,
            is_fallback=False,
            model_name=self.model_name,
        )


class OpenAICompatibleClient(BaseLLMClient):
    """Client for OpenAI-compatible APIs (vLLM, Ollama, llama.cpp, OpenAI, Groq)."""

    def __init__(self, config: ModelConfig, allow_fallback: bool = False):
        import os
        try:
            from dotenv import load_dotenv
            load_dotenv()
        except ImportError:
            pass

        self.config = config
        self.api_base = config.api_base or "http://localhost:8000/v1"
        key = config.api_key or ""
        if key.startswith("${") and key.endswith("}"):
            var_name = key[2:-1].strip()
            key = os.environ.get(var_name, "")
        if not key or key == "EMPTY":
            key = (
                os.environ.get("DEEPSEEK_API_KEY")
                or os.environ.get("GROQ_API_KEY")
                or os.environ.get("OPENAI_API_KEY")
                or "EMPTY"
            )
        self.api_key = key
        self.allow_fallback = allow_fallback

    def check_health(self) -> Dict[str, Any]:
        """Check if the remote vLLM/OpenAI server is reachable and query available models."""
        import httpx

        url = f"{self.api_base.rstrip('/')}/models"
        headers = {"Authorization": f"Bearer {self.api_key}"}
        try:
            with httpx.Client(timeout=5.0) as client:
                res = client.get(url, headers=headers)
                res.raise_for_status()
                data = res.json()
            models = [m.get("id") for m in data.get("data", [])]
            return {"status": "ok", "reachable": True, "models": models}
        except Exception as e:
            return {"status": "unreachable", "reachable": False, "error": str(e), "models": []}

    def generate(
        self,
        messages: List[Dict[str, str]],
        tools: Optional[List[Dict[str, Any]]] = None,
        temperature: Optional[float] = None,
    ) -> LLMResponse:
        import httpx

        start = time.time()
        url = f"{self.api_base.rstrip('/')}/chat/completions"
        headers = {"Authorization": f"Bearer {self.api_key}", "Content-Type": "application/json"}
        payload: Dict[str, Any] = {
            "model": self.config.name,
            "messages": messages,
            "temperature": temperature if temperature is not None else self.config.temperature,
            "top_p": self.config.top_p,
            "max_tokens": self.config.max_tokens,
        }
        if tools:
            payload["tools"] = tools

        max_attempts = 6
        last_error = None

        for attempt in range(max_attempts):
            try:
                with httpx.Client(timeout=60.0) as client:
                    res = client.post(url, headers=headers, json=payload)
                    if res.status_code == 429 or res.status_code >= 500:
                        retry_after = 2.0 * (attempt + 1)
                        if "retry-after" in res.headers:
                            try:
                                retry_after = max(float(res.headers["retry-after"]), 1.0)
                            except Exception:
                                pass
                        else:
                            import re
                            try:
                                match = re.search(r"try again in ([\d\.]+)s", res.text)
                                if match:
                                    retry_after = max(float(match.group(1)) + 0.5, 1.0)
                            except Exception:
                                pass
                        print(
                            f"  [LLM Rate Limit] Received status {res.status_code}. Waiting {retry_after:.1f}s before attempt {attempt + 2}/{max_attempts}...",
                            flush=True,
                        )
                        time.sleep(retry_after)
                        continue

                    res.raise_for_status()
                    data = res.json()

                choice = data["choices"][0]
                message = choice["message"]
                content = message.get("content") or ""
                tool_calls = message.get("tool_calls") or []

                usage = data.get("usage", {})
                tokens_in = usage.get("prompt_tokens", len(str(messages)) // 4)
                tokens_out = usage.get("completion_tokens", len(content) // 4)
                cost = PricingModel.calculate_cost(self.config.name, tokens_in, tokens_out)
                latency_ms = int((time.time() - start) * 1000)

                return LLMResponse(
                    content=content,
                    tool_calls=tool_calls,
                    tokens_in=tokens_in,
                    tokens_out=tokens_out,
                    cost_usd=cost,
                    latency_ms=latency_ms,
                    is_fallback=False,
                    model_name=self.config.name,
                    raw_response=data,
                )
            except Exception as e:
                last_error = e
                if attempt < max_attempts - 1:
                    time.sleep(2.0 * (attempt + 1))
                else:
                    break

        if not self.allow_fallback:
            raise RuntimeError(
                f"Real LLM generation failed after {max_attempts} attempts for endpoint '{url}' with model '{self.config.name}': {last_error}"
            ) from last_error

        # Explicit fallback only if permitted
        mock = MockLLMClient(self.config.name)
        resp = mock.generate(messages, tools, temperature)
        resp.is_fallback = True
        resp.content = f"[Offline Fallback due to: {str(last_error)}]\n" + resp.content
        return resp


class AnthropicClient(BaseLLMClient):
    """Client for Anthropic Messages API (Claude 3.5 Sonnet, Claude 3.5 Haiku)."""

    def __init__(self, config: ModelConfig, allow_fallback: bool = False):
        import os
        try:
            from dotenv import load_dotenv
            load_dotenv()
        except ImportError:
            pass

        self.config = config
        self.api_base = (config.api_base or "https://api.anthropic.com/v1").rstrip("/")
        key = config.api_key or ""
        if key.startswith("${") and key.endswith("}"):
            var_name = key[2:-1].strip()
            key = os.environ.get(var_name, "")
        if not key or key == "EMPTY":
            key = os.environ.get("ANTHROPIC_API_KEY", "")
        self.api_key = key
        self.allow_fallback = allow_fallback

    def check_health(self) -> Dict[str, Any]:
        """Check if Anthropic credentials and endpoint are configured."""
        if not self.api_key:
            return {"status": "missing_api_key", "reachable": False, "error": "ANTHROPIC_API_KEY not found in environment", "models": []}
        return {"status": "ok", "reachable": True, "models": [self.config.name]}

    def generate(
        self,
        messages: List[Dict[str, str]],
        tools: Optional[List[Dict[str, Any]]] = None,
        temperature: Optional[float] = None,
    ) -> LLMResponse:
        import httpx

        start = time.time()
        url = f"{self.api_base}/messages" if not self.api_base.endswith("/messages") else self.api_base
        headers = {
            "x-api-key": self.api_key,
            "anthropic-version": "2023-06-01",
            "content-type": "application/json",
        }

        # Format system prompt and conversation turns for Anthropic Messages API
        system_prompt = ""
        anthropic_messages: List[Dict[str, str]] = []
        for m in messages:
            role = m.get("role", "user")
            content = m.get("content", "")
            if role == "system":
                if system_prompt:
                    system_prompt += "\n\n" + content
                else:
                    system_prompt = content
            else:
                anthropic_role = "user" if role == "user" else "assistant"
                anthropic_messages.append({"role": anthropic_role, "content": content})

        if not anthropic_messages:
            anthropic_messages.append({"role": "user", "content": "Execute task instructions."})

        # Merge consecutive turns with identical role (Anthropic requires strict alternation)
        merged_turns: List[Dict[str, str]] = []
        for turn in anthropic_messages:
            if merged_turns and merged_turns[-1]["role"] == turn["role"]:
                merged_turns[-1]["content"] += "\n\n" + turn["content"]
            else:
                merged_turns.append(turn)

        payload: Dict[str, Any] = {
            "model": self.config.name,
            "messages": merged_turns,
            "max_tokens": min(self.config.max_tokens or 4096, 4096),
            "temperature": temperature if temperature is not None else self.config.temperature,
        }
        if system_prompt:
            payload["system"] = system_prompt

        max_attempts = 6
        last_error = None

        for attempt in range(max_attempts):
            try:
                with httpx.Client(timeout=90.0) as client:
                    res = client.post(url, headers=headers, json=payload)
                    if res.status_code == 429 or res.status_code >= 500:
                        retry_after = 2.0 * (attempt + 1)
                        if "retry-after" in res.headers:
                            try:
                                retry_after = max(float(res.headers["retry-after"]), 1.0)
                            except Exception:
                                pass
                        print(
                            f"  [Anthropic Rate Limit] Received status {res.status_code}. Waiting {retry_after:.1f}s before attempt {attempt + 2}/{max_attempts}...",
                            flush=True,
                        )
                        time.sleep(retry_after)
                        continue

                    res.raise_for_status()
                    data = res.json()

                blocks = data.get("content", [])
                content = "".join(b.get("text", "") for b in blocks if b.get("type") == "text")

                usage = data.get("usage", {})
                tokens_in = usage.get("input_tokens", len(str(messages)) // 4)
                tokens_out = usage.get("output_tokens", len(content) // 4)
                cost = PricingModel.calculate_cost(self.config.name, tokens_in, tokens_out)
                latency_ms = int((time.time() - start) * 1000)

                return LLMResponse(
                    content=content,
                    tool_calls=[],
                    tokens_in=tokens_in,
                    tokens_out=tokens_out,
                    cost_usd=cost,
                    latency_ms=latency_ms,
                    is_fallback=False,
                    model_name=self.config.name,
                    raw_response=data,
                )
            except Exception as e:
                last_error = e
                if attempt < max_attempts - 1:
                    time.sleep(2.0 * (attempt + 1))
                else:
                    break

        if not self.allow_fallback:
            raise RuntimeError(
                f"Anthropic API generation failed after {max_attempts} attempts for endpoint '{url}' with model '{self.config.name}': {last_error}"
            ) from last_error

        mock = MockLLMClient(self.config.name)
        resp = mock.generate(messages, tools, temperature)
        resp.is_fallback = True
        resp.content = f"[Offline Fallback due to: {str(last_error)}]\n" + resp.content
        return resp


class LocalLlamaClient(BaseLLMClient):
    """Direct in-process GGUF LLM client powered by llama-cpp-python."""

    _cached_llm: Optional[Any] = None
    _cached_path: Optional[str] = None

    def __init__(
        self,
        model_path: str = "models/qwen2.5-coder-3b-instruct-q4_k_m.gguf",
        context_window: int = 4096,
        n_threads: int = 8,
    ):
        from pathlib import Path

        p = Path(model_path)
        if not p.is_absolute():
            # Check relative to cwd or repo root
            repo_root = Path(__file__).resolve().parent.parent.parent
            if (repo_root / model_path).exists():
                p = repo_root / model_path
            elif Path(model_path).exists():
                p = Path(model_path).resolve()

        self.model_path = str(p.resolve())
        self.model_name = p.stem
        self.context_window = context_window
        self.n_threads = n_threads

        if LocalLlamaClient._cached_llm is None or LocalLlamaClient._cached_path != self.model_path:
            from llama_cpp import Llama
            LocalLlamaClient._cached_llm = Llama(
                model_path=self.model_path,
                n_ctx=self.context_window,
                n_threads=self.n_threads,
                verbose=False,
            )
            LocalLlamaClient._cached_path = self.model_path

        self.llm = LocalLlamaClient._cached_llm

    def check_health(self) -> Dict[str, Any]:
        return {"status": "ok", "reachable": True, "models": [self.model_name]}

    def generate(
        self,
        messages: List[Dict[str, str]],
        tools: Optional[List[Dict[str, Any]]] = None,
        temperature: Optional[float] = None,
    ) -> LLMResponse:
        start = time.time()
        temp = temperature if temperature is not None else 0.2
        resp = self.llm.create_chat_completion(
            messages=messages,
            temperature=temp,
            max_tokens=2048,
        )
        latency_ms = int((time.time() - start) * 1000)
        choice = resp["choices"][0]
        content = choice["message"].get("content", "") or ""
        usage = resp.get("usage", {})
        tokens_in = usage.get("prompt_tokens", max(20, len(str(messages)) // 4))
        tokens_out = usage.get("completion_tokens", max(10, len(content) // 4))
        cost = PricingModel.calculate_cost(self.model_name, tokens_in, tokens_out)

        return LLMResponse(
            content=content,
            tool_calls=[],
            tokens_in=tokens_in,
            tokens_out=tokens_out,
            cost_usd=cost,
            latency_ms=latency_ms,
            is_fallback=False,
            model_name=self.model_name,
            raw_response=resp,
        )
