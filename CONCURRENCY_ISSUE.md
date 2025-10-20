# Concurrency Issue Analysis

## Problem

vLLama is **slower than Ollama under concurrent load**:
- 5 parallel requests: Ollama 1.16x faster (6.5s vs 7.6s)
- Expected: vLLama should maintain or improve its 4.4x sequential advantage

## Root Cause

**Location:** `python/llm_service/server.py:235`

```python
@app.post("/generate", response_model=GenerateResponse)
async def generate(request: GenerateRequest):
    # ... (async handler)

    llm = engine.models[request.model_id]

    # ❌ BLOCKING SYNCHRONOUS CALL in async function
    outputs = llm.generate([request.prompt], sampling_params)
```

### Why This Breaks Concurrency

1. **FastAPI receives 5 concurrent requests** → Creates 5 async tasks
2. **Each task calls `llm.generate()`** → **Blocks the entire event loop**
3. **Other requests wait** → Requests are effectively serialized
4. **No batching** → vLLM's batch processing advantage is lost

The synchronous `LLM.generate()` call blocks the async event loop, preventing true concurrent execution.

## Solution Options

### Option 1: Use AsyncLLMEngine (Recommended)

Replace synchronous `LLM` with `AsyncLLMEngine`:

```python
from vllm.engine.async_llm_engine import AsyncLLMEngine

# In load_model():
engine = AsyncLLMEngine.from_engine_args(...)

# In generate():
async for output in engine.generate(request.prompt, ...):
    # Process streaming output
```

**Pros:**
- Native async support
- Automatic request batching
- True concurrent execution
- Streaming support built-in

**Cons:**
- Requires refactoring engine initialization
- Different API than synchronous LLM

### Option 2: Thread Pool Executor

Run synchronous `generate()` in a thread pool:

```python
from concurrent.futures import ThreadPoolExecutor
import asyncio

executor = ThreadPoolExecutor(max_workers=4)

async def generate(request: GenerateRequest):
    # ...
    loop = asyncio.get_event_loop()
    outputs = await loop.run_in_executor(
        executor,
        llm.generate,
        [request.prompt],
        sampling_params
    )
```

**Pros:**
- Minimal code changes
- Works with existing LLM API

**Cons:**
- Doesn't leverage vLLM's batch processing
- Thread overhead
- Still somewhat serialized

### Option 3: Use vLLM OpenAI-Compatible Server

Replace custom service with vLLM's official server:

```bash
python -m vllm.entrypoints.openai.api_server \
  --model Qwen/Qwen2.5-1.5B-Instruct \
  --port 8100
```

**Pros:**
- Production-ready async implementation
- Maintained by vLLM team
- Proper request batching
- OpenAI API compatible

**Cons:**
- Less control over engine configuration
- May not support all custom features
- Additional dependency

## Recommendation

**✅ Phase 1 COMPLETE:** Switched to **AsyncLLMEngine** (Option 1)
- Fixed blocking sync calls (11% improvement at 5 concurrent)
- Now competitive for low concurrency (5 requests: nearly tied with Ollama)

**⚠️ Phase 1 Limitation Discovered:**
- At higher concurrency (10+), performance degrades significantly
- 10 concurrent: Ollama 3.38x faster (21.7s vs 6.4s)
- Root cause: FastAPI handler pattern doesn't leverage continuous batching
- See BATCHING_INVESTIGATION.md for detailed analysis

**📋 Phase 4 Recommendation:** Migrate to **vLLM OpenAI server** (Option 3)
- Production-ready continuous batching
- Official vLLM implementation
- Better scaling at high concurrency (10+, 50+, 100+)
- Active maintenance and updates

**Current Status:**
- Sequential: vLLama 4.4x faster ✅
- Low concurrency (5): Nearly tied ✅
- High concurrency (10+): Needs vLLM OpenAI server for production use

## Expected Performance After Fix

With proper async implementation and request batching:
- **Sequential:** Maintain 4.4x advantage (232ms vs 1010ms)
- **Concurrent (5 parallel):** Should improve to 3-4x faster than Ollama
- **High concurrency (50+):** vLLM batch processing should scale much better

## Testing Plan

After implementing fix:

1. **Low concurrency (5 parallel):** Should beat Ollama
2. **Medium concurrency (20 parallel):** vLLM batching advantage emerges
3. **High concurrency (50+ parallel):** vLLM should dominate due to batch processing

## References

- vLLM AsyncLLMEngine: https://docs.vllm.ai/en/latest/getting_started/async_engine.html
- vLLM OpenAI Server: https://docs.vllm.ai/en/latest/serving/openai_compatible_server.html
- Issue discovered: Phase 3 benchmarking (2025-10-20)
