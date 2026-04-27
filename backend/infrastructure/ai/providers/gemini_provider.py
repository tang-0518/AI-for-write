"""Gemini LLM 提供商实现（官方 generateContent / streamGenerateContent 协议）"""
from __future__ import annotations

import asyncio
import json
import logging
from typing import Any, AsyncIterator

import httpx

from domain.ai.services.llm_service import GenerationConfig, GenerationResult
from domain.ai.value_objects.prompt import Prompt
from domain.ai.value_objects.token_usage import TokenUsage
from infrastructure.ai.config.settings import Settings
from .base import BaseProvider

logger = logging.getLogger(__name__)

DEFAULT_MODEL = 'gemini-2.5-pro'
DEFAULT_BASE_URL = 'https://generativelanguage.googleapis.com/v1beta'


class GeminiProvider(BaseProvider):
    def __init__(self, settings: Settings):
        super().__init__(settings)
        if not settings.api_key:
            raise ValueError('API key is required for GeminiProvider')
        self.base_url = (settings.base_url or DEFAULT_BASE_URL).rstrip('/')

    async def generate(self, prompt: Prompt, config: GenerationConfig) -> GenerationResult:
        payload = self._build_payload(prompt, config)
        query = self._build_query()
        url = self._build_url(config.model or self.settings.default_model or DEFAULT_MODEL, 'generateContent')
        timeout = httpx.Timeout(self.settings.timeout_seconds)

        last_exc: Exception | None = None
        for attempt in range(3):
            try:
                async with httpx.AsyncClient(timeout=timeout) as client:
                    response = await client.post(
                        url,
                        params=query,
                        headers=self._build_headers(stream=False),
                        json=payload,
                    )
                    response.raise_for_status()
                    data = response.json()
                break
            except httpx.HTTPStatusError as e:
                if e.response.status_code == 503 and attempt < 2:
                    wait = 5 * (attempt + 1)
                    logger.warning('Gemini 503, retry %d/3 in %ds', attempt + 1, wait)
                    await asyncio.sleep(wait)
                    last_exc = e
                    continue
                raise
        else:
            raise last_exc  # type: ignore[misc]

        content = self._extract_text(data)
        if not content.strip():
            raise RuntimeError('Gemini returned empty content')

        usage = data.get('usageMetadata') or {}
        token_usage = TokenUsage(
            input_tokens=int(usage.get('promptTokenCount') or 0),
            output_tokens=int(usage.get('candidatesTokenCount') or 0),
        )
        return GenerationResult(content=content, token_usage=token_usage)

    async def stream_generate(self, prompt: Prompt, config: GenerationConfig) -> AsyncIterator[str]:
        payload = self._build_payload(prompt, config)
        query = self._build_query({'alt': 'sse'})
        url = self._build_url(config.model or self.settings.default_model or DEFAULT_MODEL, 'streamGenerateContent')
        timeout = httpx.Timeout(self.settings.timeout_seconds)

        async with httpx.AsyncClient(timeout=timeout) as client:
            async with client.stream(
                'POST',
                url,
                params=query,
                headers=self._build_headers(stream=True),
                json=payload,
            ) as response:
                response.raise_for_status()
                buffer = ''
                async for chunk in response.aiter_text():
                    buffer += chunk.replace('\r\n', '\n')
                    while '\n\n' in buffer:
                        event_text, buffer = buffer.split('\n\n', 1)
                        text = self._parse_sse_event(event_text)
                        if text:
                            yield text

    def _build_url(self, model: str, action: str) -> str:
        model_name = model.strip() or DEFAULT_MODEL
        return f'{self.base_url}/models/{model_name}:{action}'

    def _build_query(self, extra: dict[str, Any] | None = None) -> dict[str, Any]:
        query: dict[str, Any] = {'key': self.settings.api_key}
        query.update(self.settings.extra_query or {})
        if extra:
            query.update(extra)
        return query

    def _build_headers(self, *, stream: bool) -> dict[str, str]:
        headers = {'Content-Type': 'application/json'}
        if stream:
            headers['Accept'] = 'text/event-stream'
        headers.update(self.settings.extra_headers or {})
        return headers

    def _build_payload(self, prompt: Prompt, config: GenerationConfig) -> dict[str, Any]:
        # thinkingBudget=1024：限制 Gemini 2.5 Pro thinking tokens，
        # 避免其无限制消耗 maxOutputTokens 预算导致正文被截断。
        # 可通过 extra_body.generationConfig.thinkingConfig 覆盖。
        generation_config = {
            'temperature': config.temperature,
            'maxOutputTokens': config.max_tokens,
            'thinkingConfig': {'thinkingBudget': 1024},
        }
        payload: dict[str, Any] = {
            'contents': [
                {
                    'role': 'user',
                    'parts': [{'text': prompt.user}],
                }
            ],
            'generationConfig': generation_config,
        }
        if prompt.system.strip():
            payload['systemInstruction'] = {
                'parts': [{'text': prompt.system}],
            }
        extra_body = dict(self.settings.extra_body or {})
        generation_override = extra_body.pop('generationConfig', None)
        if isinstance(generation_override, dict):
            payload['generationConfig'].update(generation_override)
        payload.update(extra_body)
        return payload

    def _extract_text(self, data: dict[str, Any]) -> str:
        pieces: list[str] = []
        for candidate in data.get('candidates') or []:
            content = candidate.get('content') or {}
            for part in content.get('parts') or []:
                text = part.get('text')
                if text:
                    pieces.append(str(text))
        return ''.join(pieces)

    def _parse_sse_event(self, event_text: str) -> str:
        data_lines: list[str] = []
        for line in event_text.splitlines():
            if line.startswith('data:'):
                data_lines.append(line[5:].strip())

        if not data_lines:
            return ''

        raw_payload = ''.join(data_lines).strip()
        if not raw_payload or raw_payload == '[DONE]':
            return ''

        try:
            payload = json.loads(raw_payload)
        except json.JSONDecodeError:
            logger.debug('Gemini SSE parse skip: %s', raw_payload[:120])
            return ''

        if isinstance(payload, list):
            return ''.join(self._extract_text(item) for item in payload if isinstance(item, dict))
        if isinstance(payload, dict):
            return self._extract_text(payload)
        return ''
