"""
LLM Client — 统一的 LLM API 调用模块
从 main.py 提取，供所有路由和内部模块使用

包含:
- LLM API 配置（DeepSeek/GLM）
- HTTP 客户端管理
- Pydantic Message 模型
- 所有 LLM 调用函数（Pro/Flash/Visual/Behavior）
- 聊天记忆后台写入
"""
import os
import json
import random
import asyncio
import logging
import time
from datetime import datetime
from typing import List, Optional, Dict, Any
import httpx
from fastapi import HTTPException
from pydantic import BaseModel
from time_utils import now_iso
from token_tracker import log_token_usage
from shared_state import get_context_scheduler, get_latest_session_id, get_active_session_id, get_latest_persona_prompt
logger = logging.getLogger(__name__)
DEEPSEEK_API_KEY = os.getenv('DEEPSEEK_API_KEY', '')
DEEPSEEK_API_URL = os.getenv('DEEPSEEK_API_URL', 'https://api.deepseek.com/v1/chat/completions')
DEEPSEEK_MODEL = os.getenv('DEEPSEEK_MODEL', 'deepseek-v4-pro')
DEEPSEEK_THINKING_ENABLED = os.getenv('DEEPSEEK_THINKING_ENABLED', 'true').lower() == 'true'
DEEPSEEK_REASONING_EFFORT = os.getenv('DEEPSEEK_REASONING_EFFORT', 'medium')
DEEPSEEK_FLASH_MODEL = os.getenv('DEEPSEEK_FLASH_MODEL', 'deepseek-v4-flash-vision-exp')
DEEPSEEK_FLASH_API_KEY = os.getenv('DEEPSEEK_FLASH_API_KEY', '')
DEEPSEEK_FLASH_API_URL = os.getenv('DEEPSEEK_FLASH_API_URL', 'https://api.deepseek.com/v1/chat/completions')
GLM_API_KEY = os.getenv('GLM_API_KEY', '')
GLM_API_URL = os.getenv('GLM_API_URL', '')
GLM_MODEL = os.getenv('GLM_MODEL', 'glm-4')
SF_API_KEY = os.getenv('SILICONFLOW_API_KEY', '')
SF_API_URL = os.getenv('SILICONFLOW_API_URL', 'https://api.siliconflow.cn/v1/chat/completions')
SF_VL_MODEL = os.getenv('SILICONFLOW_VL_MODEL', 'deepseek-ai/DeepSeek-OCR')
SILICONFLOW_STRUCTURED_API_KEY = os.getenv('SILICONFLOW_STRUCTURED_API_KEY', '')
SILICONFLOW_STRUCTURED_API_URL = os.getenv('SILICONFLOW_STRUCTURED_API_URL', 'https://api.siliconflow.cn/v1/chat/completions')
SILICONFLOW_STRUCTURED_MODEL_V3_2 = os.getenv('SILICONFLOW_STRUCTURED_MODEL_V3_2', 'deepseek-ai/DeepSeek-V3.2')
SILICONFLOW_STRUCTURED_MODEL_V4_FLASH = os.getenv('SILICONFLOW_STRUCTURED_MODEL_V4_FLASH', 'deepseek-ai/DeepSeek-V4-Flash')
SILICONFLOW_STRUCTURED_MODEL_QWEN3_6 = os.getenv('SILICONFLOW_STRUCTURED_MODEL_QWEN3_6', 'Qwen/Qwen3.6-35B-A3B')

def resolve_siliconflow_structured_model(profile: str='', legacy_model: str='') -> str:
    """Resolve the text/JSON SiliconFlow lane without deleting old config.

    ``SILICONFLOW_STRUCTURED_MODEL_PROFILE`` is the one-line switch used in
    production.  The legacy explicit model remains the fallback so older
    deployments and one-off overrides keep working unchanged.
    """
    normalized = str(profile or '').strip().lower().replace('-', '_')
    if normalized in {'v3.2', 'v3_2', 'deepseek_v3.2', 'deepseek_v3_2'}:
        return SILICONFLOW_STRUCTURED_MODEL_V3_2
    if normalized in {'v4', 'v4_flash', 'deepseek_v4_flash'}:
        return SILICONFLOW_STRUCTURED_MODEL_V4_FLASH
    if normalized in {'qwen3.6', 'qwen3_6', 'qwen3.6_35b_a3b', 'qwen3_6_35b_a3b'}:
        return SILICONFLOW_STRUCTURED_MODEL_QWEN3_6
    return str(legacy_model or SILICONFLOW_STRUCTURED_MODEL_V4_FLASH).strip()
SILICONFLOW_STRUCTURED_MODEL_PROFILE = os.getenv('SILICONFLOW_STRUCTURED_MODEL_PROFILE', '')
SILICONFLOW_STRUCTURED_MODEL = resolve_siliconflow_structured_model(SILICONFLOW_STRUCTURED_MODEL_PROFILE, os.getenv('SILICONFLOW_STRUCTURED_MODEL', ''))
SUMMARY_MODEL = os.getenv('SUMMARY_MODEL', 'deepseek')
http_client: Optional[httpx.AsyncClient] = None
llm_semaphore = asyncio.Semaphore(int(os.getenv('MAX_CONCURRENT_LLM_REQUESTS', '10')))
LLM_TIMEOUT = httpx.Timeout(float(os.getenv('LLM_READ_TIMEOUT_SECONDS', '90')), connect=float(os.getenv('LLM_CONNECT_TIMEOUT_SECONDS', '10')))
LLM_LONG_TIMEOUT = httpx.Timeout(float(os.getenv('LLM_LONG_READ_TIMEOUT_SECONDS', '600')), connect=float(os.getenv('LLM_CONNECT_TIMEOUT_SECONDS', '10')))
LLM_LIMITS = httpx.Limits(max_connections=int(os.getenv('LLM_MAX_CONNECTIONS', '50')), max_keepalive_connections=int(os.getenv('LLM_MAX_KEEPALIVE_CONNECTIONS', '8')))

def set_http_client(client: httpx.AsyncClient):
    """设置全局 HTTP 客户端（由 main.py startup 调用）"""
    global http_client
    http_client = client

