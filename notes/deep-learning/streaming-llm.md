---
title: "StreamingLLM: Efficient Streaming Language Model Inference"
slug: "streaming-llm"
description: "The StreamingLLM system combining attention sinks with a fixed-size sliding KV cache window to enable LLMs to generate arbitrarily long sequences without context-length restrictions."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"StreamingLLM (Xiao et al., 2023) is an inference system that enables pretrained large language models to generate text of unbounded length without retraining, architectural changes, or context-length restrictions. It achieves this by combining two insights: (1) the attention sink phenomenon — that models reliably attend to initial tokens regardless of content — means those tokens must be kept in the KV cache permanently; and (2) a fixed sliding window of recent tokens provides sufficient local context for coherent generation. The result is a constant-memory, constant-speed inference engine that transforms any pretrained LLM into a streaming model capable of producing millions of tokens in a single session, enabling applications such as real-time transcription summarization, always-on AI assistants, and streaming code generation over entire repositories."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Standard autoregressive generation stores all past KV pairs in memory (the KV cache), which grows linearly with sequence length and eventually exhausts GPU memory. Truncating the input to a fixed context window forces the model to discard earlier content and breaks generation quality. StreamingLLM avoids both problems by implementing a SinkCache: a fixed-size KV store that always contains the first n_sink=4 tokens (the sink region) plus the most recent window_size tokens (the sliding window). Total cache size is constant at n_sink + window_size entries. When a new token is generated, its KV pair enters the window; if the window is full, the oldest window entry is evicted. Sink entries are never evicted. The model attends over this bounded cache at each step, producing stable perplexity for sequences of arbitrary length. The paper demonstrates stable generation at 4 million tokens."},{"type":"heading","level":2,"content":"System Architecture"},{"type":"text","content":"StreamingLLM is a pure inference modification — the model weights are untouched. The system inserts a SinkCache manager between the transformer\u0027s attention modules and the KV cache storage. At each generation step, the attention module calls SinkCache.add(key, value) to store the new KV pair, then calls SinkCache.get_kv() to retrieve the full bounded KV state for attention computation. The get_kv() return is a concatenation of [sink_keys; window_keys] and [sink_values; window_values] in their original causal order. Position IDs are re-indexed at each step to match the actual attended positions: sink tokens retain positions [0, 1, 2, 3]; window tokens are assigned contiguous positions [n_sink, n_sink+1, ..., n_sink+window_size-1]. This re-indexing is critical for RoPE consistency — the model must see positions that reflect the relative order of attended tokens."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom typing import Optional, Tuple\n\nclass SinkCache:\n    # StreamingLLM KV cache: permanent sink region + sliding window\n    # Enables infinite-length generation at constant memory and compute\n\n    def __init__(self, n_sink: int = 4, window_size: int = 512):\n        self.n_sink = n_sink\n        self.window_size = window_size\n        self._sink_k:  list = []\n        self._sink_v:  list = []\n        self._win_k:   list = []\n        self._win_v:   list = []\n        self.seq_len = 0\n\n    def add(self, key: torch.Tensor, value: torch.Tensor) -\u003e None:\n        # key/value: (batch, n_heads, 1, head_dim) — single new token\n        if self.seq_len \u003c self.n_sink:\n            self._sink_k.append(key)\n            self._sink_v.append(value)\n        else:\n            self._win_k.append(key)\n            self._win_v.append(value)\n            if len(self._win_k) \u003e self.window_size:\n                self._win_k.pop(0)\n                self._win_v.pop(0)\n        self.seq_len += 1\n\n    def get_kv(self) -\u003e Tuple[torch.Tensor, torch.Tensor]:\n        # Returns concatenated [sink | window] keys and values\n        all_k = torch.cat(self._sink_k + self._win_k, dim=2)\n        all_v = torch.cat(self._sink_v + self._win_v, dim=2)\n        return all_k, all_v\n\n    def get_position_ids(self) -\u003e torch.Tensor:\n        # Contiguous positions [0..n_sink-1, n_sink..cache_len-1]\n        cache_len = len(self._sink_k) + len(self._win_k)\n        return torch.arange(cache_len, dtype=torch.long)\n\n    @property\n    def cache_size(self) -\u003e int:\n        return len(self._sink_k) + len(self._win_k)"},{"type":"heading","level":2,"content":"Sink Cache Implementation"},{"type":"text","content":"The SinkCache.add() method routes incoming KV pairs based on whether the sequence length has reached the sink budget. For the first n_sink tokens, entries are appended to the permanent sink lists. From token n_sink onward, entries go into the window lists, which are pruned by evicting from the front whenever length exceeds window_size. This means the first n_sink tokens of any document are always retained, matching the attention sink structure observed in pretrained models. The SinkCache.get_kv() method concatenates sink and window lists along the sequence dimension, returning a view suitable for use as past_key_values in any HuggingFace model. The total number of KV entries returned is always at most n_sink + window_size, providing the constant-memory guarantee regardless of how many tokens have been generated."},{"type":"code","language":"python","content":"import torch\nfrom transformers import AutoTokenizer, AutoModelForCausalLM\n\ndef build_streaming_position_ids(sink_len: int, window_len: int,\n                                  new_token_pos: int) -\u003e torch.Tensor:\n    # Re-index positions so attended tokens have contiguous RoPE-compatible IDs\n    # Sink tokens: [0, 1, ..., sink_len-1] — always fixed\n    # Window tokens: [new_token_pos - window_len, ..., new_token_pos - 1]\n    sink_ids   = torch.arange(sink_len, dtype=torch.long)\n    window_start = max(sink_len, new_token_pos - window_len)\n    window_ids = torch.arange(window_start, new_token_pos, dtype=torch.long)\n    return torch.cat([sink_ids, window_ids])\n\ndef streaming_generate(model, tokenizer, prompt: str,\n                        n_sink: int = 4, window: int = 512,\n                        max_new_tokens: int = 2000) -\u003e str:\n    # Autoregressive generation using SinkCache for constant-memory streaming\n    cache = SinkCache(n_sink=n_sink, window_size=window)\n    ids = tokenizer(prompt, return_tensors=\u0027pt\u0027).input_ids.to(model.device)\n    generated = []\n    # Prefill: process all prompt tokens through the cache\n    for i in range(ids.shape[1]):\n        tok = ids[:, i:i+1]\n        pos = torch.tensor([[i]], dtype=torch.long, device=model.device)\n        with torch.no_grad():\n            out = model(tok, position_ids=pos, use_cache=True)\n        new_k, new_v = out.past_key_values[-1]\n        cache.add(new_k[:, :, -1:, :], new_v[:, :, -1:, :])\n    # Decode: generate up to max_new_tokens using the bounded cache\n    next_tok = ids[:, -1:]\n    for step in range(max_new_tokens):\n        pos_ids = build_streaming_position_ids(cache.n_sink, window, cache.seq_len)\n        pos_ids = pos_ids[-1:].unsqueeze(0).to(model.device)\n        with torch.no_grad():\n            out = model(next_tok, position_ids=pos_ids, use_cache=False)\n        next_tok = out.logits[:, -1, :].argmax(dim=-1, keepdim=True)\n        generated.append(next_tok.item())\n        if next_tok.item() == tokenizer.eos_token_id:\n            break\n    return tokenizer.decode(generated, skip_special_tokens=True)"},{"type":"heading","level":2,"content":"Sliding Window Attention"},{"type":"text","content":"The sliding window component of SinkCache provides local context coherence: each generated token can attend to the most recent window_size tokens. This window captures sentence-level and paragraph-level dependencies — typically sufficient for fluent text generation. Content from beyond the window is permanently lost to attention, which is the primary limitation of StreamingLLM compared to full long-context models. However, for many streaming applications (live transcription, real-time dialogue), only the recent context is needed and the window approach is perfectly adequate. The window size is a tunable parameter: window_size=512 uses approximately 1GB of KV cache memory for a 7B model, while window_size=2048 uses ~4GB. Larger windows provide better long-term coherence at the cost of slower attention computation (though still O(window_size) per step, not O(n))."},{"type":"code","language":"python","content":"import torch\nimport time\nfrom transformers import AutoTokenizer, AutoModelForCausalLM\n\ndef throughput_benchmark(model_name: str, n_tokens: int = 1000,\n                          window: int = 512, n_sink: int = 4) -\u003e dict:\n    # Compare tokens/sec: StreamingLLM vs standard generation with 4K truncation\n    tokenizer = AutoTokenizer.from_pretrained(model_name)\n    model = AutoModelForCausalLM.from_pretrained(\n        model_name, torch_dtype=torch.float16, device_map=\u0027auto\u0027\n    )\n    prompt = \u0027The following is a long technical discussion about machine learning: \u0027\n    ids = tokenizer(prompt, return_tensors=\u0027pt\u0027).input_ids.cuda()\n    # Benchmark 1: Standard generation (truncation at max_length=4096)\n    t0 = time.perf_counter()\n    with torch.no_grad():\n        out = model.generate(ids, max_new_tokens=n_tokens,\n                             max_length=4096, do_sample=False)\n    std_speed = n_tokens / (time.perf_counter() - t0)\n    # Benchmark 2: StreamingLLM with SinkCache\n    cache = SinkCache(n_sink=n_sink, window_size=window)\n    t0 = time.perf_counter()\n    for _ in range(n_tokens):\n        k, v = cache.get_kv() if cache.cache_size \u003e 0 else (None, None)\n        pass  # placeholder for actual streaming step\n    stream_speed = n_tokens / (time.perf_counter() - t0)\n    print(f\u0027Standard generation: {std_speed:.1f} tokens/sec\u0027)\n    print(f\u0027StreamingLLM ({window}-token window): {stream_speed:.1f} tokens/sec\u0027)\n    return {\u0027standard\u0027: std_speed, \u0027streaming\u0027: stream_speed}"},{"type":"heading","level":2,"content":"Position Re-indexing"},{"type":"text","content":"After each eviction step, the window tokens have a gap between the sink positions (0–3) and their original sequence positions. Without re-indexing, the RoPE embeddings would use the original positions, creating a large positional gap that disrupts relative position attention. StreamingLLM re-indexes positions at each step: sink tokens retain positions [0, 1, 2, 3]; window tokens are assigned positions [n_sink, n_sink+1, ..., n_sink+window_len-1] regardless of their original absolute positions. This makes the attended sequence appear contiguous from the model\u0027s perspective. The practical effect is that the model believes it is attending to a sequence of length n_sink + window_size — the sink tokens at the beginning and the recent window right after. Position re-indexing requires only a change to the position_ids tensor passed to the model; no weight modification is needed."},{"type":"code","language":"python","content":"import torch\n\ndef demo_multiturn_streaming(n_turns: int = 20, window: int = 256,\n                              n_sink: int = 4) -\u003e None:\n    # Simulate multi-turn dialogue with StreamingLLM SinkCache\n    # Each turn appends user + assistant tokens to the cache\n    cache_status = []\n    total_tokens = 0\n    for turn in range(n_turns):\n        user_tokens   = torch.randn(1, 8, 1, 64)   # simulate 8 new user tokens\n        assist_tokens = torch.randn(1, 8, 1, 64)   # simulate 8 assistant tokens\n        for tok in range(8):  # add user tokens\n            k = user_tokens[:, :, tok:tok+1, :]\n            v = user_tokens[:, :, tok:tok+1, :]\n            if total_tokens \u003c n_sink:\n                pass  # goes to sink\n            total_tokens += 1\n        for tok in range(8):  # add assistant tokens\n            total_tokens += 1\n        cache_len = min(total_tokens, n_sink + window)\n        cache_status.append({\u0027turn\u0027: turn + 1, \u0027total\u0027: total_tokens, \u0027cache\u0027: cache_len})\n    print(f\u0027{\"Turn\":\u003e5} | {\"Total Tokens\":\u003e12} | {\"Cache Size\":\u003e10}\u0027)\n    for s in cache_status[::5]:\n        print(f\u0027{s[\"turn\"]:\u003e5} | {s[\"total\"]:\u003e12} | {s[\"cache\"]:\u003e10}\u0027)\n    print(f\u0027Cache stays bounded at max {n_sink + window} regardless of total tokens\u0027)"},{"type":"table","headers":["Scenario","Context Needed","Cache Size","Approach","StreamingLLM Works?"],"rows":[["Short document Q\u0026A","\u003c window_size","\u003c 516 tokens","Standard or streaming","Yes — trivially"],["Long document summarization","Full document","Grows with doc","Full long-context model or RAG","Partial — loses earlier content"],["Streaming transcription","Recent audio only","512-2048 tokens","Sink + window","Yes — ideal use case"],["Multi-turn dialogue","Recent turns","512-2048 tokens","Sink + window","Yes — window covers recent turns"],["Infinite novel generation","Local coherence only","512-2048 tokens","Sink + window","Yes — stable indefinitely"],["Needle-in-haystack retrieval","Full document","Grows to OOM","Full long-context model","No — evicted content unattendable"]]},{"type":"heading","level":2,"content":"Throughput and Latency"},{"type":"text","content":"StreamingLLM achieves constant per-token latency because the KV cache size is bounded. In standard generation, attention computation per token grows as O(n) (linear in sequence length, quadratic total), causing generation to slow down significantly for long sequences. With a fixed cache of size n_sink + window_size = 516 entries (at default settings), each token requires a constant number of attention operations regardless of how many tokens have been generated. The paper reports that StreamingLLM maintains 95% of the single-token throughput of the base model indefinitely. Memory usage is also constant: for LLaMA-7B with 32 layers, 32 heads, head_dim=128, float16, and a 516-entry cache, total KV memory is 32 × 32 × 516 × 128 × 2 bytes ≈ 1.37 GB — a fixed budget regardless of generation duration."},{"type":"callout","variant":"tip","title":"StreamingLLM Solves Memory, Not Retrieval","content":"StreamingLLM solves the memory problem but not the retrieval problem — the model can only attend to content in its window; for true long-context retrieval, combine StreamingLLM with RAG or use a full long-context model. StreamingLLM is ideal for streaming generation where only local coherence is needed."},{"type":"heading","level":2,"content":"Limitations and Use Cases"},{"type":"text","content":"StreamingLLM has one fundamental limitation: content evicted from the window is permanently inaccessible to attention. This means the model cannot retrieve information from more than window_size tokens ago, regardless of how long the generation session is. For needle-in-haystack retrieval tasks where the answer may be anywhere in a long document, StreamingLLM will fail unless the relevant content happens to remain in the window. The appropriate use cases are those where only recent context is needed: live transcription and summarization, streaming code completion, real-time dialogue systems, and long creative writing where local style coherence suffices. For true long-context understanding tasks — legal document analysis, multi-chapter book summarization, long-form research report Q\u0026A — a full long-context model with RoPE extension or a RAG system is required."},{"type":"list","ordered":false,"items":["Memory cost is constant: (n_sink + window_size) × layers × heads × head_dim × 2 bytes, fixed for the session.","Per-token speed is constant: attention over a fixed cache of size 516 rather than a growing sequence.","Sink tokens are never evicted: the first 4 tokens of any session are permanently retained throughout generation.","Position re-indexing is required: sink tokens get positions 0-3, window tokens get positions 4 to 4+window_len-1.","No retraining needed: works with any pretrained RoPE or ALiBi model without weight modification.","Critical limitation: content evicted from the window is unattendable — combine with RAG for long-context retrieval.","Window size tuning: 512 tokens for minimal memory, 2048 for better coherence, 4096 for near-full-context quality."]},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"StreamingLLM is a practical system enabling pretrained LLMs to function as true streaming models. Its design is principled: the SinkCache is not a heuristic but a direct response to the observed attention sink structure of transformer models. By retaining 4 sink tokens plus a sliding window, StreamingLLM achieves constant memory, constant speed, and stable perplexity over arbitrarily long sequences. The approach requires no retraining, no fine-tuning, and no architectural changes — a zero-shot capability that makes it immediately applicable to any pretrained RoPE-based model including the entire LLaMA family."},{"type":"list","ordered":false,"items":["SinkCache design: keep first n_sink=4 tokens permanently + rolling window_size=512 for recent context.","Cache is bounded at n_sink + window_size entries, giving O(1) memory growth over arbitrary generation length.","Position re-index at each step: sink at [0..3], window at [4..4+win_len-1] for RoPE consistency.","Works without retraining on any pretrained RoPE model — pure inference-time modification.","Stable perplexity demonstrated at 4 million generated tokens in the original paper.","Combine with RAG for long-context retrieval tasks; StreamingLLM alone cannot retrieve evicted content.","For training-time improvement, add a dedicated \u003csink\u003e token prefix so content tokens are not repurposed as sinks."]},{"type":"divider"}]"
---
# StreamingLLM: Efficient Streaming Language Model Inference

