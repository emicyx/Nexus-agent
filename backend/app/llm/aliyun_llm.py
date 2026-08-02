"""
阿里云通义千问 LLM 实现

基于 CrewAI BaseLLM 抽象类实现，完全兼容 CrewAI 接口，支持：
1. 重试机制：自动重试失败的请求
2. 空内容重试：处理模型返回空内容的情况
3. 异步调用：支持异步 API 调用
4. Function Calling：支持工具调用
5. 多模态支持：支持图片输入（多模态消息）
6. 多地域支持：支持 cn、intl、finance 三个地域

通过自定义 LLM，我们可以在不依赖 OpenAI API 的情况下使用 CrewAI 框架。

- BaseLLM 抽象类：如何实现自定义 LLM
- 错误处理：如何处理 API 错误和重试
- Function Calling：如何实现工具调用机制
- 多模态支持：如何处理图片输入
"""
from __future__ import annotations

import asyncio
import base64
import contextvars
import json
import logging
import os
import re
import time
from dataclasses import dataclass
from pathlib import Path
from typing import Any

import httpx
import requests
from crewai import BaseLLM


def _get_logger():
    """获取模块级 logger。"""
    logger = logging.getLogger("llm.aliyun_llm")
    if not logger.handlers:
        handler = logging.StreamHandler()
        handler.setFormatter(
            logging.Formatter(
                "%(asctime)s - %(name)s - %(levelname)s - %(message)s",
                datefmt="%Y-%m-%d %H:%M:%S",
            )
        )
        logger.addHandler(handler)
        logger.setLevel(logging.INFO)
    logger.propagate = False
    return logger


logger = _get_logger()


@dataclass
class _StreamContext:
    """流式上下文：由 factory.py 的 step_callback 设置，AliyunLLM.call() 读取。

    每个 HTTP 请求有独立的 asyncio Task → 独立的 context → 互不干扰。
    """
    queue: Any            # asyncio.Queue[AgentEvent | None]
    loop: Any             # asyncio.AbstractEventLoop
    agent_role: str
    step_n: int
    route_to_answer: bool = False  # True 时同时推送 token 事件（助手气泡实时流式）

    def on_token(self, token: str) -> None:
        """推送 thinking_token + 可选 token 事件到 SSE 队列（线程安全）。"""
        from app.core.events import AgentEvent
        try:
            self.loop.call_soon_threadsafe(
                self.queue.put_nowait,
                AgentEvent(
                    type="thinking_token",
                    content=token,
                    agent=self.agent_role,
                    step=self.step_n,
                ),
            )
            if self.route_to_answer:
                self.loop.call_soon_threadsafe(
                    self.queue.put_nowait,
                    AgentEvent(type="token", content=token),
                )
        except RuntimeError:
            pass  # loop 已关闭，丢弃事件


_stream_ctx: contextvars.ContextVar = contextvars.ContextVar('_stream_ctx', default=None)


# 模块级 httpx.AsyncClient 单例：原生异步 LLM 调用复用连接池（keep-alive）。
_async_client: httpx.AsyncClient | None = None


def _get_async_client() -> httpx.AsyncClient:
    """懒创建并复用 httpx.AsyncClient（连接池 + TLS 会话复用，进程生命周期不关闭）。"""
    global _async_client
    if _async_client is None:
        _async_client = httpx.AsyncClient(
            timeout=httpx.Timeout(connect=30.0, read=60.0, write=30.0, pool=30.0),
            limits=httpx.Limits(max_connections=100, max_keepalive_connections=20),
        )
    return _async_client


def _sanitize_tool_calls_arguments(tool_calls: list[dict]) -> list[dict]:
    """规范化 tool_calls：确保 function.arguments 是合法 JSON 字符串。

    DashScope 会校验 arguments 必须是 JSON 格式，模型可能返回空串或纯文本。
    同步/异步路径共用。
    """
    out: list[dict] = []
    for tc in tool_calls:
        tc_copy = dict(tc)
        fn = dict(tc_copy.get("function", {}))
        raw_args = fn.get("arguments", "{}")
        if isinstance(raw_args, str):
            try:
                json.loads(raw_args)
            except json.JSONDecodeError:
                logger.warning(
                    "function arguments not valid JSON, replacing with {}: %s",
                    raw_args[:200],
                )
                fn["arguments"] = "{}"
        else:
            fn["arguments"] = json.dumps(raw_args, ensure_ascii=False)
        tc_copy["function"] = fn
        out.append(tc_copy)
    return out