def close_http_client():
    """清理全局 HTTP 客户端（由 main.py shutdown 调用）"""
    global http_client
    http_client = None

class Message(BaseModel):
    """LLM API 消息格式"""
    role: str
    content: str

def write_context_log(log_entry: dict):
    """同步写入 LLM 上下文日志（由 asyncio.to_thread 调用，不阻塞事件循环）"""
    with open('llm_context_log.jsonl', 'a', encoding='utf-8') as f:
        f.write(json.dumps(log_entry, ensure_ascii=False) + '\n')

async def _call_llm_raw(api_key: str, api_url: str, model_name: str, payload: dict, headers: dict, timeout, usage_tag: str, max_attempts: int=3, billing_provider: str='unknown') -> Dict[str, Any]:
    """共享重试+错误处理核心 — 所有 LLM 调用函数共用"""
    from context_builder.channel_projection import prepare
    payload = dict(payload)
    from api_sources.model_context import with_current_model
    source_messages = with_current_model(payload.get('messages', []), model_name)
    request_projection = None
    if 'messages' in payload:
        payload['messages'], request_projection = prepare(source_messages)
    client = http_client or httpx.AsyncClient(timeout=timeout, limits=LLM_LIMITS, proxy=None, trust_env=False)
    _fresh = False
    started_at = time.perf_counter()
    from api_sources import audit as api_audit
    import uuid as _audit_uuid
    audit_task_id = _audit_uuid.uuid4().hex
    audit_source = await asyncio.to_thread(api_audit.identify_source, api_url, model_name, api_key)
    audit_category = 'main' if usage_tag in {'chat_final_reply', 'module_profile_reply'} else 'vision' if usage_tag == 'visual_reply' else 'expression'
    attempts = max(1, int(max_attempts))
    async with llm_semaphore:
        for attempt in range(attempts):
            _retry_client = client
            if _fresh:
                _retry_client = httpx.AsyncClient(timeout=timeout, limits=LLM_LIMITS, proxy=None, trust_env=False)
            inspection_handle = None
            audit_handle = None
            audit_status, audit_error, audit_http, audit_usage, audit_trace = ('error', 'provider_error', 0, {}, '')
            try:
                from context_inspection import observe_provider, finish_provider
                inspection_handle = observe_provider(payload.get('messages', []), model=model_name, provider=usage_tag, use_bound=False, source_messages=source_messages, request_projection=request_projection)
                audit_handle = await asyncio.to_thread(api_audit.begin, audit_task_id, audit_category, usage_tag, audit_source, attempt + 1)
                response = await _retry_client.post(api_url, json=payload, headers=headers, timeout=timeout)
                audit_http = response.status_code
                audit_headers = getattr(response, 'headers', {})
                audit_trace = audit_headers.get('x-request-id') or audit_headers.get('x-siliconcloud-trace-id') or ''
                response.raise_for_status()
                finish_provider(inspection_handle, 'response_received')
                result = response.json()
                audit_usage = result.get('usage') or {}
                choices = result.get('choices') if isinstance(result, dict) else None
                if not choices:
                    audit_status, audit_error = ('empty_choice', 'response_has_no_choices')
                    raise HTTPException(status_code=502, detail=f'{model_name} returned unexpected response')
                message = choices[0].get('message', {})
                content = message.get('content')
                if message.get('refusal') or choices[0].get('finish_reason') == 'content_filter':
                    audit_status, audit_error = ('refusal', 'model_refusal')
                elif not content:
                    audit_status, audit_error = ('empty_content', 'model_returned_no_content')
                else:
                    audit_status, audit_error = ('ok', '')
                if not content:
                    raise HTTPException(status_code=502, detail=f'{model_name} returned empty message')
                reasoning = message.get('reasoning_content') or message.get('reasoning')
                asyncio.create_task(log_token_usage(usage_tag, model_name, result.get('usage'), provider=billing_provider))
                prompt_call_id = None
                try:
                    from prompt_ledger import record_provider_usage_for_messages
                    prompt_call_id = record_provider_usage_for_messages(payload.get('messages', []), result.get('usage'), model=model_name, provider=usage_tag, billing_provider=billing_provider, source_messages=source_messages, request_projection=request_projection, latency_ms=(time.perf_counter() - started_at) * 1000.0)
                except Exception:
                    pass
                return {'content': content, 'reasoning': reasoning, 'usage': result.get('usage'), 'call_id': prompt_call_id, 'finish_reason': choices[0].get('finish_reason'), 'audit_id': audit_handle.get('id') if audit_handle else None}
            except asyncio.CancelledError:
                audit_status, audit_error = ('cancelled', 'request_cancelled')
                raise
            except httpx.TimeoutException as e:
                audit_status, audit_error = ('timeout', 'request_timeout')
                logger.warning(f'LLM timeout (attempt {attempt + 1}, {model_name}): {repr(e)}')
                if attempt == attempts - 1:
                    raise HTTPException(status_code=504, detail=f'{model_name} API timed out')
                await asyncio.sleep(2 ** attempt * 0.5 + random.uniform(0, 0.5))
            except httpx.HTTPStatusError as e:
                audit_status, audit_error = ('http_error', 'rate_limited' if e.response.status_code == 429 else 'upstream_http_error')
                response_text = e.response.text[:500] if e.response is not None else ''
                logger.warning(f'LLM HTTP {e.response.status_code} (attempt {attempt + 1}): {response_text}')
                if e.response is not None and e.response.status_code >= 500 and (attempt < attempts - 1):
                    await asyncio.sleep(2 ** attempt * 0.5 + random.uniform(0, 0.5))
                    continue
                raise HTTPException(status_code=502, detail=f'{model_name} API returned HTTP {e.response.status_code}')
            except httpx.ConnectError as e:
                audit_status, audit_error = ('connection_error', 'connection_failed')
                logger.warning(f'LLM connect error (attempt {attempt + 1}): {repr(e)}')
                if attempt == attempts - 1:
                    raise HTTPException(status_code=502, detail=f'Failed to connect to {model_name} API')
                _fresh = True
                await asyncio.sleep(2 ** attempt * 0.5 + random.uniform(0, 1.0))
            except httpx.RequestError as e:
                audit_status, audit_error = ('connection_error', 'request_failed')
                logger.warning(f'LLM request error (attempt {attempt + 1}): {repr(e)}')
                if attempt == attempts - 1:
                    raise HTTPException(status_code=502, detail=f'Failed to connect to {model_name} API')
                await asyncio.sleep(2 ** attempt * 0.5 + random.uniform(0, 0.5))
            except HTTPException:
                raise
            except Exception as e:
                logger.error(f'LLM unexpected error ({model_name}): {type(e).__name__}: {repr(e)}')
                raise HTTPException(status_code=500, detail=f'Unexpected error calling {model_name} API')
            finally:
                if audit_handle:
                    await asyncio.to_thread(api_audit.finish, audit_handle, audit_status, error_code=audit_error, http_status=audit_http, trace_id=audit_trace, usage=audit_usage)
                if inspection_handle:
                    finish_provider(inspection_handle, 'finished_without_response')
                if _fresh and _retry_client is not client:
                    await _retry_client.aclose()

