"""
Swizzle Continuous Batching Engine: Production OpenAI-Compatible API Server.
=============================================================================
Exposes OpenAI-compatible endpoints (/v1/chat/completions, /v1/completions,
/v1/models, /health, /metrics) powered by the high-throughput Swizzle continuous
batching scheduler, AST-diff prefix cache, and prefill-decode disaggregation.
"""

import time
import uuid
import json
import asyncio
from typing import List, Dict, Any, Optional, AsyncIterator
from contextlib import asynccontextmanager
from fastapi import FastAPI, HTTPException, Request
from fastapi.middleware.cors import CORSMiddleware
from fastapi.responses import StreamingResponse, JSONResponse
from pydantic import BaseModel, Field

from swizzle.engine.llm_engine import LLMEngine, RequestOutput
from swizzle.engine.sequence import SamplingParams


# Global LLM Engine Instance
engine = LLMEngine(
    model_name="Qwen/Qwen2.5-Coder-7B-Instruct",
    num_blocks=2048,
    block_size=16,
    max_num_seqs=64,
    max_num_batched_tokens=4096,
    enable_speculative=True,
    enable_prefix_cache=True,
    enable_disagg=True,
)


@asynccontextmanager
async def lifespan(app: FastAPI):
    app.state.start_time = time.time()
    yield


# Initialize FastAPI application
app = FastAPI(
    title="Swizzle Continuous Batching Engine",
    description="Tier-1 continuous batching LLM inference engine with AST-diff virtual prefix caching and speculative verification.",
    version="0.2.0",
    lifespan=lifespan,
)

app.add_middleware(
    CORSMiddleware,
    allow_origins=["*"],
    allow_credentials=True,
    allow_methods=["*"],
    allow_headers=["*"],
)


# --- Request and Response Pydantic Schemas ---

class ChatMessage(BaseModel):
    role: str
    content: str


class ChatCompletionRequest(BaseModel):
    model: str = "Qwen/Qwen2.5-Coder-7B-Instruct"
    messages: List[ChatMessage]
    temperature: float = 0.7
    top_p: float = 0.95
    max_tokens: Optional[int] = 128
    stream: bool = False
    ast_metadata: Optional[Dict[str, Any]] = None


class CompletionRequest(BaseModel):
    model: str = "Qwen/Qwen2.5-Coder-7B-Instruct"
    prompt: str
    temperature: float = 0.7
    top_p: float = 0.95
    max_tokens: Optional[int] = 128
    stream: bool = False
    ast_metadata: Optional[Dict[str, Any]] = None


def _encode_text(text: str) -> List[int]:
    """Encodes UTF-8 text into token IDs."""
    if not text:
        return [1]
    return [int(b) + 1 for b in text.encode("utf-8")]


def _decode_tokens(tokens: List[int]) -> str:
    """Decodes token IDs into UTF-8 text."""
    if not tokens:
        return ""
    byte_vals = bytes([max(0, min(255, (t - 1) % 256)) for t in tokens])
    return byte_vals.decode("utf-8", errors="replace")


# --- Endpoints ---

@app.get("/health")
def health():
    return {
        "status": "healthy",
        "engine": "swizzle",
        "version": "0.2.0",
        "uptime_s": round(time.time() - getattr(app.state, "start_time", time.time()), 2),
    }


@app.get("/v1/models")
def list_models():
    return {
        "object": "list",
        "data": [
            {
                "id": "Qwen/Qwen2.5-Coder-7B-Instruct",
                "object": "model",
                "created": 1793510000,
                "owned_by": "swizzle-ai",
                "capabilities": {
                    "continuous_batching": True,
                    "ast_prefix_cache": True,
                    "speculative_decoding": True,
                    "prefill_decode_disagg": True,
                },
            },
            {
                "id": "meta-llama/Llama-3.1-8B-Instruct",
                "object": "model",
                "created": 1793510000,
                "owned_by": "swizzle-ai",
                "capabilities": {
                    "continuous_batching": True,
                    "ast_prefix_cache": True,
                    "speculative_decoding": True,
                    "prefill_decode_disagg": True,
                },
            },
        ],
    }


@app.get("/metrics")
def metrics():
    total_blocks = engine.block_manager.num_blocks
    free_blocks = len(engine.block_manager.free_block_ids)
    used_blocks = total_blocks - free_blocks
    total_allocs = engine.block_manager.total_allocations
    hit_rate = (
        (engine.block_manager.prefix_cache_hits + engine.block_manager.ast_cache_hits) / total_allocs
        if total_allocs > 0
        else 0.0
    )
    return {
        "step_counter": engine.step_counter,
        "waiting_requests": len(engine.scheduler.waiting),
        "running_requests": len(engine.scheduler.running),
        "swapped_requests": len(engine.scheduler.swapped),
        "used_gpu_blocks": used_blocks,
        "free_gpu_blocks": free_blocks,
        "block_utilization_ratio": round(used_blocks / total_blocks if total_blocks else 0.0, 4),
        "prefix_cache_hit_ratio": round(hit_rate, 4),
        "speculative_accepted_tokens": engine.speculative_scheduler.total_accepted,
        "speculative_drafted_tokens": engine.speculative_scheduler.total_drafted,
    }