StreamingLLM (Xiao et al., 2023) is an inference system that enables pretrained large language models to generate text of unbounded length without retraining, architectural changes, or context-length restrictions. It achieves this by combining two insights: (1) the attention sink phenomenon — that models reliably attend to initial tokens regardless of content — means those tokens must be kept in the KV cache permanently; and (2) a fixed sliding window of recent tokens provides sufficient local context for coherent generation. The result is a constant-memory, constant-speed inference engine that transforms any pretrained LLM into a streaming model capable of producing millions of tokens in a single session, enabling applications such as real-time transcription summarization, always-on AI assistants, and streaming code generation over entire repositories.

## Overview

Standard autoregressive generation stores all past KV pairs in memory (the KV cache), which grows linearly with sequence length and eventually exhausts GPU memory. Truncating the input to a fixed context window forces the model to discard earlier content and breaks generation quality. StreamingLLM avoids both problems by implementing a SinkCache: a fixed-size KV store that always contains the first n_sink=4 tokens (the sink region) plus the most recent window_size tokens (the sliding window). Total cache size is constant at n_sink + window_size entries. When a new token is generated, its KV pair enters the window; if the window is full, the oldest window entry is evicted. Sink entries are never evicted. The model attends over this bounded cache at each step, producing stable perplexity for sequences of arbitrary length. The paper demonstrates stable generation at 4 million tokens.

