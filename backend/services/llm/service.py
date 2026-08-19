"""
LLM 服务模块 - 统一管理大模型客户端

"""
import logging
import os
import threading
import time
from typing import Optional, List, Dict, Any

import httpx
import re

logger = logging.getLogger(__name__)

# 匹配 Gemini 思考标签及其内容：<think>...</think>
_THINK_TAG_RE = re.compile(r'<think>[\s\S]*?</think>\s*', re.IGNORECASE)
# 匹配未闭合的 <think> 标签（流式截断场景）
_THINK_UNCLOSED_RE = re.compile(r'<think>[\s\S]*', re.IGNORECASE)


def _strip_thinking(text: str) -> str:
    """清理模型输出中的思考文本（Gemini <think> 标签）。

    Gemini 等模型可能在正文前输出 <think>...</think> 推理过程，
    导致下游 JSON 解析或 markdown 渲染失败。在 LLM 层统一清理。
    """
    if not text or '<think>' not in text.lower():
        return text
    # 先清理闭合的 <think>...</think>
    cleaned = _THINK_TAG_RE.sub('', text)
    # 再清理未闭合的 <think>（流式截断）
    cleaned = _THINK_UNCLOSED_RE.sub('', cleaned)
    return cleaned.strip()


def _resolve_caller(caller: str) -> str:
    """解析 caller 标识：优先使用显式传入值，否则从中间件上下文获取当前节点名。"""
    if caller:
        return caller
    try:
        from services.blog_generator.middleware import current_node_name
        node = current_node_name.get("")
        if node:
            return node
    except Exception:
        pass
    return "unknown"

# 全局请求限流器：防止并发请求触发 API 速率限制
# 41.07: 委托给 GlobalRateLimiter 单例（多域隔离 + 指标暴露）
_request_lock = threading.Lock()
_last_request_time = 0.0
_MIN_REQUEST_INTERVAL = float(__import__('os').environ.get('LLM_MIN_REQUEST_INTERVAL', '1.0'))  # 秒


def _rate_limit():
    """全局 LLM 限流（向后兼容接口，内部委托 GlobalRateLimiter）"""
    from utils.rate_limiter import get_global_rate_limiter
    get_global_rate_limiter().wait_sync(domain='llm')