async def call_llm_api(messages: List[Message], model: str) -> Dict[str, Any]:
    """调用LLM API（DeepSeek或GLM），返回包含内容和推理链的字典"""
    logger.debug(f'call_llm_api model={model}')
    if model == 'deepseek':
        api_key = DEEPSEEK_API_KEY
        api_url = DEEPSEEK_API_URL
        model_name = DEEPSEEK_MODEL
        logger.debug(f'DEEPSEEK_API_KEY length: {(len(api_key) if api_key else 0)}')
    elif model == 'glm':
        api_key = GLM_API_KEY
        api_url = GLM_API_URL
        model_name = GLM_MODEL
        logger.debug(f'GLM_API_KEY length: {(len(api_key) if api_key else 0)}')
    else:
        raise ValueError(f'Unsupported model: {model}')
    logger.debug(f'api_key present: {bool(api_key)}')
    if not api_key:
        logger.error(f'{model} API key not configured')
        raise HTTPException(status_code=400, detail=f'{model.upper()} API key not configured. Please configure the API key in .env file')
    headers = {'Authorization': f'Bearer {api_key}', 'Content-Type': 'application/json'}
    logger.debug(f"call_llm_api received {len(messages)} messages, first type: {(type(messages[0]) if messages else 'empty')}")
    from context_builder.channel_projection import copy_messages
    messages_list = copy_messages(messages)
    payload = {'model': model_name, 'messages': messages_list, 'stream': False}
    if model == 'deepseek' and DEEPSEEK_THINKING_ENABLED:
        payload['reasoning_effort'] = DEEPSEEK_REASONING_EFFORT
        payload['thinking'] = {'type': 'enabled'}
        logger.debug(f'DeepSeek thinking enabled: reasoning_effort={DEEPSEEK_REASONING_EFFORT}')
    try:
        log_entry = {'timestamp': now_iso(), 'model': model_name, 'message_count': len(messages_list), 'messages': messages_list, 'thinking_enabled': model == 'deepseek' and DEEPSEEK_THINKING_ENABLED}
        await asyncio.to_thread(write_context_log, log_entry)
    except Exception as e:
        logger.warning(f'Failed to write LLM context log: {e}')
    return await _call_llm_raw(api_key, api_url, model_name, payload, headers, LLM_TIMEOUT, 'chat_final_reply', billing_provider='deepseek' if model == 'deepseek' else 'glm')

async def call_llm_api_profile(messages: List[Message], profile_id: str, *, temperature: Optional[float]=None, read_timeout_seconds: Optional[float]=None, max_attempts: int=3) -> Dict[str, Any]:
    """Call one endpoint-owning main-model profile without changing live chat.

    Feature surfaces such as a module may offer a stable model choice, but
    must not reuse ``GLM_MODEL``: that variable belongs to the GLM-4V visual
    fallback.  Resolving the complete profile here keeps model, endpoint and
    credential from the same provider boundary.
    """
    from main_model_profiles import get_main_model_profile
    profile = get_main_model_profile(profile_id)
    if not profile.available:
        missing = ', '.join(profile.missing_env) or 'provider configuration'
        raise HTTPException(status_code=400, detail=f'{profile.label} 尚未配置完整（缺少 {missing}）')
    from context_builder.channel_projection import copy_messages
    messages_list = copy_messages(messages)
    payload: Dict[str, Any] = {'model': profile.model, 'messages': messages_list, 'stream': False}
    if temperature is not None:
        payload['temperature'] = temperature
    if profile.provider == 'deepseek' and DEEPSEEK_THINKING_ENABLED:
        payload['reasoning_effort'] = DEEPSEEK_REASONING_EFFORT
        payload['thinking'] = {'type': 'enabled'}
    api_url = profile.base_url.rstrip('/') + '/chat/completions'
    headers = {'Authorization': f'Bearer {profile.api_key}', 'Content-Type': 'application/json'}
    request_timeout = LLM_TIMEOUT
    if read_timeout_seconds is not None:
        request_timeout = httpx.Timeout(max(1.0, float(read_timeout_seconds)), connect=float(os.getenv('LLM_CONNECT_TIMEOUT_SECONDS', '10')))
    return await _call_llm_raw(profile.api_key, api_url, profile.model, payload, headers, request_timeout, 'module_profile_reply', max_attempts=max_attempts, billing_provider=profile.provider)