## System Architecture

StreamingLLM is a pure inference modification — the model weights are untouched. The system inserts a SinkCache manager between the transformer's attention modules and the KV cache storage. At each generation step, the attention module calls SinkCache.add(key, value) to store the new KV pair, then calls SinkCache.get_kv() to retrieve the full bounded KV state for attention computation. The get_kv() return is a concatenation of [sink_keys; window_keys] and [sink_values; window_values] in their original causal order. Position IDs are re-indexed at each step to match the actual attended positions: sink tokens retain positions [0, 1, 2, 3]; window tokens are assigned contiguous positions [n_sink, n_sink+1, ..., n_sink+window_size-1]. This re-indexing is critical for RoPE consistency — the model must see positions that reflect the relative order of attended tokens.

```python
import torch
import torch.nn as nn
from typing import Optional, Tuple

class SinkCache:
    # StreamingLLM KV cache: permanent sink region + sliding window
    # Enables infinite-length generation at constant memory and compute

    def __init__(self, n_sink: int = 4, window_size: int = 512):
        self.n_sink = n_sink
        self.window_size = window_size
        self._sink_k:  list = []
        self._sink_v:  list = []
        self._win_k:   list = []
        self._win_v:   list = []
        self.seq_len = 0

    def add(self, key: torch.Tensor, value: torch.Tensor) -> None:
        # key/value: (batch, n_heads, 1, head_dim) — single new token
        if self.seq_len < self.n_sink:
            self._sink_k.append(key)
            self._sink_v.append(value)
        else:
            self._win_k.append(key)
            self._win_v.append(value)
            if len(self._win_k) > self.window_size:
                self._win_k.pop(0)
                self._win_v.pop(0)
        self.seq_len += 1

    def get_kv(self) -> Tuple[torch.Tensor, torch.Tensor]:
        # Returns concatenated [sink | window] keys and values
        all_k = torch.cat(self._sink_k + self._win_k, dim=2)
        all_v = torch.cat(self._sink_v + self._win_v, dim=2)
        return all_k, all_v

    def get_position_ids(self) -> torch.Tensor:
        # Contiguous positions [0..n_sink-1, n_sink..cache_len-1]
        cache_len = len(self._sink_k) + len(self._win_k)
        return torch.arange(cache_len, dtype=torch.long)

    @property
    def cache_size(self) -> int:
        return len(self._sink_k) + len(self._win_k)
```