class LLMService:
    """
    LLM 服务类 - 统一管理文本模型

    支持:
    - OpenAI 兼容 API (OpenAI, Azure, 阿里云 DashScope 等)
    - Google Gemini
    """

    def __init__(
        self,
        provider_format: str = "openai",
        openai_api_key: str = "",
        openai_api_base: str = "",
        google_api_key: str = "",
        text_model: str = "gpt-4o",
        max_tokens: int = None,
        fast_model: str = "",
        smart_model: str = "",
        strategic_model: str = "",
        fast_max_tokens: int = 3000,
        smart_max_tokens: int = 8192,
        strategic_max_tokens: int = 4000,
    ):
        """
        初始化 LLM 服务

        Args:
            provider_format: AI Provider 格式 ('openai' 或 'gemini')
            openai_api_key: OpenAI 兼容 API Key
            openai_api_base: OpenAI 兼容 API 基础 URL
            google_api_key: Google API Key
            text_model: 文本生成模型名称
            max_tokens: 最大输出 token 数 (默认 None 使用环境变量或 8192)
            fast_model: 快速模型名称（41.06 三级 LLM，留空退化为 text_model）
            smart_model: 智能模型名称
            strategic_model: 策略模型名称
            fast_max_tokens: 快速模型 max_tokens
            smart_max_tokens: 智能模型 max_tokens
            strategic_max_tokens: 策略模型 max_tokens
        """
        self.provider_format = provider_format.lower()
        self._openai_api_key = openai_api_key
        self._openai_api_base = openai_api_base
        self._google_api_key = google_api_key
        self.text_model = text_model

        import os
        self.max_tokens = max_tokens or int(os.environ.get('LLM_MAX_TOKENS', '8192'))

        # 懒加载的模型实例
        self._text_chat_model = None

        # 41.06 三级 LLM 模型配置（空字符串退化为 text_model）
        self._model_config = {
            'fast': {'model': fast_model or self.text_model, 'max_tokens': fast_max_tokens, 'instance': None},
            'smart': {'model': smart_model or self.text_model, 'max_tokens': smart_max_tokens, 'instance': None},
            'strategic': {'model': strategic_model or self.text_model, 'max_tokens': strategic_max_tokens, 'instance': None},
        }

        # Token 追踪器（由 BlogGenerator 注入，默认 None）
        self.token_tracker = None

        # SSE 事件推送（由 BlogService 注入，默认 None）
        self.task_manager = None
        self.task_id = None

        # LLM 调用完整日志（v2 方案 10）
        self.llm_logger = None

    def _create_chat_model(self, model_name: str):
        """创建 LangChain ChatModel 实例（优先使用 ClientFactory）"""
        try:
            # 37.29: 尝试通过 ClientFactory 创建（支持多提供商）
            from .factory import create_llm_client, PROVIDER_CONFIGS
            # 根据模型名动态选择 provider（gemini → google, claude → anthropic, 其他 → provider_format）
            provider = self.provider_format
            api_key = self._openai_api_key or None
            base_url = self._openai_api_base or None
            if 'gemini' in model_name.lower() and 'google' in PROVIDER_CONFIGS:
                provider = 'google'
                api_key = None  # 让 factory 从环境变量取 GOOGLE_API_KEY
                base_url = None  # 让 factory 用预设的 base_url
            elif 'claude' in model_name.lower() and 'anthropic' in PROVIDER_CONFIGS:
                provider = 'anthropic'
                api_key = None
                base_url = None
            if provider in PROVIDER_CONFIGS:
                return create_llm_client(
                    provider=provider,
                    model_name=model_name,
                    api_key=api_key,
                    base_url=base_url,
                    max_tokens=self.max_tokens,
                )
        except (ImportError, ValueError):
            pass
        except Exception as e:
            logger.debug(f"ClientFactory 创建失败，回退原始逻辑: {e}")

        # 回退：原始创建逻辑（gemini 等）
        try:
            if self.provider_format == 'gemini' and self._google_api_key:
                from langchain_google_genai import ChatGoogleGenerativeAI
                return ChatGoogleGenerativeAI(
                    model=model_name,
                    google_api_key=self._google_api_key,
                    temperature=0.7,
                    max_output_tokens=self.max_tokens
                )
            elif self._openai_api_key:
                from langchain_openai import ChatOpenAI
                no_proxy_client = httpx.Client(
                    proxy=None,
                    timeout=httpx.Timeout(timeout=300.0, connect=10.0),
                )
                return ChatOpenAI(
                    model=model_name,
                    api_key=self._openai_api_key,
                    base_url=self._openai_api_base if self._openai_api_base else None,
                    temperature=0.7,
                    max_tokens=self.max_tokens,
                    max_retries=6,
                    http_client=no_proxy_client,
                )
            else:
                logger.warning(f"未配置有效的 API Key，无法创建模型: {model_name}")
                return None
        except Exception as e:
            logger.error(f"创建模型失败 ({model_name}): {e}")
            return None

    def get_text_model(self):
        """获取文本生成模型"""
        if self._text_chat_model is None:
            self._text_chat_model = self._create_chat_model(self.text_model)
        return self._text_chat_model

    def get_model_for_tier(self, tier: str):
        """按级别获取模型实例（懒加载）

        Args:
            tier: 'fast' | 'smart' | 'strategic'

        Returns:
            LangChain ChatModel 实例
        """
        config = self._model_config.get(tier)
        if not config:
            return self.get_text_model()
        if config['instance'] is None:
            config['instance'] = self._create_chat_model(config['model'])
        return config['instance']

    def _get_tier_info(self, tier: str):
        """获取 tier 对应的 (model_instance, model_name, max_tokens)

        未指定 tier 或 tier 无效时返回默认模型信息。
        """
        if tier and tier in self._model_config:
            cfg = self._model_config[tier]
            return self.get_model_for_tier(tier), cfg['model'], cfg['max_tokens']
        return self.get_text_model(), self.text_model, self.max_tokens

    def is_available(self) -> bool:
        """检查 LLM 服务是否可用"""
        if self.provider_format == 'gemini':
            return bool(self._google_api_key)
        if self.provider_format == 'anthropic':
            return bool(os.environ.get('ANTHROPIC_API_KEY', ''))
        return bool(self._openai_api_key)

    @staticmethod
    def _supports_thinking(model_name: str) -> bool:
        """检查模型是否支持 Extended Thinking（仅 Claude 系列）"""
        if not model_name:
            return False
        return "claude" in model_name.lower()

    def _chat_with_thinking(
        self,
        langchain_messages: list,
        budget_tokens: int = 19000,
        caller: str = "",
        model_name_override: str = "",
    ) -> Optional[str]:
        """使用 Anthropic Extended Thinking 模式调用

        通过 anthropic SDK 直接调用（LangChain 尚未完整支持 thinking 参数）。
        如果 anthropic SDK 不可用，降级为普通调用。
        """
        model_name = model_name_override or self.text_model
        try:
            import anthropic
        except ImportError:
            logger.warning(f"[{caller}] anthropic SDK 未安装，降级为普通调用")
            return self._chat_with_thinking_fallback(langchain_messages, caller)

        try:
            # 将 LangChain 消息转为 Anthropic API 格式
            api_messages = []
            system_text = ""
            for msg in langchain_messages:
                role = msg.type  # "human" / "system" / "ai"
                content = msg.content
                if role == "system":
                    system_text = content
                elif role == "ai":
                    api_messages.append({"role": "assistant", "content": content})
                else:
                    api_messages.append({"role": "user", "content": content})

            client = anthropic.Anthropic(
                api_key=self._openai_api_key,
                base_url=self._openai_api_base or None,
            )

            kwargs = {
                "model": model_name,
                "max_tokens": self.max_tokens + budget_tokens,
                "thinking": {
                    "type": "enabled",
                    "budget_tokens": budget_tokens,
                },
                "messages": api_messages,
            }
            if system_text:
                kwargs["system"] = system_text

            _rate_limit()
            response = client.messages.create(**kwargs)

            # 提取最终文本（跳过 thinking blocks）
            text_parts = []
            for block in response.content:
                if getattr(block, "type", None) == "text":
                    text_parts.append(block.text)

            # 记录 thinking token 用量
            if self.token_tracker and response.usage:
                try:
                    from utils.token_tracker import TokenUsage
                    usage = TokenUsage(
                        input_tokens=response.usage.input_tokens,
                        output_tokens=response.usage.output_tokens,
                        model=model_name,
                        provider="anthropic",
                    )
                    # 记录 thinking tokens（如果 API 返回）
                    thinking_tokens = getattr(response.usage, "cache_creation_input_tokens", 0)
                    if hasattr(response.usage, "thinking_tokens"):
                        thinking_tokens = response.usage.thinking_tokens
                    if thinking_tokens:
                        usage.extra = {"thinking_tokens": thinking_tokens}
                    self.token_tracker.record(usage, agent=_resolve_caller(caller))
                except Exception:
                    pass

            return "\n".join(text_parts).strip() if text_parts else None

        except Exception as e:
            logger.warning(f"[{caller}] Thinking 模式调用失败: {e}，降级为普通调用")
            return self._chat_with_thinking_fallback(langchain_messages, caller)

    def _chat_with_thinking_fallback(self, langchain_messages: list, caller: str) -> Optional[str]:
        """Thinking 模式降级：使用普通 resilient_chat"""
        from utils.resilient_llm_caller import resilient_chat
        model = self.get_text_model()
        if not model:
            return None
        content, _ = resilient_chat(model=model, messages=langchain_messages, caller=caller)
        return content

    @staticmethod
    def _convert_messages(messages: List[Dict[str, Any]]) -> list:
        """将 dict 格式消息转换为 LangChain 消息对象"""
        from langchain_core.messages import HumanMessage, SystemMessage, AIMessage
        langchain_messages = []
        for i, msg in enumerate(messages):
            role = msg.get("role", "user")
            content = msg.get("content", "")
            # 防御性校验：content 必须是字符串或 LangChain 支持的 content block 列表，
            # None/dict/其他类型会导致 langchain pydantic 校验失败（role/Input should be a valid string）
            if content is None:
                logger.warning(
                    f"[_convert_messages] 第 {i} 条消息 content 为 None (role={role})，"
                    f"已替换为空字符串。原始消息: {str(msg)}"
                )
                content = ""
            elif not isinstance(content, (str, list)):
                logger.warning(
                    f"[_convert_messages] 第 {i} 条消息 content 类型异常: {type(content).__name__} (role={role})，"
                    f"可能引发 langchain 消息校验失败。原始消息: {str(msg)}"
                )
            if role == "system":
                langchain_messages.append(SystemMessage(content=content))
            elif role == "assistant":
                langchain_messages.append(AIMessage(content=content))
            else:
                langchain_messages.append(HumanMessage(content=content))
        return langchain_messages

    def chat(
        self,
        messages: List[Dict[str, Any]],
        temperature: float = 0.7,
        response_format: Dict[str, Any] = None,
        caller: str = "",
        thinking: bool = False,
        thinking_budget: int = 19000,
        tier: str = "",
    ) -> Optional[str]:
        """
        发送聊天请求（带截断扩容、智能重试、超时保护）

        Args:
            messages: 消息列表，格式 [{"role": "user/system/assistant", "content": "..."}]
            temperature: 温度参数
            response_format: 响应格式，如 {"type": "json_object"}
            caller: 调用方标识（用于日志追踪）
            thinking: 是否启用 Extended Thinking 模式（仅 Claude 模型支持）
            thinking_budget: Thinking 模式的 budget_tokens（默认 19000）
            tier: 模型级别 ('fast'|'smart'|'strategic')，留空使用默认模型

        Returns:
            模型响应文本，失败返回 None
        """
        from utils.resilient_llm_caller import resilient_chat, ContextLengthExceeded
        from utils.context_guard import ContextGuard

        model, model_name, max_tokens = self._get_tier_info(tier)
        if not model:
            logger.error("模型不可用")
            return None

        try:
            # 上下文长度预警（不阻断调用）
            guard = ContextGuard(model_name, max_output_tokens=max_tokens)
            check = guard.check(messages)
            if not check["is_safe"]:
                logger.warning(
                    f"[{caller}] prompt 超限 {check['overflow_tokens']:,} tokens，"
                    f"建议调用方裁剪内容"
                )
            # 如果指定了 JSON 格式，尝试绑定到模型（Anthropic 不支持 response_format）
            if response_format and response_format.get("type") == "json_object":
                if self.provider_format == 'anthropic':
                    logger.debug(f"[{caller}] Anthropic 不支持 response_format，依赖 prompt 约束 JSON 输出")
                else:
                    try:
                        model = model.bind(response_format={"type": "json_object"})
                    except Exception as bind_err:
                        logger.warning(f"模型不支持 response_format 绑定: {bind_err}")

            # 转换消息格式
            langchain_messages = self._convert_messages(messages)

            # SSE: 发送 llm_start 事件
            _send_llm = (
                self.task_manager and self.task_id
                and os.environ.get('SSE_LLM_EVENTS_ENABLED', 'true').lower() != 'false'
            )
            start_time = time.time()
            if _send_llm:
                self.task_manager.send_event(self.task_id, 'llm_start', {
                    'agent': caller,
                    'model': model_name,
                    'thinking': thinking,
                })

            # LLM 调用期间每 5 秒发一次心跳，让前端知道还在工作
            _llm_done = threading.Event()
            def _llm_heartbeat():
                tick = 0
                while not _llm_done.wait(5):
                    tick += 1
                    if self.task_manager and self.task_id:
                        self.task_manager.send_event(self.task_id, 'log', {
                            'logger': caller or 'llm',
                            'message': f'🧠 模型思考中... ({tick * 5}s)',
                        })
            hb_thread = threading.Thread(target=_llm_heartbeat, daemon=True)
            if _send_llm:
                hb_thread.start()

            # Thinking 模式分支
            if thinking and self._supports_thinking(model_name):
                content = self._chat_with_thinking(
                    langchain_messages, thinking_budget, caller=caller,
                    model_name_override=model_name,
                )
                metadata = {"attempts": 1}
            else:
                if thinking:
                    logger.info(f"[{caller}] 模型 {model_name} 不支持 Thinking，降级为普通调用")
                # 使用 resilient_chat 替代原来的简单调用
                content, metadata = resilient_chat(
                    model=model,
                    messages=langchain_messages,
                    caller=caller,
                )

            # 停止 LLM 心跳线程
            _llm_done.set()

            # SSE: 发送 llm_end 事件
            if _send_llm:
                duration_ms = int((time.time() - start_time) * 1000)
                self.task_manager.send_event(self.task_id, 'llm_end', {
                    'agent': caller,
                    'model': model_name,
                    'duration_ms': duration_ms,
                    'truncated': metadata.get('truncated', False),
                    'attempts': metadata.get('attempts', 1),
                    'thinking': thinking,
                })

            if metadata.get("truncated"):
                logger.warning(f"[{caller}] 响应被截断，内容可能不完整")

            # 记录 token 用量
            if self.token_tracker and metadata.get("token_usage"):
                token_usage = metadata["token_usage"]
                token_usage.model = model_name
                token_usage.provider = self.provider_format
                self.token_tracker.record(token_usage, agent=_resolve_caller(caller))

                # 41.08 成本追踪
                if hasattr(self, '_cost_tracker') and self._cost_tracker:
                    self._cost_tracker.record_call(
                        input_tokens=token_usage.input_tokens,
                        output_tokens=token_usage.output_tokens,
                        cache_read_tokens=token_usage.cache_read_tokens,
                        cache_write_tokens=token_usage.cache_write_tokens,
                        model=model_name,
                        agent=_resolve_caller(caller),
                    )

            # v2 方案 10: LLM 调用完整日志
            if self.llm_logger:
                prompt_text = "\n".join(
                    m.get("content", "") if isinstance(m, dict) else str(m)
                    for m in messages
                )
                tu = metadata.get("token_usage")
                self.llm_logger.log(
                    agent=_resolve_caller(caller),
                    action="chat",
                    prompt=prompt_text,
                    response=content or "",
                    input_tokens=tu.input_tokens if tu else 0,
                    output_tokens=tu.output_tokens if tu else 0,
                    duration_ms=int((time.time() - start_time) * 1000),
                    model=model_name,
                )

            return _strip_thinking(content)

        except ContextLengthExceeded as e:
            logger.error(f"上下文超限: {e}")
            return None
        except Exception as e:
            logger.error(f"LLM 调用失败: {e}")
            return None

    def chat_stream(
        self,
        messages: List[Dict[str, Any]],
        temperature: float = 0.7,
        on_chunk: callable = None,
        response_format: Dict[str, Any] = None,
        caller: str = "",
        tier: str = "",
    ) -> Optional[str]:
        """
        发送流式聊天请求（带超时保护和智能重试）

        Args:
            messages: 消息列表
            temperature: 温度参数
            on_chunk: 每收到一个 chunk 时的回调函数 (delta, accumulated)
            response_format: 响应格式，如 {"type": "json_object"}
            caller: 调用方标识（用于日志追踪）
            tier: 模型级别 ('fast'|'smart'|'strategic')，留空使用默认模型

        Returns:
            完整的模型响应文本，失败返回 None
        """
        from utils.resilient_llm_caller import (
            timeout_guard, is_truncated, is_context_length_error,
            LLMCallTimeout, ContextLengthExceeded,
            DEFAULT_LLM_TIMEOUT, DEFAULT_MAX_RETRIES, DEFAULT_BASE_WAIT, DEFAULT_MAX_WAIT,
        )

        model, model_name, _ = self._get_tier_info(tier)
        if not model:
            logger.error("模型不可用")
            return None

        # 是否已检测到 reasoning-only 模型（如 sensenova-* flash-lite），
        # 其流式响应只有 delta.reasoning 无 delta.role，langchain 解析会报 ChatMessage.role 校验错误。
        _reasoning_model_detected = False

        try:
            if response_format and response_format.get("type") == "json_object":
                if self.provider_format == 'anthropic':
                    logger.debug("Anthropic 不支持 response_format，依赖 prompt 约束 JSON 输出")
                else:
                    try:
                        model = model.bind(response_format={"type": "json_object"})
                    except Exception as bind_err:
                        logger.warning(f"模型不支持 response_format 绑定: {bind_err}")

            langchain_messages = self._convert_messages(messages)
            label = f"[{caller}] " if caller else ""

            for attempt in range(DEFAULT_MAX_RETRIES):
                attempts = attempt + 1
                try:
                    _rate_limit()
                    full_content = ""
                    last_chunk = None
                    with timeout_guard(DEFAULT_LLM_TIMEOUT):
                        for chunk in model.stream(langchain_messages):
                            delta = chunk.content if hasattr(chunk, 'content') else str(chunk)
                            full_content += delta
                            last_chunk = chunk
                            if on_chunk:
                                on_chunk(delta, full_content)

                    # 流式完成后提取 token 用量
                    if self.token_tracker and last_chunk:
                        try:
                            from utils.token_tracker import extract_token_usage_from_langchain
                            token_usage = extract_token_usage_from_langchain(
                                last_chunk, model=model_name, provider=self.provider_format
                            )
                            if token_usage.input_tokens or token_usage.output_tokens:
                                self.token_tracker.record(token_usage, agent=_resolve_caller(caller))
                        except Exception:
                            pass

                    # v2 方案 10: LLM 调用完整日志
                    if self.llm_logger:
                        prompt_text = "\n".join(
                            m.get("content", "") if isinstance(m, dict) else str(m)
                            for m in messages
                        )
                        self.llm_logger.log(
                            agent=_resolve_caller(caller),
                            action="chat_stream",
                            prompt=prompt_text,
                            response=full_content,
                            model=model_name,
                        )

                    return _strip_thinking(full_content.strip())

                except LLMCallTimeout:
                    if attempt < DEFAULT_MAX_RETRIES - 1:
                        wait = min(DEFAULT_BASE_WAIT * (2 ** attempt), DEFAULT_MAX_WAIT)
                        logger.warning(f"{label}流式调用超时，等待 {wait:.0f}s 后重试 (attempt {attempts}/{DEFAULT_MAX_RETRIES})")
                        time.sleep(wait)
                        continue
                    raise

                except Exception as stream_err:
                    if is_context_length_error(stream_err):
                        raise ContextLengthExceeded(str(stream_err)) from stream_err

                    # == reasoning-only 模型兼容 ==
                    # 检测特征：流式 chunk 只有 delta.reasoning 无 delta.role →
                    # ChatMessage.role Input should be a valid string (input_value=None)
                    if not _reasoning_model_detected and (
                        'validation error for ChatMessage' in str(stream_err)
                        and 'input_value=None' in str(stream_err)
                    ):
                        _reasoning_model_detected = True
                        logger.warning(
                            f"{label}检测到 reasoning-only 模型响应 (流式无 delta.role)，"
                            f"自动解除 response_format 绑定，改用 prompt 约束 JSON 输出"
                        )
                        # 重新获取原始模型（非 bind 版），用 prompt 约束代替 response_format
                        model, _, _ = self._get_tier_info(tier)
                        if attempt < DEFAULT_MAX_RETRIES - 1:
                            wait = min(DEFAULT_BASE_WAIT * (2 ** attempt), DEFAULT_MAX_WAIT)
                            logger.warning(f"{label}解除 bind 后立即重试 (attempt {attempts}/{DEFAULT_MAX_RETRIES})")
                            time.sleep(wait)
                            continue

                    # pydantic 消息校验失败（如 role/content 类型错误）：输出详细上下文便于定位
                    if 'validation error' in str(stream_err).lower() or 'input should be' in str(stream_err).lower():
                        logger.error(
                            f"{label}消息格式校验失败: {stream_err}\n"
                            f"── 调用方: {caller or 'unknown'}, 模型: {model_name}\n"
                            f"── 消息数量: {len(messages)}\n"
                            f"── 消息内容:\n" + "\n".join(
                                f"   [{i}] role={m.get('role', 'user')!r}, "
                                f"content类型={type(m.get('content')).__name__}, "
                                f"content={str(m.get('content'))!r}"
                                for i, m in enumerate(messages)
                            )
                        )

                    if '429' in str(stream_err) and attempt < DEFAULT_MAX_RETRIES - 1:
                        wait = min(DEFAULT_BASE_WAIT * (2 ** attempt), DEFAULT_MAX_WAIT)
                        logger.warning(f"{label}流式 429 速率限制，等待 {wait:.0f}s 后重试 (attempt {attempts}/{DEFAULT_MAX_RETRIES})")
                        time.sleep(wait)
                        continue

                    if attempt < DEFAULT_MAX_RETRIES - 1:
                        wait = min(DEFAULT_BASE_WAIT * (2 ** attempt), DEFAULT_MAX_WAIT)
                        logger.warning(f"{label}流式调用失败: {stream_err}，等待 {wait:.0f}s 后重试 (attempt {attempts}/{DEFAULT_MAX_RETRIES})")
                        time.sleep(wait)
                        continue
                    raise

        except ContextLengthExceeded as e:
            logger.error(f"流式调用上下文超限: {e}")
            return None
        except Exception as e:
            # == 方案 C: 流式全部失败后降级为非流式 ==
            # 适用于 reasoning-only 模型（商汤 sensenova-* flash-lite 等），
            # 流式 chunk 不兼容 langchain 解析，但非流式接口正常返回。
            if _reasoning_model_detected:
                logger.warning(
                    f"{label}流式调用全部失败，降级为非流式 chat() (模型: {model_name})"
                )
                try:
                    return self.chat(
                        messages=messages,
                        temperature=temperature,
                        response_format=response_format,
                        caller=caller,
                        tier=tier,
                    )
                except Exception as fallback_err:
                    logger.error(f"{label}非流式降级也失败: {fallback_err}")
            logger.error(f"LLM 流式调用失败: {e}")
            return None

    def chat_with_image(
        self,
        prompt: str,
        image_base64: str,
        mime_type: str = "image/jpeg",
        tier: str = "",
    ) -> Optional[str]:
        """
        发送包含图片的聊天请求（多模态）

        Args:
            prompt: 文本提示词
            image_base64: Base64 编码的图片数据
            mime_type: 图片 MIME 类型 (image/jpeg, image/png 等)
            tier: 模型级别 ('fast'|'smart'|'strategic')，留空使用默认模型

        Returns:
            模型响应文本，失败返回 None
        """
        try:
            from langchain_core.messages import HumanMessage

            model, _, _ = self._get_tier_info(tier)
            if not model:
                logger.error("模型不可用")
                return None

            # 构建包含图片的消息
            message = HumanMessage(
                content=[
                    {"type": "text", "text": prompt},
                    {
                        "type": "image_url",
                        "image_url": {
                            "url": f"data:{mime_type};base64,{image_base64}"
                        }
                    }
                ]
            )

            _rate_limit()
            response = model.invoke([message])
            return response.content.strip() if response else None

        except Exception as e:
            logger.warning(f"多模态调用失败: {e}")
            return None