async def call_llm_api_flash(messages: List[Message], enable_thinking: bool=False, temperature: Optional[float]=None, request_timeout: Optional[httpx.Timeout]=None, max_attempts: int=3, usage_tag: str='flash_internal', json_mode: bool=False, max_tokens: Optional[int]=None) -> Dict[str, Any]:
    """调用官方 DeepSeek Flash，用于主动表达、视觉与内部操作。

    Args:
        messages: 消息列表
        enable_thinking: 是否启用 thinking 模式（行为调度器需要，摘要/日记不需要）
        temperature: 采样温度；None 时用 API 默认（1.0）。主动推送等需要克制/聚焦的
            生成路径应显式传值（如 0.7），不要在提示词里靠运气约束模型。
        usage_tag: 无正文的调用场景标签，用于区分主动推送和后台用量。

    Returns:
        {"content": str, "reasoning": Optional[str]}
    """
    from llm_usage_scope import resolve_usage_tag
    usage_tag = resolve_usage_tag(usage_tag)
    api_key = DEEPSEEK_FLASH_API_KEY or DEEPSEEK_API_KEY
    api_url = DEEPSEEK_FLASH_API_URL or DEEPSEEK_API_URL
    model_name = DEEPSEEK_FLASH_MODEL
    headers = {'Authorization': f'Bearer {api_key}', 'Content-Type': 'application/json'}
    from context_builder.channel_projection import copy_messages, prepare
    messages_list = copy_messages(messages)
    from api_sources.managed import call_managed, flash_route
    from api_sources.config import ConfigError
    try:
        managed = await call_managed(flash_route(usage_tag), messages_list, enable_thinking=enable_thinking, temperature=temperature, max_tokens=max_tokens, json_mode=json_mode, request_timeout=request_timeout, max_attempts=max_attempts, inspect_provider=True)
    except ConfigError as exc:
        exc.request_dispatched = False
        raise
    if managed is not None:
        if managed.status != 'ok':
            from llm_usage_scope import usage_metadata
            if json_mode and usage_metadata().get('cognition_call_id'):
                from cognition.provider_contract import managed_output_error
                output_error = managed_output_error(managed)
                if output_error is not None:
                    raise output_error
            error = HTTPException(status_code=403 if managed.status == 'refusal' else 502, detail='模型明确拒答' if managed.status == 'refusal' else '模型线路未返回有效结果')
            error.request_dispatched = getattr(managed, 'request_dispatched', None)
            raise error
        return {'content': managed.raw_content, 'reasoning': managed.reasoning, 'refusal': managed.status == 'refusal', 'model_source': getattr(managed, 'model_source', None), 'routing_status': managed.status, 'error_code': managed.error}
    if not api_key:
        error = HTTPException(status_code=400, detail='DEEPSEEK_FLASH API key not configured')
        error.request_dispatched = False
        raise error
    from api_sources.model_context import with_current_model
    source_messages = with_current_model(messages_list, model_name)
    messages_list, request_projection = prepare(source_messages)
    payload = {'model': model_name, 'messages': messages_list, 'stream': False, 'thinking': {'type': 'enabled' if enable_thinking else 'disabled'}}
    if json_mode:
        payload['response_format'] = {'type': 'json_object'}
    if max_tokens is not None:
        payload['max_tokens'] = max_tokens
    if enable_thinking:
        payload['reasoning_effort'] = DEEPSEEK_REASONING_EFFORT
        payload['thinking'] = {'type': 'enabled'}
    if temperature is not None:
        payload['temperature'] = temperature
    timeout = request_timeout or LLM_TIMEOUT
    attempts = max(1, int(max_attempts))
    from api_sources.legacy_transport import tracked_post
    from uuid import uuid4
    audit_task_id = uuid4().hex
    client = http_client or httpx.AsyncClient(timeout=timeout, limits=LLM_LIMITS, proxy=None, trust_env=False)
    _fresh = False
    started_at = time.perf_counter()
    async with llm_semaphore:
        for attempt in range(attempts):
            _retry_client = client
            if _fresh:
                _retry_client = httpx.AsyncClient(timeout=timeout, limits=LLM_LIMITS, proxy=None, trust_env=False)
            inspection_handle = None
            try:
                from context_inspection import observe_provider, finish_provider
                inspection_handle = observe_provider(payload.get('messages', []), model=model_name, provider=usage_tag, use_bound=False, source_messages=source_messages, request_projection=request_projection)
                response = await tracked_post(_retry_client, api_url, json=payload, headers=headers, timeout=timeout, task_id=audit_task_id, category='expression', node=usage_tag, ordinal=attempt + 1)
                response.raise_for_status()
                finish_provider(inspection_handle, 'response_received')
                result = response.json()
                choices = result.get('choices') if isinstance(result, dict) else None
                if not choices:
                    raise HTTPException(status_code=502, detail='Flash API returned unexpected response')
                message = choices[0].get('message', {})
                if message.get('refusal') or choices[0].get('finish_reason') in {'content_filter', 'refusal'}:
                    raise HTTPException(status_code=403, detail='模型明确拒答')
                content = message.get('content')
                if not content:
                    raise HTTPException(status_code=502, detail='Flash API returned empty message')
                asyncio.create_task(log_token_usage(usage_tag, model_name, result.get('usage')))
                prompt_call_id = None
                try:
                    from prompt_ledger import record_provider_usage_for_messages
                    prompt_call_id = record_provider_usage_for_messages(messages_list, result.get('usage'), model=model_name, provider=usage_tag, billing_provider='deepseek', source_messages=source_messages, request_projection=request_projection, latency_ms=(time.perf_counter() - started_at) * 1000.0)
                except Exception:
                    pass
                return {'content': content, 'reasoning': message.get('reasoning_content') or message.get('reasoning'), 'usage': result.get('usage'), 'call_id': prompt_call_id, 'finish_reason': choices[0].get('finish_reason')}
            except httpx.TimeoutException:
                if attempt == attempts - 1:
                    raise HTTPException(status_code=504, detail='Flash API request timed out')
                await asyncio.sleep(2 ** attempt * 0.5 + random.uniform(0, 0.5))
            except httpx.HTTPStatusError as e:
                if e.response is not None and e.response.status_code >= 500 and (attempt < attempts - 1):
                    await asyncio.sleep(2 ** attempt * 0.5 + random.uniform(0, 0.5))
                    continue
                raise HTTPException(status_code=502, detail=f'Flash API returned HTTP {e.response.status_code}')
            except httpx.ConnectError as e:
                logger.warning(f'Flash API connect error (attempt {attempt + 1}): {repr(e)}')
                if attempt == attempts - 1:
                    raise HTTPException(status_code=502, detail='Failed to connect to Flash API')
                _fresh = True
                await asyncio.sleep(2 ** attempt * 0.5 + random.uniform(0, 1.0))
            except httpx.RequestError:
                if attempt == attempts - 1:
                    raise HTTPException(status_code=502, detail='Failed to connect to Flash API')
                await asyncio.sleep(2 ** attempt * 0.5 + random.uniform(0, 0.5))
            finally:
                if inspection_handle:
                    finish_provider(inspection_handle, 'finished_without_response')
                if _fresh and _retry_client is not client:
                    await _retry_client.aclose()