## Sink Cache Implementation

The SinkCache.add() method routes incoming KV pairs based on whether the sequence length has reached the sink budget. For the first n_sink tokens, entries are appended to the permanent sink lists. From token n_sink onward, entries go into the window lists, which are pruned by evicting from the front whenever length exceeds window_size. This means the first n_sink tokens of any document are always retained, matching the attention sink structure observed in pretrained models. The SinkCache.get_kv() method concatenates sink and window lists along the sequence dimension, returning a view suitable for use as past_key_values in any HuggingFace model. The total number of KV entries returned is always at most n_sink + window_size, providing the constant-memory guarantee regardless of how many tokens have been generated.

```python
import torch
from transformers import AutoTokenizer, AutoModelForCausalLM

def build_streaming_position_ids(sink_len: int, window_len: int,
                                  new_token_pos: int) -> torch.Tensor:
    # Re-index positions so attended tokens have contiguous RoPE-compatible IDs
    # Sink tokens: [0, 1, ..., sink_len-1] — always fixed
    # Window tokens: [new_token_pos - window_len, ..., new_token_pos - 1]
    sink_ids   = torch.arange(sink_len, dtype=torch.long)
    window_start = max(sink_len, new_token_pos - window_len)
    window_ids = torch.arange(window_start, new_token_pos, dtype=torch.long)
    return torch.cat([sink_ids, window_ids])

def streaming_generate(model, tokenizer, prompt: str,
                        n_sink: int = 4, window: int = 512,
                        max_new_tokens: int = 2000) -> str:
    # Autoregressive generation using SinkCache for constant-memory streaming
    cache = SinkCache(n_sink=n_sink, window_size=window)
    ids = tokenizer(prompt, return_tensors='pt').input_ids.to(model.device)
    generated = []
    # Prefill: process all prompt tokens through the cache
    for i in range(ids.shape[1]):
        tok = ids[:, i:i+1]
        pos = torch.tensor([[i]], dtype=torch.long, device=model.device)
        with torch.no_grad():
            out = model(tok, position_ids=pos, use_cache=True)
        new_k, new_v = out.past_key_values[-1]
        cache.add(new_k[:, :, -1:, :], new_v[:, :, -1:, :])
    # Decode: generate up to max_new_tokens using the bounded cache
    next_tok = ids[:, -1:]
    for step in range(max_new_tokens):
        pos_ids = build_streaming_position_ids(cache.n_sink, window, cache.seq_len)
        pos_ids = pos_ids[-1:].unsqueeze(0).to(model.device)
        with torch.no_grad():
            out = model(next_tok, position_ids=pos_ids, use_cache=False)
        next_tok = out.logits[:, -1, :].argmax(dim=-1, keepdim=True)
        generated.append(next_tok.item())
        if next_tok.item() == tokenizer.eos_token_id:
            break
    return tokenizer.decode(generated, skip_special_tokens=True)
```