# 全局 LLM 服务实例 (懒加载)
_llm_service: Optional[LLMService] = None


def get_llm_service() -> Optional[LLMService]:
    """获取全局 LLM 服务实例"""
    return _llm_service


def _infer_provider_format(config: dict) -> str:
    """根据实际配置自动推断 provider_format，无需手动设置 AI_PROVIDER_FORMAT"""
    explicit = config.get('AI_PROVIDER_FORMAT', '').strip()

    # 如果有 Anthropic API Key 且未被注释，且 base_url 不是 OpenAI 兼容的
    anthropic_key = os.environ.get('ANTHROPIC_API_KEY', '')
    openai_key = config.get('OPENAI_API_KEY', '')
    google_key = config.get('GOOGLE_API_KEY', '')
    text_model = config.get('TEXT_MODEL', '')

    # 模型名自动推断（最可靠）
    if text_model:
        if 'claude' in text_model.lower():
            return 'anthropic'
        # gemini 通过 OpenAI 兼容代理调用，走 openai format
        if 'gemini' in text_model.lower():
            return 'openai'

    # 有 Anthropic key 且没有 OpenAI key → anthropic
    if anthropic_key and not openai_key:
        return 'anthropic'

    # 有 Google key 且没有 OpenAI key → gemini
    if google_key and not openai_key:
        return 'gemini'

    # 显式配置作为兜底
    if explicit:
        return explicit.lower()

    return 'openai'