async def call_llm_flash_for_text(prompt: str, temperature: Optional[float]=None, *, usage_tag: str='flash_text') -> str:
    """调用 Flash 模型生成文本（摘要、日记等），不带 thinking

    Args:
        prompt: 用户提示词
        temperature: 采样温度；None 时用 API 默认（1.0）。
    """
    messages = [Message(role='user', content=prompt)]
    try:
        response = await call_llm_api_flash(messages, enable_thinking=False, temperature=temperature, usage_tag=usage_tag)
        return response.get('content', '')
    except Exception as e:
        logger.error(f'Flash text generation failed: {e}')
        return ''

async def call_sentinel_first_layer_flash(prompt) -> str:
    """Run the configured Sentinel JSON lane without flattening source messages."""
    from wander_manager.flash_structured import call_flash_json_detailed
    from silicon_perception.analysis.sentinel_prompt import SentinelPrompt, sentinel_messages
    messages = sentinel_messages(prompt)
    result = await call_flash_json_detailed(messages, temperature=0.0, max_tokens=512, json_mode=True, enable_thinking=False, route_label='sentinel_first_layer')
    if result.status == 'ok' and result.parsed is not None:
        logger.info('Sentinel first-layer judge: provider=%s model=%s duration_ms=%s', result.provider, result.model, result.duration_ms)
        return json.dumps(result.parsed, ensure_ascii=False)
    if result.routing_managed or result.status == 'refusal':
        return ''
    logger.warning('Sentinel judge unavailable: status=%s error=%s; falling back to direct Flash', result.status, result.error)
    if isinstance(prompt, str) and (not isinstance(prompt, SentinelPrompt)):
        return await call_llm_flash_for_text(prompt, temperature=0.0)
    try:
        response = await call_llm_api_flash([Message(**item) for item in messages], enable_thinking=False, temperature=0.0, usage_tag='sentinel_first_layer_fallback')
        return response.get('content', '')
    except Exception as exc:
        logger.error('Sentinel direct Flash generation failed: %s', exc)
        return ''

async def call_llm_flash_for_long_text(prompt: str, temperature: Optional[float]=None, *, usage_tag: str='flash_long_text', enable_thinking: Optional[bool]=None) -> str:
    """长文本整理调用：给单次生成完整时间，不在网络层重复同一大请求。

    业务层（如日记）仍可针对解析失败决定是否再调用；网络层的一次超时
    直接抛出，避免 45 秒 × 3 次再叠加业务重试造成假卡死。
    显式 enable_thinking 优先；认知请求可声明阶段偏好，其余入口默认关闭。
    """
    from cognition.prompt_request import CognitionPrompt
    if enable_thinking is None:
        enable_thinking = bool(getattr(prompt, 'preferred_thinking', False)) if isinstance(prompt, CognitionPrompt) else False
    if isinstance(prompt, CognitionPrompt):
        from cognition.diagnostics import call_request
        response = await call_request(prompt, call_llm_api_flash, enable_thinking=enable_thinking, temperature=temperature, request_timeout=LLM_LONG_TIMEOUT, max_attempts=1, usage_tag=usage_tag, json_mode=True, max_tokens=32768)
        return response.get('content', '')
    messages = [Message(role='user', content=prompt)]
    response = await call_llm_api_flash(messages, enable_thinking=enable_thinking, temperature=temperature, request_timeout=LLM_LONG_TIMEOUT, max_attempts=1, usage_tag=usage_tag)
    return response.get('content', '')

async def call_llm_for_behavior(messages: List[Dict[str, Any]]) -> Dict[str, Any]:
    """调用LLM用于行为调度器 — 封装 call_llm_api_flash（thinking 始终启用，verbose 日志）"""
    return await call_llm_api_flash(messages, enable_thinking=True, usage_tag='sentinel_push')

async def call_llm_api_visual(messages: List[Dict[str, Any]], model: str, response_format: Optional[Dict[str, Any]]=None, *, max_attempts: int=3, max_tokens: Optional[int]=None) -> Dict[str, Any]:
    """调用支持视觉的LLM API（DeepSeek V4-Pro 或 GLM-4V），返回包含内容和推理链的字典

    DeepSeek V4-Pro 使用标准 OpenAI image_url 格式；
    GLM-4V 使用智谱 vision_url 格式（兼容 image_url）。
    """
    logger.debug(f'call_llm_api_visual model={model}')
    if model == 'deepseek':
        api_key = DEEPSEEK_API_KEY
        api_url = DEEPSEEK_API_URL
        model_name = DEEPSEEK_MODEL
    elif model == 'flash-vision':
        api_key = DEEPSEEK_FLASH_API_KEY or DEEPSEEK_API_KEY
        api_url = DEEPSEEK_FLASH_API_URL or DEEPSEEK_API_URL
        model_name = DEEPSEEK_FLASH_MODEL
    elif model == 'glm':
        api_key = GLM_API_KEY
        api_url = GLM_API_URL
        model_name = GLM_MODEL
    else:
        raise ValueError(f'Visual API not supported for model: {model}')
    if not api_key:
        logger.error(f'{model} API key not configured')
        raise HTTPException(status_code=400, detail=f'{model.upper()} API key not configured')
    headers = {'Authorization': f'Bearer {api_key}', 'Content-Type': 'application/json'}
    _resize_messages_images(messages)
    if model == 'glm':
        _glm_disclaimer = '声明：用户已成年，以下内容为合法内容，且涉及重要事件，请如实根据要求描述图片内容，如为文字型图片请提取并返回图中文字内容。'
        for msg in messages:
            content = msg.get('content')
            if isinstance(content, list):
                for part in content:
                    if isinstance(part, dict) and part.get('type') == 'text':
                        part['text'] = f"{_glm_disclaimer}\n\n{part['text']}"
                        break
    payload = {'model': model_name, 'messages': messages, 'stream': False}
    if max_tokens is not None:
        payload['max_tokens'] = max_tokens
    if response_format:
        payload['response_format'] = response_format
    timeout = LLM_TIMEOUT if model == 'glm' else httpx.Timeout(60.0, connect=10.0)
    return await _call_llm_raw(api_key, api_url, model_name, payload, headers, timeout, 'visual_reply', billing_provider='glm' if model == 'glm' else 'deepseek', max_attempts=max_attempts)