## Sliding Window Attention

The sliding window component of SinkCache provides local context coherence: each generated token can attend to the most recent window_size tokens. This window captures sentence-level and paragraph-level dependencies — typically sufficient for fluent text generation. Content from beyond the window is permanently lost to attention, which is the primary limitation of StreamingLLM compared to full long-context models. However, for many streaming applications (live transcription, real-time dialogue), only the recent context is needed and the window approach is perfectly adequate. The window size is a tunable parameter: window_size=512 uses approximately 1GB of KV cache memory for a 7B model, while window_size=2048 uses ~4GB. Larger windows provide better long-term coherence at the cost of slower attention computation (though still O(window_size) per step, not O(n)).

```python
import torch
import time
from transformers import AutoTokenizer, AutoModelForCausalLM

def throughput_benchmark(model_name: str, n_tokens: int = 1000,
                          window: int = 512, n_sink: int = 4) -> dict:
    # Compare tokens/sec: StreamingLLM vs standard generation with 4K truncation
    tokenizer = AutoTokenizer.from_pretrained(model_name)
    model = AutoModelForCausalLM.from_pretrained(
        model_name, torch_dtype=torch.float16, device_map='auto'
    )
    prompt = 'The following is a long technical discussion about machine learning: '
    ids = tokenizer(prompt, return_tensors='pt').input_ids.cuda()
    # Benchmark 1: Standard generation (truncation at max_length=4096)
    t0 = time.perf_counter()
    with torch.no_grad():
        out = model.generate(ids, max_new_tokens=n_tokens,
                             max_length=4096, do_sample=False)
    std_speed = n_tokens / (time.perf_counter() - t0)
    # Benchmark 2: StreamingLLM with SinkCache
    cache = SinkCache(n_sink=n_sink, window_size=window)
    t0 = time.perf_counter()
    for _ in range(n_tokens):
        k, v = cache.get_kv() if cache.cache_size > 0 else (None, None)
        pass  # placeholder for actual streaming step
    stream_speed = n_tokens / (time.perf_counter() - t0)
    print(f'Standard generation: {std_speed:.1f} tokens/sec')
    print(f'StreamingLLM ({window}-token window): {stream_speed:.1f} tokens/sec')
    return {'standard': std_speed, 'streaming': stream_speed}
```

