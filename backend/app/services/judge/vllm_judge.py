"""The primary judge — any model served over an OpenAI-compatible vLLM endpoint.

Currently qwen3.6-27b. A deterministic mock is used when `settings.mock_judge`
is true, so the pipeline runs without the GPU box being available.
"""

from __future__ import annotations

from openai import AsyncOpenAI
from tenacity import retry, stop_after_attempt, wait_exponential

from app.core.config import settings
from app.core.exceptions import ExternalServiceError
from app.core.logging import get_logger
from app.services.judge.base import JudgeRequest, JudgeResult
from app.services.judge.prompts import (
    ABSOLUTE_SYSTEM_PROMPT,
    build_absolute_prompt,
    parse_absolute_output,
)

logger = get_logger(__name__)


class VLLMJudge:
    """Absolute-grading judge over a self-hosted vLLM (OpenAI-compatible) endpoint.

    The actual model is whatever ``settings.judge_model`` points at; the display
    ``name`` reflects it so audit votes are labeled by the real grader.
    """

    def __init__(self) -> None:
        self._client: AsyncOpenAI | None = None
        self.name = settings.judge_model
        # Known judge endpoints, tried in order. The tunnel URL is ephemeral —
        # on a call failure we rotate to the next URL (see _grade_vllm) so a
        # rotated tunnel degrades to a fallback instead of failing the run.
        urls = [settings.judge_base_url.rstrip("/")]
        urls += [
            u.strip().rstrip("/")
            for u in settings.judge_fallback_base_urls.split(",")
            if u.strip()
        ]
        self._urls = urls
        self._url_idx = 0

    @property
    def client(self) -> AsyncOpenAI:
        if self._client is None:
            self._client = AsyncOpenAI(
                base_url=self._urls[self._url_idx],
                api_key=settings.judge_api_key,
            )
        return self._client

    async def grade(self, request: JudgeRequest) -> JudgeResult:
        if settings.mock_judge:
            return self._grade_mock(request)
        return await self._grade_vllm(request)

    @retry(
        stop=stop_after_attempt(3),
        wait=wait_exponential(multiplier=1, min=1, max=10),
        reraise=True,
    )
    async def _grade_vllm(self, request: JudgeRequest) -> JudgeResult:
        prompt = build_absolute_prompt(
            instruction=request.instruction,
            response=request.response,
            rubric=request.rubric,
            reference_answer=request.reference_answer,
        )
        try:
            completion = await self.client.chat.completions.create(
                model=settings.judge_model,
                messages=[
                    {"role": "system", "content": ABSOLUTE_SYSTEM_PROMPT},
                    {"role": "user", "content": prompt},
                ],
                # Turn off the vLLM reasoning model's hidden "thinking" step
                # (~7x faster; grading is rubric-driven so it isn't needed).
                extra_body=(
                    {"chat_template_kwargs": {"enable_thinking": False}}
                    if settings.judge_disable_thinking
                    else None
                ),
                # Deterministic grading for a stable, reproducible TrustScore.
                # The 2048 ceiling leaves room for reasoning models that "think"
                # before the score — 1024 gets eaten and the reply comes back empty.
                temperature=0.0,
                max_tokens=2048,
            )
        except Exception as exc:  # network / server error
            logger.error(
                "judge.vllm_error", error=str(exc), base_url=self._urls[self._url_idx]
            )
            # Rotate to the next known endpoint; the retry decorator's next
            # attempt then rebuilds the client against it.
            if len(self._urls) > 1:
                self._url_idx = (self._url_idx + 1) % len(self._urls)
                self._client = None
                logger.warning("judge.rotate_url", next_url=self._urls[self._url_idx])
            raise ExternalServiceError(f"Judge request failed: {exc}") from exc

        content = completion.choices[0].message.content or ""
        score, feedback = parse_absolute_output(content)
        return JudgeResult(score=score, feedback=feedback)

    def _grade_mock(self, request: JudgeRequest) -> JudgeResult:
        """Deterministic heuristic stub: rewards non-empty, error-free output."""
        resp = request.response.strip().lower()
        if not resp:
            return JudgeResult(1, "[mock] Empty response.")
        if "error" in resp or "traceback" in resp:
            return JudgeResult(2, "[mock] Response contains errors.")
        score = 5 if len(resp) > 20 else 4
        return JudgeResult(score, f"[mock] Looks reasonable (len={len(resp)}).")