@app.post("/v1/chat/completions")
async def chat_completions(req: ChatCompletionRequest):
    req_id = f"chatcmpl-{uuid.uuid4().hex[:12]}"
    combined_prompt = "\n".join([f"{m.role}: {m.content}" for m in req.messages]) + "\nassistant:"
    prompt_tokens = _encode_text(combined_prompt)

    sampling_params = SamplingParams(
        temperature=req.temperature,
        top_p=req.top_p,
        max_tokens=req.max_tokens or 64,
    )

    engine.add_request(
        request_id=req_id,
        prompt_tokens=prompt_tokens,
        sampling_params=sampling_params,
        ast_metadata=req.ast_metadata,
    )

    if req.stream:
        async def stream_generator() -> AsyncIterator[str]:
            created_ts = int(time.time())
            # Initial role chunk
            first_chunk = {
                "id": req_id,
                "object": "chat.completion.chunk",
                "created": created_ts,
                "model": req.model,
                "choices": [
                    {
                        "index": 0,
                        "delta": {"role": "assistant", "content": ""},
                        "finish_reason": None,
                    }
                ],
            }
            yield f"data: {json.dumps(first_chunk)}\n\n"

            emitted_tokens_count = 0
            while True:
                step_outputs = engine.step()
                req_output: Optional[RequestOutput] = None
                for out in step_outputs:
                    if out.request_id == req_id:
                        req_output = out
                        break

                if req_output is not None:
                    new_tokens = req_output.output_tokens[emitted_tokens_count:]
                    if new_tokens:
                        content_delta = _decode_tokens(new_tokens)
                        emitted_tokens_count = len(req_output.output_tokens)
                        chunk = {
                            "id": req_id,
                            "object": "chat.completion.chunk",
                            "created": created_ts,
                            "model": req.model,
                            "choices": [
                                {
                                    "index": 0,
                                    "delta": {"content": content_delta},
                                    "finish_reason": req_output.finish_reason if req_output.finished else None,
                                }
                            ],
                        }
                        yield f"data: {json.dumps(chunk)}\n\n"

                    if req_output.finished:
                        break

                await asyncio.sleep(0.001)

            yield "data: [DONE]\n\n"

        return StreamingResponse(
            stream_generator(),
            media_type="text/event-stream",
            headers={
                "Cache-Control": "no-cache",
                "Connection": "keep-alive",
                "x-swizzle-engine": "v0.2.0",
            },
        )

    # Non-streaming request: loop step until finished
    req_output: Optional[RequestOutput] = None
    while True:
        step_outputs = engine.step()
        for out in step_outputs:
            if out.request_id == req_id:
                req_output = out
                break
        if req_output and req_output.finished:
            break
        await asyncio.sleep(0.001)

    generated_text = _decode_tokens(req_output.output_tokens)
    return {
        "id": req_id,
        "object": "chat.completion",
        "created": int(time.time()),
        "model": req.model,
        "choices": [
            {
                "index": 0,
                "message": {
                    "role": "assistant",
                    "content": generated_text,
                },
                "finish_reason": req_output.finish_reason or "stop",
            }
        ],
        "usage": {
            "prompt_tokens": len(req_output.prompt_tokens),
            "completion_tokens": len(req_output.output_tokens),
            "total_tokens": len(req_output.prompt_tokens) + len(req_output.output_tokens),
        },
        "swizzle_telemetry": req_output.telemetry,
    }


@app.post("/v1/completions")
async def completions(req: CompletionRequest):
    req_id = f"cmpl-{uuid.uuid4().hex[:12]}"
    prompt_tokens = _encode_text(req.prompt)

    sampling_params = SamplingParams(
        temperature=req.temperature,
        top_p=req.top_p,
        max_tokens=req.max_tokens or 64,
    )

    engine.add_request(
        request_id=req_id,
        prompt_tokens=prompt_tokens,
        sampling_params=sampling_params,
        ast_metadata=req.ast_metadata,
    )

    req_output: Optional[RequestOutput] = None
    while True:
        step_outputs = engine.step()
        for out in step_outputs:
            if out.request_id == req_id:
                req_output = out
                break
        if req_output and req_output.finished:
            break
        await asyncio.sleep(0.001)

    generated_text = _decode_tokens(req_output.output_tokens)
    return {
        "id": req_id,
        "object": "text_completion",
        "created": int(time.time()),
        "model": req.model,
        "choices": [
            {
                "text": generated_text,
                "index": 0,
                "logprobs": None,
                "finish_reason": req_output.finish_reason or "stop",
            }
        ],
        "usage": {
            "prompt_tokens": len(req_output.prompt_tokens),
            "completion_tokens": len(req_output.output_tokens),
            "total_tokens": len(req_output.prompt_tokens) + len(req_output.output_tokens),
        },
    }