## Position Re-indexing

After each eviction step, the window tokens have a gap between the sink positions (0–3) and their original sequence positions. Without re-indexing, the RoPE embeddings would use the original positions, creating a large positional gap that disrupts relative position attention. StreamingLLM re-indexes positions at each step: sink tokens retain positions [0, 1, 2, 3]; window tokens are assigned positions [n_sink, n_sink+1, ..., n_sink+window_len-1] regardless of their original absolute positions. This makes the attended sequence appear contiguous from the model's perspective. The practical effect is that the model believes it is attending to a sequence of length n_sink + window_size — the sink tokens at the beginning and the recent window right after. Position re-indexing requires only a change to the position_ids tensor passed to the model; no weight modification is needed.

```python
import torch

def demo_multiturn_streaming(n_turns: int = 20, window: int = 256,
                              n_sink: int = 4) -> None:
    # Simulate multi-turn dialogue with StreamingLLM SinkCache
    # Each turn appends user + assistant tokens to the cache
    cache_status = []
    total_tokens = 0
    for turn in range(n_turns):
        user_tokens   = torch.randn(1, 8, 1, 64)   # simulate 8 new user tokens
        assist_tokens = torch.randn(1, 8, 1, 64)   # simulate 8 assistant tokens
        for tok in range(8):  # add user tokens
            k = user_tokens[:, :, tok:tok+1, :]
            v = user_tokens[:, :, tok:tok+1, :]
            if total_tokens < n_sink:
                pass  # goes to sink
            total_tokens += 1
        for tok in range(8):  # add assistant tokens
            total_tokens += 1
        cache_len = min(total_tokens, n_sink + window)
        cache_status.append({'turn': turn + 1, 'total': total_tokens, 'cache': cache_len})
    print(f'{"Turn":>5} | {"Total Tokens":>12} | {"Cache Size":>10}')
    for s in cache_status[::5]:
        print(f'{s["turn"]:>5} | {s["total"]:>12} | {s["cache"]:>10}')
    print(f'Cache stays bounded at max {n_sink + window} regardless of total tokens')
```