def init_llm_service(config: dict) -> LLMService:
    """
    从配置初始化 LLM 服务

    Args:
        config: Flask app.config 字典

    Returns:
        LLMService 实例
    """
    global _llm_service
    _llm_service = LLMService(
        provider_format=_infer_provider_format(config),
        openai_api_key=config.get('OPENAI_API_KEY', ''),
        openai_api_base=config.get('OPENAI_API_BASE', ''),
        google_api_key=config.get('GOOGLE_API_KEY', ''),
        text_model=config.get('TEXT_MODEL', 'gpt-4o'),
        # 41.06 三级 LLM 模型配置
        fast_model=config.get('LLM_FAST', ''),
        smart_model=config.get('LLM_SMART', ''),
        strategic_model=config.get('LLM_STRATEGIC', ''),
        fast_max_tokens=config.get('LLM_FAST_MAX_TOKENS', 3000),
        smart_max_tokens=config.get('LLM_SMART_MAX_TOKENS', 8192),
        strategic_max_tokens=config.get('LLM_STRATEGIC_MAX_TOKENS', 4000),
    )
    logger.info(f"LLM 服务已初始化: provider={_llm_service.provider_format}, text_model={_llm_service.text_model}")
    for tier_name in ('fast', 'smart', 'strategic'):
        tier_model = _llm_service._model_config[tier_name]['model']
        if tier_model != _llm_service.text_model:
            logger.info(f"  LLM {tier_name}: {tier_model}")
    return _llm_service