class AliyunLLM(BaseLLM):
    """阿里云通义千问 LLM 实现类，支持重试与异步调用。"""

    ENDPOINTS = {
        "cn": "https://dashscope.aliyuncs.com/compatible-mode/v1/chat/completions",
        "intl": "https://dashscope-intl.aliyuncs.com/compatible-mode/v1/chat/completions",
        "finance": "https://dashscope-finance.aliyuncs.com/compatible-mode/v1/chat/completions",
    }

    def __init__(
        self,
        model: str,
        image_model: str | None = None,
        api_key: str | None = None,
        region: str = "cn",
        temperature: float | None = None,
        timeout: int = 600,
        retry_count: int | None = None,
    ) -> None:
        """
        初始化阿里云 LLM。

        Args:
            model: 模型名称，如 "qwen-plus", "qwen-turbo" 等
            api_key: API Key，不提供则从环境变量 QWEN_API_KEY 或 DASHSCOPE_API_KEY 读取
            region: 地域 "cn" / "intl" / "finance"
            temperature: 采样温度
            timeout: 请求超时（秒），默认 600
            retry_count: 请求失败时的重试次数，默认 2；可从环境变量 LLM_RETRY_COUNT 读取
        """
        super().__init__(model=model, temperature=temperature)

        self.api_key = api_key or os.getenv("QWEN_API_KEY") or os.getenv("DASHSCOPE_API_KEY")
        if not self.api_key:
            raise ValueError(
                "API Key 未提供。请通过 api_key 传入或设置环境变量 QWEN_API_KEY 或 DASHSCOPE_API_KEY"
            )

        if region not in self.ENDPOINTS:
            raise ValueError(f"不支持的地域: {region}，支持: {list(self.ENDPOINTS.keys())}")
        self.endpoint = self.ENDPOINTS[region]
        self.region = region
        self.timeout = timeout
        self.image_model = image_model
        if not self.image_model:
            self.image_model = "qwen3-vl-plus"
        _rc = retry_count
        if _rc is None and os.getenv("LLM_RETRY_COUNT") is not None:
            try:
                _rc = int(os.getenv("LLM_RETRY_COUNT", "2"))
            except ValueError:
                _rc = 2
        self.retry_count = _rc if _rc is not None else 2
        # Week 11 性能优化：复用 requests.Session，让 keep-alive 连接池跨请求复用，
        # 首次 chat 不必重新 TLS 握手（startup 时 warmup 已建立会话）。
        self._session: requests.Session | None = None

    def _get_session(self) -> requests.Session:
        """延迟创建并复用 requests.Session（连接池+TLS 会话复用）。"""
        if self._session is None:
            self._session = requests.Session()
        return self._session

    def _normalize_multimodal_tool_result(self, messages: list[dict[str, Any]]) -> tuple[list[dict[str, Any]], bool]:
        """
        将 CrewAI 对 AddImageTool/AddImageToolLocal 的 stringify 结果还原为多模态 user 消息，
        否则 DashScope 会因消息格式或体积返回 400。

        兼容两种 Agent 调用模式：
        - 旧版 ReAct：base64/URL 在 assistant 消息的 content 字符串中（Thought/Action/Observation）
        - 新版 Function Calling：base64 在 role=tool 消息的 content 中，图片合并到紧随其后的 user
          消息。假设 user 消息紧跟在所有 tool 消息之后（CrewAI 当前行为）；若消息列表以 tool 结尾
          则自动 flush 一条合成 user 消息。

        Returns:
            tuple[list[dict[str, Any]], bool]: 处理后的消息列表 + 是否需要切换多模态模型
        """
        out: list[dict[str, Any]] = []
        flag = False
        # function calling 模式：累积待注入到下一条 user 消息的图片 URL 列表
        # 用列表支持同一轮多个 tool 返回图片的情况
        pending_images: list[str] = []

        for msg in messages:
            role = msg.get("role")
            content = msg.get("content")

            # ── 新版 Function Calling：tool 消息 content 含 base64 data URL ───
            if role == "tool" and isinstance(content, str) and "data:image/" in content and ";base64," in content:
                data_url_start = content.find("data:image/")
                prefix = content[:data_url_start]
                data_url = content[data_url_start:]
                pending_images.append(data_url)
                new_msg = dict(msg)
                new_msg["content"] = (prefix + "图片内容已加载") if prefix else "图片内容已加载"
                out.append(new_msg)
                flag = True
                logger.info("normalized_multimodal_tool_result: function calling mode, base64 in tool message")
                continue

            # ── 新版 Function Calling：把图片合并到紧随其后的 user 消息 ──────
            # 注：仅在紧跟 tool 消息的第一条 user 消息时触发，与 CrewAI 当前消息结构一致
            if pending_images and role == "user":
                text = content if isinstance(content, str) else ""
                image_blocks = [{"type": "image_url", "image_url": {"url": u}} for u in pending_images]
                out.append({
                    "role": "user",
                    "content": [{"type": "text", "text": text}] + image_blocks,
                })
                pending_images = []
                logger.info("normalized_multimodal_tool_result: injected %d image(s) into user message (function calling)", len(image_blocks))
                continue

            # ── 旧版 ReAct：assistant 消息 content 字符串含 Observation base64 ─
            # content 可能是 None（tool_calls 消息）或 list（多模态 assistant），均跳过
            if role == "assistant" and isinstance(content, str):
                s = content
                if "Add image to content Local" in s and "data:image/" in s and ";base64," in s:
                    logger.info("normalized_multimodal_tool_result: ReAct mode, base64 in assistant message")
                    data_url_start = s.find("data:image/")
                    data_url = s[data_url_start:]
                    text = s[:data_url_start] + "图片内容已加载"
                    out.append({
                        "role": "user",
                        "content": [
                            {"type": "text", "text": text},
                            {"type": "image_url", "image_url": {"url": data_url}},
                        ],
                    })
                    flag = True
                    continue
                elif "Add image to content Local" in s and "Observation: http" in s:
                    obs_start = s.find("Observation: http")
                    http_start = s.find("http", obs_start)
                    data_url = s[http_start:]
                    text = s[:obs_start] + "图片内容已加载"
                    out.append({
                        "role": "user",
                        "content": [
                            {"type": "text", "text": text},
                            {"type": "image", "image": data_url},
                        ],
                    })
                    flag = True
                    continue

            out.append(msg)

        # ── Flush：tool 消息是最后一条（后面没有 user 消息）时合成一条 user 消息 ─
        if pending_images:
            image_blocks = [{"type": "image_url", "image_url": {"url": u}} for u in pending_images]
            out.append({
                "role": "user",
                "content": [{"type": "text", "text": "请分析上面工具返回的图片内容。"}] + image_blocks,
            })
            logger.warning(
                "normalized_multimodal_tool_result: flushed %d pending image(s) — tool message was last in list",
                len(image_blocks),
            )

        return out, flag

    def call(
        self,
        messages: str | list[dict[str, Any]],
        tools: list[dict] | None = None,
        callbacks: list[Any] | None = None,
        available_functions: dict[str, Any] | None = None,
        max_iterations: int = 10,
        _retry_on_empty: bool = True,
        **kwargs: Any,
    ) -> str | Any:
        """
        调用阿里云 LLM API，支持 Function Calling、多模态消息、重试与空内容重试。

        Args:
            messages: 消息列表或单字符串；content 可为字符串或多模态数组
            tools: 工具定义（Function Calling）
            callbacks: 回调列表
            available_functions: 可执行函数映射
            max_iterations: Function Calling 最大迭代次数
            _retry_on_empty: 是否在返回空内容时自动重试
            **kwargs: 兼容 CrewAI 额外参数（如 from_task）
        Returns:
            LLM 返回的文本内容
        """
        if max_iterations <= 0:
            raise RuntimeError("Function calling 达到最大迭代次数，可能存在无限循环")

        if isinstance(messages, str):
            messages = [{"role": "user", "content": messages}]

        messages, flag = self._normalize_multimodal_tool_result(messages)
        logger.info("normalized_multimodal_tool_result flag=%s messages=%s", flag, json.dumps(messages, ensure_ascii=False, indent=2))
        self._validate_messages(messages)

        payload: dict[str, Any] = {
            "model": self.model,
            "messages": messages,
        }
        if flag:
            payload["model"] = self.image_model
        if self.temperature is not None:
            payload["temperature"] = self.temperature
        if self.stop and self.supports_stop_words():
            stop_value = self._prepare_stop_words(self.stop)
            if stop_value:
                payload["stop"] = stop_value
        if tools and self.supports_function_calling():
            payload["tools"] = tools

        if callbacks:
            for cb in callbacks:
                if hasattr(cb, "on_llm_start"):
                    try:
                        cb.on_llm_start(messages)
                    except Exception:
                        pass

        # 流式路径：有 stream context 时走流式（包括有 tool_calls 的情况）
        # 多模态模型 (flag=True) 可能不支持流式 tool_calls，安全降级到非流式
        from app.config import settings as app_settings
        stream_ctx = _stream_ctx.get()
        result: dict[str, Any] | None = None
        content: str | None = None

        if stream_ctx is not None and app_settings.STREAMING_WITH_TOOLS_ENABLED and not flag:
            session = self._get_session()
            stream_result = self._call_streaming(payload, session, stream_ctx)
            if isinstance(stream_result, dict):
                # 含 tool_calls → 与非流式路径共享 _process_response
                result = stream_result
            else:
                # 纯文本，token 已全部流式推送
                content = stream_result
        else:
            result = self._do_call(payload)
            logger.info("收到 LLM API 响应  result=%s", result)

        # 统一触发 on_llm_end 回调
        if result is not None:
            if callbacks:
                for cb in callbacks:
                    if hasattr(cb, "on_llm_end"):
                        try:
                            cb.on_llm_end(result)
                        except Exception:
                            pass
            content = self._process_response(result, messages, tools, available_functions, max_iterations)
            if not isinstance(content, str):
                # tool_calls 列表或 _handle_function_calls 递归结果
                return content
        else:
            # 纯文本流式路径：content 已设置，构造回调数据
            if callbacks:
                for cb in callbacks:
                    if hasattr(cb, "on_llm_end"):
                        try:
                            cb.on_llm_end({"choices": [{"message": {"content": content}}]})
                        except Exception:
                            pass

        if content is None or (isinstance(content, str) and not content.strip()):
            if _retry_on_empty:
                max_empty_retries = 2
                empty_retry_count = kwargs.get("_empty_retry_count", 0)
                if empty_retry_count >= max_empty_retries:
                    raise ValueError(
                        f"LLM 连续 {max_empty_retries + 1} 次返回空内容，可能是模型限流或异常，请稍后重试或检查 API 配额"
                    )
                logger.warning(
                    "llm_empty_content_retry model=%s retry_count=%s max_retries=%s",
                    self.model,
                    empty_retry_count + 1,
                    max_empty_retries,
                )
                return self.call(
                    messages,
                    tools=tools,
                    callbacks=callbacks,
                    available_functions=available_functions,
                    max_iterations=max_iterations,
                    _retry_on_empty=False,
                    _empty_retry_count=empty_retry_count + 1,
                    **kwargs,
                )
            raise ValueError(
                "LLM 返回空内容，可能是模型限流或偶发异常，请稍后重试或检查 API 配额"
            )

        return content

    def _do_call(
        self,
        payload: dict[str, Any],
    ) -> dict[str, Any]:
        """非流式 HTTP 请求（含重试、错误处理），返回原始 result dict。"""
        last_exception: BaseException | None = None
        result: dict[str, Any] = {}
        _t_llm0 = time.perf_counter()
        session = self._get_session()
        for attempt in range(self.retry_count + 1):
            try:
                response = session.post(
                    self.endpoint,
                    headers={
                        "Authorization": f"Bearer {self.api_key}",
                        "Content-Type": "application/json",
                    },
                    json=payload,
                    timeout=self.timeout,
                )
                status_code = response.status_code
                if status_code >= 500:
                    if attempt < self.retry_count:
                        logger.warning(
                            "llm_server_error_retry status_code=%s attempt=%s max=%s",
                            status_code,
                            attempt + 1,
                            self.retry_count + 1,
                        )
                        last_exception = RuntimeError(
                            f"LLM 服务器错误 {status_code}: {response.text[:200]}"
                        )
                        continue
                    response.raise_for_status()
                elif status_code == 429:
                    if attempt < self.retry_count:
                        logger.warning(
                            "llm_rate_limit_retry attempt=%s max=%s",
                            attempt + 1,
                            self.retry_count + 1,
                        )
                        last_exception = RuntimeError(f"LLM 请求限流: {response.text[:200]}")
                        continue
                    response.raise_for_status()
                elif status_code >= 400:
                    err_body = response.text[:500] if response.text else ""
                    logger.error(
                        "llm_request_4xx status_code=%s url=%s body=%s",
                        status_code,
                        response.url,
                        err_body,
                    )
                    response.raise_for_status()

                result = response.json()
                if attempt > 0:
                    logger.info(
                        "llm_request_success_after_retry attempt=%s total=%s",
                        attempt + 1,
                        self.retry_count + 1,
                    )
                logger.info(
                    "timing: llm.call request %.3fs (model=%s, attempt=%s, status=%s)",
                    time.perf_counter() - _t_llm0,
                    payload.get("model"),
                    attempt + 1,
                    status_code,
                )
                # 打印百炼返回的限流 quota 信息（帮助诊断 TPM/RPM 瓶颈）
                rl_rem_req = response.headers.get("X-RateLimit-Remaining-Requests")
                rl_rem_tok = response.headers.get("X-RateLimit-Remaining-Tokens")
                if rl_rem_req is not None or rl_rem_tok is not None:
                    logger.info(
                        "llm rate-limit headers: remaining_requests=%s remaining_tokens=%s "
                        "reset_requests=%s reset_tokens=%s",
                        rl_rem_req or "N/A",
                        rl_rem_tok or "N/A",
                        response.headers.get("X-RateLimit-Reset-Requests", "N/A"),
                        response.headers.get("X-RateLimit-Reset-Tokens", "N/A"),
                    )
                if logger.isEnabledFor(logging.DEBUG):
                    logger.debug("Response result: %s", json.dumps(result, ensure_ascii=False, indent=2))
                return result

            except requests.Timeout:
                last_exception = TimeoutError(f"LLM 请求超时（{self.timeout} 秒）")
                if attempt < self.retry_count:
                    logger.warning(
                        "llm_timeout_retry timeout=%s attempt=%s max=%s",
                        self.timeout,
                        attempt + 1,
                        self.retry_count + 1,
                    )
                    continue
                logger.error(
                    "llm_timeout_final timeout=%s total_attempts=%s",
                    self.timeout,
                    self.retry_count + 1,
                )
                raise last_exception
            except requests.RequestException as e:
                last_exception = RuntimeError(f"LLM 请求失败: {e}")
                if attempt < self.retry_count:
                    logger.warning(
                        "llm_request_error_retry error=%s attempt=%s max=%s",
                        str(e),
                        attempt + 1,
                        self.retry_count + 1,
                    )
                    continue
                logger.exception("llm_request_failed error=%s total_attempts=%s", str(e), self.retry_count + 1)
                raise last_exception
        if last_exception:
            raise last_exception
        raise RuntimeError("LLM 请求失败：未知错误")
    
    def _process_response(
        self,
        result: dict[str, Any],
        messages: list[dict[str, Any]],
        tools: list[dict] | None,
        available_functions: dict[str, Any] | None,
        max_iterations: int,
    ) -> str | Any:
        """解析 LLM 响应 dict：提取 tool_calls 或 content。

        共享路径 — 流式（含 tool_calls）和非流式均使用本方法处理 result dict。
        返回 str（文本内容）或 tool_calls 列表（或 _handle_function_calls 的递归结果）。
        """
        if "choices" not in result or not result["choices"]:
            raise ValueError("响应中未找到 choices 字段")

        message = result["choices"][0].get("message", {})
        if "tool_calls" in message:
            if available_functions:
                return self._handle_function_calls(
                    message["tool_calls"],
                    messages,
                    tools,
                    available_functions,
                    max_iterations - 1,
                )
            # CrewAI 会故意传 available_functions=None，让 LLM 只返回原始 tool_calls，
            # 由 executor 的 _handle_native_tool_calls 执行。此处直接返回 tool_calls 列表。
            for tc in message["tool_calls"]:
                fn = tc.get("function")
                if fn and isinstance(fn.get("arguments"), str):
                    raw = fn["arguments"]
                    try:
                        json.loads(raw)
                    except json.JSONDecodeError:
                        logger.warning("function arguments not valid JSON, replacing with {}: %s", raw[:200])
                        fn["arguments"] = "{}"
            return message["tool_calls"]

        content = message.get("content")
        if content is None:
            raise ValueError("响应中未找到 content 字段")
        return content

    def _handle_function_calls(
        self,
        tool_calls: list[dict],
        messages: list[dict[str, Any]],
        tools: list[dict] | None,
        available_functions: dict[str, Any],
        max_iterations: int,
    ) -> str | Any:
        """处理 Function Calling 递归调用。"""
        if max_iterations <= 0:
            raise RuntimeError("Function calling 达到最大迭代次数，可能存在无限循环")

        # 规范化 tool_calls：确保 function.arguments 是合法 JSON 字符串
        # DashScope 会校验 arguments 必须是 JSON 格式，模型可能返回空串或纯文本
        sanitized_tool_calls = []
        for tc in tool_calls:
            tc_copy = dict(tc)
            fn = dict(tc_copy.get("function", {}))
            raw_args = fn.get("arguments", "{}")
            if isinstance(raw_args, str):
                try:
                    json.loads(raw_args)
                except json.JSONDecodeError:
                    logger.warning(
                        "function arguments not valid JSON, replacing with {}: %s",
                        raw_args[:200],
                    )
                    fn["arguments"] = "{}"
            else:
                fn["arguments"] = json.dumps(raw_args, ensure_ascii=False)
            tc_copy["function"] = fn
            sanitized_tool_calls.append(tc_copy)

        messages.append({
            "role": "assistant",
            "content": None,
            "tool_calls": sanitized_tool_calls,
        })

        for tool_call in sanitized_tool_calls:
            fn_info = tool_call.get("function", {})
            fn_name = fn_info.get("name")
            tool_call_id = tool_call.get("id")
            if not tool_call_id:
                raise ValueError(f"tool_call 缺少 id: {tool_call}")

            if fn_name in available_functions:
                try:
                    raw = fn_info.get("arguments", "{}")
                    args = json.loads(raw) if isinstance(raw, str) and raw.strip() else {}
                except json.JSONDecodeError as e:
                    raise ValueError(f"无法解析函数参数: {e}") from e
                try:
                    function_result = available_functions[fn_name](**args)
                except Exception as e:
                    function_result = f"函数执行错误: {str(e)}"
                messages.append({
                    "role": "tool",
                    "tool_call_id": tool_call_id,
                    "content": str(function_result),
                })
            else:
                messages.append({
                    "role": "tool",
                    "tool_call_id": tool_call_id,
                    "content": f"函数 {fn_name} 不可用",
                })

        return self.call(messages, tools, None, available_functions, max_iterations - 1)

    async def acall(
        self,
        messages: str | list[dict[str, Any]],
        tools: list[dict] | None = None,
        callbacks: list[Any] | None = None,
        available_functions: dict[str, Any] | None = None,
        max_iterations: int = 10,
        _retry_on_empty: bool = True,
        **kwargs: Any,
    ) -> str | Any:
        """原生异步调用阿里云 Chat Completions API（httpx.AsyncClient，不占线程）。

        与同步 call 保持相同语义：多模态归一化、流式/非流式、重试、空内容重试、
        Function Calling 递归。主路径（CrewAI async agent loop → aget_llm_response →
        await llm.acall）走本方法；同步 call 保留供 LTM 线程 / delegation 子 agent /
        边缘同步调用点使用。
        """
        return await self._acall(
            messages,
            tools=tools,
            callbacks=callbacks,
            available_functions=available_functions,
            max_iterations=max_iterations,
            _retry_on_empty=_retry_on_empty,
            **kwargs,
        )

    async def _acall(
        self,
        messages: str | list[dict[str, Any]],
        tools: list[dict] | None = None,
        callbacks: list[Any] | None = None,
        available_functions: dict[str, Any] | None = None,
        max_iterations: int = 10,
        _retry_on_empty: bool = True,
        **kwargs: Any,
    ) -> str | Any:
        """异步编排器，镜像 call() 的分支与空内容重试逻辑。"""
        if max_iterations <= 0:
            raise RuntimeError("Function calling 达到最大迭代次数，可能存在无限循环")

        if isinstance(messages, str):
            messages = [{"role": "user", "content": messages}]

        messages, flag = self._normalize_multimodal_tool_result(messages)
        self._validate_messages(messages)

        payload = self._build_payload(messages, tools, flag)

        if callbacks:
            for cb in callbacks:
                if hasattr(cb, "on_llm_start"):
                    try:
                        cb.on_llm_start(messages)
                    except Exception:
                        pass

        # 流式路径：有 stream context 时走流式（包括有 tool_calls 的情况）
        from app.config import settings as app_settings
        stream_ctx = _stream_ctx.get()
        result: dict[str, Any] | None = None
        content: str | None = None

        if stream_ctx is not None and app_settings.STREAMING_WITH_TOOLS_ENABLED and not flag:
            stream_result = await self._acall_streaming(payload, stream_ctx)
            if isinstance(stream_result, dict):
                result = stream_result
            else:
                content = stream_result
        else:
            result = await self._ado_call(payload)
            logger.info("收到 LLM API 响应  result=%s", result)

        if result is not None:
            if callbacks:
                for cb in callbacks:
                    if hasattr(cb, "on_llm_end"):
                        try:
                            cb.on_llm_end(result)
                        except Exception:
                            pass
            content = await self._extract_async_response(
                result, messages, tools, available_functions, max_iterations
            )
            if not isinstance(content, str):
                return content
        else:
            if callbacks:
                for cb in callbacks:
                    if hasattr(cb, "on_llm_end"):
                        try:
                            cb.on_llm_end({"choices": [{"message": {"content": content}}]})
                        except Exception:
                            pass

        if content is None or (isinstance(content, str) and not content.strip()):
            if _retry_on_empty:
                max_empty_retries = 2
                empty_retry_count = kwargs.get("_empty_retry_count", 0)
                if empty_retry_count >= max_empty_retries:
                    raise ValueError(
                        f"LLM 连续 {max_empty_retries + 1} 次返回空内容，可能是模型限流或异常，请稍后重试或检查 API 配额"
                    )
                logger.warning(
                    "llm_empty_content_retry model=%s retry_count=%s max_retries=%s",
                    self.model,
                    empty_retry_count + 1,
                    max_empty_retries,
                )
                return await self.acall(
                    messages,
                    tools=tools,
                    callbacks=callbacks,
                    available_functions=available_functions,
                    max_iterations=max_iterations,
                    _retry_on_empty=False,
                    _empty_retry_count=empty_retry_count + 1,
                    **kwargs,
                )
            raise ValueError(
                "LLM 返回空内容，可能是模型限流或偶发异常，请稍后重试或检查 API 配额"
            )

        return content

    def _build_payload(
        self,
        messages: list[dict[str, Any]],
        tools: list[dict] | None,
        flag: bool,
    ) -> dict[str, Any]:
        """构造请求 payload（同步/异步路径共用）。"""
        payload: dict[str, Any] = {
            "model": self.image_model if flag else self.model,
            "messages": messages,
        }
        if self.temperature is not None:
            payload["temperature"] = self.temperature
        if self.stop and self.supports_stop_words():
            stop_value = self._prepare_stop_words(self.stop)
            if stop_value:
                payload["stop"] = stop_value
        if tools and self.supports_function_calling():
            payload["tools"] = tools
        return payload

    async def _extract_async_response(
        self,
        result: dict[str, Any],
        messages: list[dict[str, Any]],
        tools: list[dict] | None,
        available_functions: dict[str, Any] | None,
        max_iterations: int,
    ) -> str | Any:
        """异步版 _process_response：解析 tool_calls 或 content。"""
        if "choices" not in result or not result["choices"]:
            raise ValueError("响应中未找到 choices 字段")

        message = result["choices"][0].get("message", {})
        if "tool_calls" in message:
            if available_functions:
                return await self._ahandle_function_calls(
                    message["tool_calls"],
                    messages,
                    tools,
                    available_functions,
                    max_iterations - 1,
                )
            # CrewAI 故意传 available_functions=None，由 executor 的
            # _handle_native_tool_calls 执行；此处直接返回规范化后的 tool_calls。
            return _sanitize_tool_calls_arguments(message["tool_calls"])

        content = message.get("content")
        if content is None:
            raise ValueError("响应中未找到 content 字段")
        return content

    async def _ahandle_function_calls(
        self,
        tool_calls: list[dict],
        messages: list[dict[str, Any]],
        tools: list[dict] | None,
        available_functions: dict[str, Any],
        max_iterations: int,
    ) -> str | Any:
        """异步版 _handle_function_calls：工具在 worker 线程执行，递归走 acall。"""
        if max_iterations <= 0:
            raise RuntimeError("Function calling 达到最大迭代次数，可能存在无限循环")

        sanitized_tool_calls = _sanitize_tool_calls_arguments(tool_calls)

        messages.append({
            "role": "assistant",
            "content": None,
            "tool_calls": sanitized_tool_calls,
        })

        for tool_call in sanitized_tool_calls:
            fn_info = tool_call.get("function", {})
            fn_name = fn_info.get("name")
            tool_call_id = tool_call.get("id")
            if not tool_call_id:
                raise ValueError(f"tool_call 缺少 id: {tool_call}")

            if fn_name in available_functions:
                try:
                    raw = fn_info.get("arguments", "{}")
                    args = json.loads(raw) if isinstance(raw, str) and raw.strip() else {}
                except json.JSONDecodeError as e:
                    raise ValueError(f"无法解析函数参数: {e}") from e
                try:
                    function_result = await asyncio.to_thread(
                        available_functions[fn_name], **args
                    )
                except Exception as e:
                    function_result = f"函数执行错误: {str(e)}"
                messages.append({
                    "role": "tool",
                    "tool_call_id": tool_call_id,
                    "content": str(function_result),
                })
            else:
                messages.append({
                    "role": "tool",
                    "tool_call_id": tool_call_id,
                    "content": f"函数 {fn_name} 不可用",
                })

        return await self.acall(messages, tools, None, available_functions, max_iterations - 1)

    async def _ado_call(self, payload: dict[str, Any]) -> dict[str, Any]:
        """原生异步非流式 HTTP 请求（含重试、错误处理），返回原始 result dict。"""
        last_exception: BaseException | None = None
        _t_llm0 = time.perf_counter()
        client = _get_async_client()
        timeout = httpx.Timeout(connect=30.0, read=float(self.timeout), write=30.0, pool=30.0)
        headers = {
            "Authorization": f"Bearer {self.api_key}",
            "Content-Type": "application/json",
        }
        for attempt in range(self.retry_count + 1):
            try:
                resp = await client.post(
                    self.endpoint,
                    headers=headers,
                    json=payload,
                    timeout=timeout,
                )
                status_code = resp.status_code
                if status_code >= 500:
                    if attempt < self.retry_count:
                        logger.warning(
                            "llm_server_error_retry status_code=%s attempt=%s max=%s",
                            status_code,
                            attempt + 1,
                            self.retry_count + 1,
                        )
                        last_exception = RuntimeError(
                            f"LLM 服务器错误 {status_code}: {resp.text[:200]}"
                        )
                        continue
                    resp.raise_for_status()
                elif status_code == 429:
                    if attempt < self.retry_count:
                        logger.warning(
                            "llm_rate_limit_retry attempt=%s max=%s",
                            attempt + 1,
                            self.retry_count + 1,
                        )
                        last_exception = RuntimeError(f"LLM 请求限流: {resp.text[:200]}")
                        continue
                    resp.raise_for_status()
                elif status_code >= 400:
                    err_body = resp.text[:500] if resp.text else ""
                    logger.error(
                        "llm_request_4xx status_code=%s url=%s body=%s",
                        status_code,
                        resp.url,
                        err_body,
                    )
                    resp.raise_for_status()

                result = resp.json()
                if attempt > 0:
                    logger.info(
                        "llm_request_success_after_retry attempt=%s total=%s",
                        attempt + 1,
                        self.retry_count + 1,
                    )
                logger.info(
                    "timing: llm.acall request %.3fs (model=%s, attempt=%s, status=%s)",
                    time.perf_counter() - _t_llm0,
                    payload.get("model"),
                    attempt + 1,
                    status_code,
                )
                rl_rem_req = resp.headers.get("X-RateLimit-Remaining-Requests")
                rl_rem_tok = resp.headers.get("X-RateLimit-Remaining-Tokens")
                if rl_rem_req is not None or rl_rem_tok is not None:
                    logger.info(
                        "llm rate-limit headers: remaining_requests=%s remaining_tokens=%s "
                        "reset_requests=%s reset_tokens=%s",
                        rl_rem_req or "N/A",
                        rl_rem_tok or "N/A",
                        resp.headers.get("X-RateLimit-Reset-Requests", "N/A"),
                        resp.headers.get("X-RateLimit-Reset-Tokens", "N/A"),
                    )
                if logger.isEnabledFor(logging.DEBUG):
                    logger.debug("Response result: %s", json.dumps(result, ensure_ascii=False, indent=2))
                return result

            except httpx.TimeoutException:
                last_exception = TimeoutError(f"LLM 请求超时（{self.timeout} 秒）")
                if attempt < self.retry_count:
                    logger.warning(
                        "llm_timeout_retry timeout=%s attempt=%s max=%s",
                        self.timeout,
                        attempt + 1,
                        self.retry_count + 1,
                    )
                    continue
                logger.error(
                    "llm_timeout_final timeout=%s total_attempts=%s",
                    self.timeout,
                    self.retry_count + 1,
                )
                raise last_exception
            except httpx.RequestError as e:
                last_exception = RuntimeError(f"LLM 请求失败: {e}")
                if attempt < self.retry_count:
                    logger.warning(
                        "llm_request_error_retry error=%s attempt=%s max=%s",
                        str(e),
                        attempt + 1,
                        self.retry_count + 1,
                    )
                    continue
                logger.exception("llm_request_failed error=%s total_attempts=%s", str(e), self.retry_count + 1)
                raise last_exception
        if last_exception:
            raise last_exception
        raise RuntimeError("LLM 请求失败：未知错误")

    async def _acall_streaming(
        self,
        payload: dict[str, Any],
        ctx: _StreamContext,
    ) -> str | dict[str, Any]:
        """原生异步流式调用：SSE 解析 + tool_calls 累积 + 文本 token 实时推送。

        DashScope SSE 格式与同步 _call_streaming 相同（delta.content 与
        delta.tool_calls 互斥、arguments 跨 chunk 累积、finish_reason 终止）。
        """
        t0 = time.perf_counter()
        full_text = ""
        tool_calls_acc: dict[int, dict[str, Any]] = {}
        has_tool_calls = False
        client = _get_async_client()
        timeout = httpx.Timeout(connect=30.0, read=float(self.timeout), write=30.0, pool=30.0)
        headers = {
            "Authorization": f"Bearer {self.api_key}",
            "Content-Type": "application/json",
            "Accept": "text/event-stream",
        }

        try:
            async with client.stream(
                "POST",
                self.endpoint,
                headers=headers,
                json={**payload, "stream": True},
                timeout=timeout,
            ) as resp:
                if resp.status_code != 200:
                    logger.warning(
                        "streaming request returned %d, falling back to non-streaming: %s",
                        resp.status_code,
                        resp.text[:200],
                    )
                    return await self._afallback_call(payload)

                async for line in resp.aiter_lines():
                    if not line:
                        continue
                    if not line.startswith("data:"):
                        continue
                    data_str = line[5:].strip()
                    if data_str == "[DONE]":
                        break
                    try:
                        chunk = json.loads(data_str)
                    except json.JSONDecodeError:
                        continue
                    choices = chunk.get("choices", [])
                    if not choices:
                        continue
                    delta = choices[0].get("delta", {})
                    finish_reason = choices[0].get("finish_reason")

                    # ① 处理 tool_calls delta（与 content 互斥）
                    tool_calls_delta = delta.get("tool_calls")
                    if tool_calls_delta:
                        has_tool_calls = True
                        for tc in tool_calls_delta:
                            idx = tc.get("index", 0)
                            if idx not in tool_calls_acc:
                                tool_calls_acc[idx] = {
                                    "id": "",
                                    "type": "function",
                                    "function": {"name": "", "arguments": ""},
                                }
                            entry = tool_calls_acc[idx]
                            if tc.get("id"):
                                entry["id"] = tc["id"]
                            if tc.get("type"):
                                entry["type"] = tc["type"]
                            fn = tc.get("function", {})
                            if fn.get("name"):
                                entry["function"]["name"] += fn["name"]
                            if fn.get("arguments"):
                                entry["function"]["arguments"] += fn["arguments"]
                        # 检测到 tool_calls 后停止流式推送文本 token
                        continue

                    # ② 处理 delta.content — 仅在未出现 tool_calls 时流式推送
                    content = delta.get("content", "")
                    if content:
                        full_text += content
                        if not has_tool_calls:
                            ctx.on_token(content)

                    if finish_reason:
                        break
        except httpx.TimeoutException as e:
            logger.warning("streaming request timed out: %s, falling back to non-streaming", e)
            return await self._afallback_call(payload)
        except httpx.RequestError as e:
            logger.warning("streaming request failed: %s, falling back to non-streaming", e)
            return await self._afallback_call(payload)
        except Exception as e:
            logger.warning("streaming parse error: %s, partial_text=%d chars", e, len(full_text))
            if full_text.strip():
                logger.info(
                    "timing: llm.acall streaming (partial) %.3fs (model=%s, chars=%d)",
                    time.perf_counter() - t0,
                    payload.get("model"),
                    len(full_text),
                )
                return full_text
            return await self._afallback_call(payload)

        # 有 tool_calls → 返回与 _ado_call 格式一致的 dict
        if has_tool_calls and tool_calls_acc:
            sorted_tool_calls = [tool_calls_acc[i] for i in sorted(tool_calls_acc.keys())]
            logger.info(
                "timing: llm.acall streaming+tool_calls %.3fs (model=%s, text_chars=%d, tool_calls=%d)",
                time.perf_counter() - t0,
                payload.get("model"),
                len(full_text),
                len(sorted_tool_calls),
            )
            return {
                "choices": [{
                    "index": 0,
                    "message": {
                        "role": "assistant",
                        "content": full_text.strip() or None,
                        "tool_calls": sorted_tool_calls,
                    },
                    "finish_reason": "tool_calls",
                }]
            }

        logger.info(
            "timing: llm.acall streaming %.3fs (model=%s, chars=%d)",
            time.perf_counter() - t0,
            payload.get("model"),
            len(full_text),
        )
        if not full_text.strip():
            return await self._afallback_call(payload)
        return full_text

    async def _afallback_call(self, payload: dict[str, Any]) -> str | dict[str, Any]:
        """原生异步非流式 fallback：单次请求返回完整响应。"""
        t0 = time.perf_counter()
        client = _get_async_client()
        timeout = httpx.Timeout(connect=30.0, read=float(self.timeout), write=30.0, pool=30.0)
        headers = {
            "Authorization": f"Bearer {self.api_key}",
            "Content-Type": "application/json",
        }
        for attempt in range(self.retry_count + 1):
            try:
                resp = await client.post(
                    self.endpoint,
                    headers=headers,
                    json=payload,
                    timeout=timeout,
                )
                if resp.status_code != 200:
                    if attempt < self.retry_count:
                        continue
                    resp.raise_for_status()
                result = resp.json()
                logger.info(
                    "timing: llm.acall non-streaming %.3fs (model=%s)",
                    time.perf_counter() - t0,
                    payload.get("model"),
                )
                choices = result.get("choices", [])
                if choices:
                    message = choices[0].get("message", {})
                    # 含 tool_calls 时返回完整 dict，供 _extract_async_response 处理
                    if "tool_calls" in message:
                        return result
                    return message.get("content", "") or ""
                return ""
            except (httpx.TimeoutException, httpx.RequestError):
                if attempt >= self.retry_count:
                    raise
                continue
        raise RuntimeError("LLM non-streaming 请求失败")

    def supports_function_calling(self) -> bool:
        """
        是否支持 Function Calling
        
        Returns:
            True，阿里云通义千问支持 Function Calling
        """
        return True
    
    def supports_stop_words(self) -> bool:
        """
        是否支持停止词
        
        Returns:
            True，阿里云通义千问支持 stop 参数
        """
        return True
    
    def _validate_messages(self, messages: list[dict[str, Any]]) -> None:
        """校验消息格式（含多模态 content）。"""
        valid_roles = {"system", "user", "assistant", "tool"}
        for i, msg in enumerate(messages):
            if not isinstance(msg, dict):
                raise ValueError(f"消息 {i} 必须是字典: {msg}")
            if "role" not in msg or msg["role"] not in valid_roles:
                raise ValueError(f"消息 {i} 缺少或无效的 role: {msg}")
            if msg["role"] == "tool":
                if "tool_call_id" not in msg or "content" not in msg:
                    raise ValueError(f"tool 消息 {i} 缺少 tool_call_id/content: {msg}")
            elif "content" not in msg and msg.get("tool_calls") is None:
                raise ValueError(f"消息 {i} 缺少 content 且无 tool_calls: {msg}")
            

    def _call_streaming(
        self,
        payload: dict[str, Any],
        session: requests.Session,
        ctx: _StreamContext,
    ) -> str | dict[str, Any]:
        """流式调用 LLM API，支持 tool_calls 累积 + 文本 token 实时推送。

        DashScope SSE 流式 tool_calls 格式：
            data: {"choices":[{"delta":{"content":"思考"},"finish_reason":null}]}
            data: {"choices":[{"delta":{"tool_calls":[{"index":0,"id":"call_xx",
                   "type":"function","function":{"name":"search","arguments":""}}]},...}]}
            data: {"choices":[{"delta":{"tool_calls":[{"index":0,
                   "function":{"arguments":"{\\"query\\""}}]},"finish_reason":null}]}
            data: {"choices":[{"delta":{"tool_calls":[{"index":0,
                   "function":{"arguments":":"天气"}"}}]},"finish_reason":null}]}
            data: {"choices":[{"delta":{},"finish_reason":"tool_calls"}]}

        关键特征：
        - delta.content 和 delta.tool_calls 互斥（同一 chunk 不会同时出现）
        - tool_calls arguments 可能跨多个 chunk
        - finish_reason="tool_calls" 表示工具调用完成，"stop" 表示纯文本完成

        返回:
        - str: 纯文本响应（无 tool_calls，token 已全部流式推送）
        - dict: 含 tool_calls 的完整响应（与 _do_call 返回格式一致）
        """
        t0 = time.perf_counter()
        full_text = ""
        tool_calls_acc: dict[int, dict[str, Any]] = {}
        has_tool_calls = False

        try:
            resp = session.post(
                self.endpoint,
                headers={
                    "Authorization": f"Bearer {self.api_key}",
                    "Content-Type": "application/json",
                    "Accept": "text/event-stream",
                },
                json={**payload, "stream": True},
                timeout=(30, self.timeout),  # (connect_timeout, read_timeout)
                stream=True,
            )
            if resp.status_code != 200:
                logger.warning(
                    "streaming request returned %d, falling back to non-streaming: %s",
                    resp.status_code,
                    resp.text[:200],
                )
                return self._fallback_call(payload)
        except requests.Timeout:
            logger.warning("streaming request timed out, falling back to non-streaming")
            return self._fallback_call(payload)
        except requests.RequestException as e:
            logger.warning("streaming request failed: %s, falling back to non-streaming", e)
            return self._fallback_call(payload)

        try:
            for line in resp.iter_lines(decode_unicode=True):
                if not line:
                    continue
                if not line.startswith("data:"):
                    continue
                data_str = line[5:].strip()
                if data_str == "[DONE]":
                    break
                try:
                    chunk = json.loads(data_str)
                except json.JSONDecodeError:
                    continue
                choices = chunk.get("choices", [])
                if not choices:
                    continue
                delta = choices[0].get("delta", {})
                finish_reason = choices[0].get("finish_reason")

                # ① 处理 tool_calls delta（与 content 互斥）
                tool_calls_delta = delta.get("tool_calls")
                if tool_calls_delta:
                    has_tool_calls = True
                    for tc in tool_calls_delta:
                        idx = tc.get("index", 0)
                        if idx not in tool_calls_acc:
                            tool_calls_acc[idx] = {
                                "id": "",
                                "type": "function",
                                "function": {"name": "", "arguments": ""},
                            }
                        entry = tool_calls_acc[idx]
                        if tc.get("id"):
                            entry["id"] = tc["id"]
                        if tc.get("type"):
                            entry["type"] = tc["type"]
                        fn = tc.get("function", {})
                        if fn.get("name"):
                            entry["function"]["name"] += fn["name"]
                        if fn.get("arguments"):
                            entry["function"]["arguments"] += fn["arguments"]
                    # 检测到 tool_calls 后停止流式推送文本 token
                    continue

                # ② 处理 delta.content — 仅在未出现 tool_calls 时流式推送
                content = delta.get("content", "")
                if content:
                    full_text += content
                    if not has_tool_calls:
                        ctx.on_token(content)

                if finish_reason:
                    break
        except Exception as e:
            logger.warning("streaming parse error: %s, partial_text=%d chars", e, len(full_text))
            if full_text.strip():
                logger.info(
                    "timing: llm.call streaming (partial) %.3fs (model=%s, chars=%d)",
                    time.perf_counter() - t0,
                    payload.get("model"),
                    len(full_text),
                )
                return full_text
            return self._fallback_call(payload)

        # 有 tool_calls → 返回与 _do_call 格式一致的 dict
        if has_tool_calls and tool_calls_acc:
            sorted_tool_calls = [tool_calls_acc[i] for i in sorted(tool_calls_acc.keys())]
            logger.info(
                "timing: llm.call streaming+tool_calls %.3fs (model=%s, text_chars=%d, tool_calls=%d)",
                time.perf_counter() - t0,
                payload.get("model"),
                len(full_text),
                len(sorted_tool_calls),
            )
            return {
                "choices": [{
                    "index": 0,
                    "message": {
                        "role": "assistant",
                        "content": full_text.strip() or None,
                        "tool_calls": sorted_tool_calls,
                    },
                    "finish_reason": "tool_calls",
                }]
            }

        # 纯文本路径
        logger.info(
            "timing: llm.call streaming %.3fs (model=%s, chars=%d)",
            time.perf_counter() - t0,
            payload.get("model"),
            len(full_text),
        )
        if not full_text.strip():
            return self._fallback_call(payload)
        return full_text

    def _fallback_call(self, payload: dict[str, Any]) -> str | dict[str, Any]:
        """非流式 fallback：单次请求返回完整响应。返回 str 或含 tool_calls 的 dict。"""
        t0 = time.perf_counter()
        session = self._get_session()
        for attempt in range(self.retry_count + 1):
            try:
                resp = session.post(
                    self.endpoint,
                    headers={
                        "Authorization": f"Bearer {self.api_key}",
                        "Content-Type": "application/json",
                    },
                    json=payload,
                    timeout=self.timeout,
                )
                if resp.status_code != 200:
                    if attempt < self.retry_count:
                        continue
                    resp.raise_for_status()
                result = resp.json()
                logger.info(
                    "timing: llm.call non-streaming %.3fs (model=%s)",
                    time.perf_counter() - t0,
                    payload.get("model"),
                )
                choices = result.get("choices", [])
                if choices:
                    message = choices[0].get("message", {})
                    # 含 tool_calls 时返回完整 dict，供 _process_response 处理
                    if "tool_calls" in message:
                        return result
                    return message.get("content", "") or ""
                return ""
            except (requests.Timeout, requests.RequestException):
                if attempt >= self.retry_count:
                    raise
                continue
        raise RuntimeError("LLM non-streaming 请求失败")

    def _prepare_stop_words(
        self, stop: str | list[str | int]
    ) -> str | list[str | int] | None:
        """准备 stop 参数。"""
        if not stop:
            return None
        if isinstance(stop, str):
            return stop
        if isinstance(stop, list) and stop:
            return stop
        return None

    def get_context_window_size(self) -> int:
        """根据模型名返回上下文窗口大小（Token 数）。"""
        m = self.model.lower()
        if "long" in m:
            return 200_000
        if "max" in m or "plus" in m or "turbo" in m or "flash" in m:
            return 8192
        return 8192


# 使用示例
if __name__ == "__main__":
    # 创建阿里云 LLM 实例
    llm = AliyunLLM(
        model="qwen-plus",
        # api_key 参数可选，会从环境变量 QWEN_API_KEY 或 DASHSCOPE_API_KEY 读取
        # 或直接传入 "sk-xxx"
        region="cn",  # 或 "intl", "finance"
        temperature=0.7
    )
    
    # 测试基本调用
    response = llm.call("你好，请介绍一下你自己")
    print("响应:", response)
    
    # 测试多轮对话
    messages = [
        {"role": "system", "content": "你是一个有用的助手。"},
        {"role": "user", "content": "1+1等于几？"}
    ]
    response = llm.call(messages)
    print("多轮对话响应:", response)