| Scenario | Context Needed | Cache Size | Approach | StreamingLLM Works? |
| --- | --- | --- | --- | --- |
| Short document Q&A | < window_size | < 516 tokens | Standard or streaming | Yes — trivially |
| Long document summarization | Full document | Grows with doc | Full long-context model or RAG | Partial — loses earlier content |
| Streaming transcription | Recent audio only | 512-2048 tokens | Sink + window | Yes — ideal use case |
| Multi-turn dialogue | Recent turns | 512-2048 tokens | Sink + window | Yes — window covers recent turns |
| Infinite novel generation | Local coherence only | 512-2048 tokens | Sink + window | Yes — stable indefinitely |
| Needle-in-haystack retrieval | Full document | Grows to OOM | Full long-context model | No — evicted content unattendable |

## Throughput and Latency

StreamingLLM achieves constant per-token latency because the KV cache size is bounded. In standard generation, attention computation per token grows as O(n) (linear in sequence length, quadratic total), causing generation to slow down significantly for long sequences. With a fixed cache of size n_sink + window_size = 516 entries (at default settings), each token requires a constant number of attention operations regardless of how many tokens have been generated. The paper reports that StreamingLLM maintains 95% of the single-token throughput of the base model indefinitely. Memory usage is also constant: for LLaMA-7B with 32 layers, 32 heads, head_dim=128, float16, and a 516-entry cache, total KV memory is 32 × 32 × 516 × 128 × 2 bytes ≈ 1.37 GB — a fixed budget regardless of generation duration.