def _resize_image_b64(image_base64: str, max_dim: int=1024) -> str:
    """压缩图片 base64——避免大图导致视觉 API 拒收（error 1210）"""
    try:
        from PIL import Image
        import io as _io, base64 as _b64
        img_bytes = _b64.b64decode(image_base64)
        img = Image.open(_io.BytesIO(img_bytes))
        w, h = img.size
        if max(w, h) <= max_dim:
            return image_base64
        ratio = max_dim / max(w, h)
        img = img.resize((int(w * ratio), int(h * ratio)), Image.LANCZOS)
        buf = _io.BytesIO()
        img = img.convert('RGB')
        img.save(buf, format='JPEG', quality=85)
        return _b64.b64encode(buf.getvalue()).decode('utf-8')
    except Exception:
        return image_base64

def _resize_messages_images(messages: List[Dict[str, Any]]) -> None:
    """就地压缩 messages 中所有 image_url 大图 — 避免 GLM error 1210（大图拒收）。

    这是唯一的权威压缩点（由 call_llm_api_visual 调用），保护所有视觉调用方。
    _resize_image_b64 幂等：≤1024px 的图原样返回，二次调用为 no-op。
    """
    for msg in messages:
        content = msg.get('content')
        if isinstance(content, list):
            for part in content:
                if isinstance(part, dict) and part.get('type') == 'image_url':
                    url = part.get('image_url', {}).get('url', '')
                    if url.startswith('data:') and 'base64,' in url:
                        try:
                            header, b64 = url.split('base64,', 1)
                            resized = _resize_image_b64(b64)
                            import base64 as _mime_b64
                            signature = _mime_b64.b64decode(resized[:16])
                            if signature.startswith(b'\xff\xd8'):
                                header = 'data:image/jpeg;'
                            elif signature.startswith(b'\x89PNG'):
                                header = 'data:image/png;'
                            part['image_url']['url'] = f'{header}base64,{resized}'
                        except Exception:
                            pass

def vision_fallback_for(model: str) -> str:
    """返回某视觉模型的降级备选模型。

    - "flash-vision" → "glm"（多模态 flash 主，GLM 兜底）
    - "deepseek" → "glm"（pro 视觉主，GLM 兜底，向后兼容）
    - "glm" → "flash-vision"（GLM 被显式选择时，flash-vision 兜底）
    """
    if model == 'flash-vision':
        return 'glm'
    if model == 'deepseek':
        return 'glm'
    return 'flash-vision'

def official_flash_vision_ready():
    """Pure preflight, before a domain claims any possibly paid dispatch."""
    from urllib.parse import urlsplit
    endpoint = urlsplit(DEEPSEEK_FLASH_API_URL or DEEPSEEK_API_URL)
    if endpoint.scheme != 'https' or endpoint.hostname != 'api.deepseek.com' or DEEPSEEK_FLASH_MODEL != 'deepseek-v4-flash-vision-exp' or (not (DEEPSEEK_FLASH_API_KEY or DEEPSEEK_API_KEY)):
        raise ValueError('official_flash_vision_unavailable')

async def call_vision_api(image_base64: str, prompt: str, model: str=None, max_tokens: int=2048, mime_type: str='image/jpeg', *, official_only: bool=False) -> dict:
    """统一视觉 API 调用入口 — 所有图片分析管道的唯一权威路径。

    内部根据 model 自动切换消息格式（DS/GLM 均支持 OpenAI image_url），
    默认主模型失败时降级；official_only 固定官方 Flash、单次派发且无回退。

    Args:
        image_base64: 图片的 base64 编码（不含 data: 前缀）
        prompt: 分析提示词
        model: 视觉模型标识 ("deepseek" | "glm")，None 时从 shared_state 读取
        max_tokens: 最大输出 token 数
        mime_type: 图片 MIME 类型，默认 image/jpeg

    Returns:
        {"content": str, "reasoning": Optional[str]}
    """
    import logging
    _logger = logging.getLogger(__name__)
    if model is None:
        try:
            from shared_state import get_current_image_model
            model = get_current_image_model()
        except Exception:
            model = 'deepseek'
    actual_mime = mime_type if mime_type in {'image/png', 'image/jpeg', 'image/webp'} else 'image/jpeg'
    data_url = f'data:{actual_mime};base64,{image_base64}'
    messages = [{'role': 'user', 'content': [{'type': 'text', 'text': prompt}, {'type': 'image_url', 'image_url': {'url': data_url}}]}]
    if official_only:
        official_flash_vision_ready()
        if model != 'flash-vision':
            raise ValueError('official_flash_vision_unavailable')
        result = await call_llm_api_visual(messages, 'flash-vision', max_attempts=1, max_tokens=max_tokens)
        return dict(result, provider='deepseek_direct', model=DEEPSEEK_FLASH_MODEL)
    primary = model if model in ('flash-vision', 'deepseek', 'glm') else 'flash-vision'
    fallback = vision_fallback_for(primary)
    try:
        return await call_llm_api_visual(messages, primary)
    except httpx.HTTPStatusError as e:
        status = e.response.status_code if e.response is not None else 0
        _logger.warning(f'视觉模型 {primary} HTTP {status}，降级到 {fallback}')
    except (httpx.ConnectError, httpx.TimeoutException) as e:
        _logger.warning(f'视觉模型 {primary} 连接/超时: {e}，降级到 {fallback}')
    except HTTPException:
        raise
    except Exception as e:
        _logger.warning(f'视觉模型 {primary} 失败: {e}，降级到 {fallback}')
    try:
        return await call_llm_api_visual(messages, fallback)
    except Exception as e:
        _logger.warning(f'视觉模型降级 {fallback} 也失败: {e}，尝试硅基流动')
    if SF_API_KEY:
        try:
            _logger.info(f'视觉模型降级到硅基流动 {SF_VL_MODEL}')
            headers = {'Authorization': f'Bearer {SF_API_KEY}', 'Content-Type': 'application/json'}
            payload = {'model': SF_VL_MODEL, 'messages': messages, 'stream': False, 'max_tokens': 1024}
            async with httpx.AsyncClient(timeout=60.0, limits=LLM_LIMITS, proxy=None, trust_env=False) as client:
                from api_sources.legacy_transport import tracked_post
                from uuid import uuid4
                r = await tracked_post(client, SF_API_URL, json=payload, headers=headers, timeout=60.0, task_id=uuid4().hex, category='vision', node='visual_sf_final_fallback', ordinal=1)
                r.raise_for_status()
                data = r.json()
                content = data['choices'][0]['message']['content']
                reasoning = data['choices'][0]['message'].get('reasoning_content', '')
                _logger.info(f'硅基流动 VL 成功: {content[:80]}...')
                return {'content': content, 'reasoning': reasoning}
        except Exception as e3:
            _logger.error(f'硅基流动 VL 也失败: {e3}')
    raise HTTPException(status_code=502, detail=f'视觉分析失败: 主模型 {primary}、降级 {fallback}、硅基流动均不可用')