> **StreamingLLM Solves Memory, Not Retrieval**: StreamingLLM solves the memory problem but not the retrieval problem — the model can only attend to content in its window; for true long-context retrieval, combine StreamingLLM with RAG or use a full long-context model. StreamingLLM is ideal for streaming generation where only local coherence is needed.

## Limitations and Use Cases

StreamingLLM has one fundamental limitation: content evicted from the window is permanently inaccessible to attention. This means the model cannot retrieve information from more than window_size tokens ago, regardless of how long the generation session is. For needle-in-haystack retrieval tasks where the answer may be anywhere in a long document, StreamingLLM will fail unless the relevant content happens to remain in the window. The appropriate use cases are those where only recent context is needed: live transcription and summarization, streaming code completion, real-time dialogue systems, and long creative writing where local style coherence suffices. For true long-context understanding tasks — legal document analysis, multi-chapter book summarization, long-form research report Q&A — a full long-context model with RoPE extension or a RAG system is required.

- Memory cost is constant: (n_sink + window_size) × layers × heads × head_dim × 2 bytes, fixed for the session.
- Per-token speed is constant: attention over a fixed cache of size 516 rather than a growing sequence.
- Sink tokens are never evicted: the first 4 tokens of any session are permanently retained throughout generation.
- Position re-indexing is required: sink tokens get positions 0-3, window tokens get positions 4 to 4+window_len-1.
- No retraining needed: works with any pretrained RoPE or ALiBi model without weight modification.
- Critical limitation: content evicted from the window is unattendable — combine with RAG for long-context retrieval.
- Window size tuning: 512 tokens for minimal memory, 2048 for better coherence, 4096 for near-full-context quality.

## Key Takeaways

StreamingLLM is a practical system enabling pretrained LLMs to function as true streaming models. Its design is principled: the SinkCache is not a heuristic but a direct response to the observed attention sink structure of transformer models. By retaining 4 sink tokens plus a sliding window, StreamingLLM achieves constant memory, constant speed, and stable perplexity over arbitrarily long sequences. The approach requires no retraining, no fine-tuning, and no architectural changes — a zero-shot capability that makes it immediately applicable to any pretrained RoPE-based model including the entire LLaMA family.

- SinkCache design: keep first n_sink=4 tokens permanently + rolling window_size=512 for recent context.
- Cache is bounded at n_sink + window_size entries, giving O(1) memory growth over arbitrary generation length.
- Position re-index at each step: sink at [0..3], window at [4..4+win_len-1] for RoPE consistency.
- Works without retraining on any pretrained RoPE model — pure inference-time modification.
- Stable perplexity demonstrated at 4 million generated tokens in the original paper.
- Combine with RAG for long-context retrieval tasks; StreamingLLM alone cannot retrieve evicted content.
- For training-time improvement, add a dedicated <sink> token prefix so content tokens are not repurposed as sinks.

---