async def call_vision_messages(messages: List[Dict[str, Any]], model: str=None, response_format: Optional[Dict[str, Any]]=None) -> dict:
    """统一视觉入口 — 预构建消息版本（聊天路径用，支持多图）。

    与 call_vision_api 的区别：接受完整的 messages 数组而非 image+prompt，
    适用于需要多图或自定义 prompt 的聊天路径。内置主模型→降级模型 fallback。

    Args:
        messages: 完整的 OpenAI-format 消息数组（含 image_url content）
        model: 视觉模型标识 ("deepseek" | "glm")，None 时从 shared_state 读取

    Returns:
        {"content": str, "reasoning": Optional[str]}
    """
    import logging
    _logger = logging.getLogger(__name__)
    if model is None:
        try:
            from shared_state import get_current_image_model
            model = get_current_image_model()
        except Exception:
            model = 'flash-vision'
    fallback = vision_fallback_for(model)
    try:
        return await call_llm_api_visual(messages, model, response_format=response_format)
    except (httpx.HTTPStatusError, httpx.ConnectError, httpx.TimeoutException) as e:
        _logger.warning(f'视觉模型 {model} 失败: {e}，降级到 {fallback}')
    except HTTPException as e:
        if e.status_code >= 500:
            _logger.warning(f'视觉模型 {model} HTTP {e.status_code}，降级到 {fallback}')
        else:
            raise
    except Exception as e:
        _logger.warning(f'视觉模型 {model} 异常: {e}，降级到 {fallback}')
    try:
        return await call_llm_api_visual(messages, fallback, response_format=response_format)
    except Exception as e:
        _logger.error(f'视觉降级 {fallback} 也失败: {e}')
        raise HTTPException(status_code=502, detail=f'视觉分析失败: 主模型 {model} 和降级模型 {fallback} 均不可用')

async def call_llm_for_wander(messages: List[Dict[str, Any]], with_reasoning: bool=False, *, route_label: str='wander_message', enable_thinking: bool=True, activity_context: Optional[dict]=None):
    """专用于漫想模式的LLM调用，错误时返回空字符串而非抛异常。

    with_reasoning=False（默认）: 返回 str content，兼容所有旧调用方。
    with_reasoning=True: 返回 {"content": str, "reasoning": str}——Flash 默认输出
    reasoning_content，此前被丢弃，漫想思考链从这里提取（trap 223）。"""
    api_key = DEEPSEEK_FLASH_API_KEY or DEEPSEEK_API_KEY
    api_url = DEEPSEEK_FLASH_API_URL or DEEPSEEK_API_URL
    model_name = DEEPSEEK_FLASH_MODEL
    headers = {'Authorization': f'Bearer {api_key}', 'Content-Type': 'application/json'}
    enriched_messages = list(messages)
    ctx_injected = False
    context_end = history_end = 0
    session_id = get_active_session_id()
    from wander_manager.activity_context import current as current_activity_context
    activity_context = activity_context or current_activity_context()
    recipe_name = 'WANDER_MUSIC_SELECTION' if route_label == 'music_song_selection' else 'WANDER_ACTIVITY' if activity_context is not None else 'WANDER_PUSH'
    try:
        if route_label == 'music_song_selection':
            from wander_manager.music_selection_context import build_context
            result = await build_context(persona=get_latest_persona_prompt() or '', session_id=session_id, activity_context=activity_context)
        elif recipe_name == 'WANDER_ACTIVITY':
            from wander_manager.activity_context import build_context
            result = await build_context(persona=get_latest_persona_prompt() or '', session_id=session_id, activity_context=activity_context)
        else:
            from context_builder import ContextBuilder
            try:
                from context_builder.ingredients import build_wander_mode_text
                _wander_text = build_wander_mode_text('push')
            except Exception:
                _wander_text = ''
            _self_book_entries = []
            try:
                from self_book import get_global_self_book
                _sb = get_global_self_book()
                _sb_query = ' '.join((str(m.get('content', '')) for m in messages))[:500]
                if _sb_query:
                    _self_book_entries = _sb.search(_sb_query)
            except Exception:
                _self_book_entries = []
            result = await ContextBuilder.build(recipe_name, persona=get_latest_persona_prompt() or '', session_id=session_id, mood='', wander_mode_text=_wander_text, self_book_entries=_self_book_entries)
        from context_builder.assembly import assemble_context_result
        assembled = assemble_context_result(result)
        if assembled:
            enriched_messages = assembled + enriched_messages
            context_end = len(assembled)
            history_end = len(result.formatted_messages)
            ctx_injected = True
            logger.debug('WANDER_LLM: %s recipe injected (messages=%d)', recipe_name, len(assembled))
    except Exception:
        import traceback
        logger.warning('WANDER_LLM: %s recipe build failed: %s', recipe_name, traceback.format_exc())
    if not ctx_injected and recipe_name in {'WANDER_ACTIVITY', 'WANDER_MUSIC_SELECTION'}:
        return {'content': '', 'reasoning': ''} if with_reasoning else ''
    if not ctx_injected:
        cs2 = get_context_scheduler()
        if cs2 and session_id:
            try:
                ctx = await cs2.build_lightweight_context(session_id=session_id, persona=get_latest_persona_prompt() or '')
                if ctx.formatted_context:
                    enriched_messages = [{'role': 'system', 'content': get_latest_persona_prompt() or '你是 AI。'}, {'role': 'system', 'content': ctx.formatted_context}] + enriched_messages
                    ctx_injected = True
            except Exception:
                pass
    if not ctx_injected and get_latest_persona_prompt():
        enriched_messages.insert(0, {'role': 'system', 'content': get_latest_persona_prompt()})
        try:
            from context_builder import record_recipe_call
            record_recipe_call('漫想（降级）', 'bare_persona', sections={'persona': get_latest_persona_prompt()[:200]}, total_chars=len(get_latest_persona_prompt()), total_tokens=0)
        except Exception:
            pass
    from wander_manager.request_projection import prepare as prepare_wander_request
    from api_sources.model_context import with_current_model
    source_messages = with_current_model(enriched_messages, model_name)
    enriched_messages, request_projection = prepare_wander_request(source_messages, model=model_name, base_url=api_url, history_end=history_end, context_end=context_end)
    from api_sources.managed import call_managed
    managed = await call_managed(route_label, source_messages, enable_thinking=enable_thinking, json_mode=route_label == 'music_song_selection', inspect_provider=True, request_projector=lambda source, canonical: prepare_wander_request(canonical, model=source['model']['model'], base_url=source['station']['base_url'], history_end=history_end, context_end=context_end))
    if managed is not None:
        if managed.status != 'ok':
            return {'content': '', 'reasoning': '', 'model_source': None} if with_reasoning else ''
        return {'content': managed.raw_content, 'reasoning': managed.reasoning, 'model_source': getattr(managed, 'model_source', None)} if with_reasoning else managed.raw_content
    if not api_key:
        logger.error('WANDER_LLM: API key not configured')
        return ''
    payload = {'model': model_name, 'messages': enriched_messages, 'stream': False}
    if request_projection['reason'] != 'other_provider_or_model':
        payload['thinking'] = {'type': 'enabled' if enable_thinking else 'disabled'}
    logger.debug(f'WANDER_LLM: calling API model={model_name}, messages={len(enriched_messages)} (with persona)')
    from neuron_registry import neuron_trace
    with neuron_trace(f'{route_label}_generator', recipe=recipe_name, model='Flash') as trace:
        trace.set_input(enriched_messages[-1].get('content', '') if enriched_messages else '')
        client = http_client or httpx.AsyncClient(timeout=LLM_TIMEOUT, limits=LLM_LIMITS, proxy=None, trust_env=False)
        _fresh = False
        started_at = time.perf_counter()
        from api_sources.legacy_transport import tracked_post
        from uuid import uuid4
        audit_task_id = uuid4().hex
        provider_started_at = datetime.now().astimezone().isoformat()
        async with llm_semaphore:
            for attempt in range(2):
                _retry_client = client
                if _fresh:
                    _retry_client = httpx.AsyncClient(timeout=LLM_TIMEOUT, limits=LLM_LIMITS, proxy=None, trust_env=False)
                inspection_handle = None
                try:
                    from context_inspection import observe_provider, finish_provider
                    inspection_handle = observe_provider(payload.get('messages', []), model=model_name, provider=route_label, use_bound=False, source_messages=source_messages, request_projection=request_projection, request_id=audit_task_id)
                    response = await tracked_post(_retry_client, api_url, json=payload, headers=headers, task_id=audit_task_id, category='expression' if route_label == 'wander_message' else 'music_selection', node=route_label, ordinal=attempt + 1)
                    response.raise_for_status()
                    finish_provider(inspection_handle, 'response_received')
                    result = response.json()
                    choices = result.get('choices') if isinstance(result, dict) else None
                    if not choices:
                        logger.error('WANDER_LLM: API returned empty choices')
                        trace.set_error('API returned empty choices')
                        return ''
                    message = choices[0].get('message', {})
                    if message.get('refusal') or choices[0].get('finish_reason') in {'content_filter', 'refusal'}:
                        trace.set_error('模型明确拒答')
                        return ''
                    content = message.get('content', '')
                    logger.debug(f'WANDER_LLM: success, content[:100]={content[:100]}')
                    asyncio.create_task(log_token_usage(route_label, model_name, result.get('usage')))
                    try:
                        from prompt_ledger import record_provider_usage_for_messages
                        record_provider_usage_for_messages(enriched_messages, result.get('usage'), model=model_name, provider=route_label, billing_provider='deepseek', latency_ms=(time.perf_counter() - started_at) * 1000.0, request_options={k: v for k, v in payload.items() if k != 'messages'}, source_messages=source_messages, request_projection=request_projection, provider_request_id=audit_task_id, provider_started_at=provider_started_at)
                    except Exception:
                        pass
                    trace.set_output(content[:300] if content else '')
                    if with_reasoning:
                        reasoning = message.get('reasoning_content', '') or ''
                        trace.set_thinking(reasoning)
                        return {'content': content, 'reasoning': reasoning}
                    return content
                except httpx.ConnectError as e:
                    logger.warning(f'WANDER_LLM: connect error attempt {attempt + 1}: {repr(e)}')
                    if attempt == 1:
                        trace.set_error(f'ConnectError: {repr(e)}')
                        return ''
                    _fresh = True
                    await asyncio.sleep(2 ** attempt * 0.5 + random.uniform(0, 1.0))
                except httpx.TimeoutException as e:
                    logger.warning(f'WANDER_LLM: timeout attempt {attempt + 1}: {repr(e)}')
                    if attempt == 1:
                        trace.set_error(f'Timeout: {repr(e)}')
                        return ''
                    await asyncio.sleep(2 ** attempt * 0.5 + random.uniform(0, 0.5))
                except Exception as e:
                    logger.error(f'WANDER_LLM: error attempt {attempt + 1}: {type(e).__name__}: {repr(e)}')
                    if attempt == 1:
                        trace.set_error(f'{type(e).__name__}: {repr(e)}')
                        return ''
                    await asyncio.sleep(2 ** attempt * 0.5 + random.uniform(0, 0.5))
                finally:
                    if inspection_handle:
                        finish_provider(inspection_handle, 'finished_without_response')
                    if _fresh and _retry_client is not client:
                        await _retry_client.aclose()
    return ''
