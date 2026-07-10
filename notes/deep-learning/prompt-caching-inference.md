---
title: "Prompt Caching in LLM Inference"
slug: "prompt-caching-inference"
description: "Reusing KV cache computations for shared prompt prefixes across requests to eliminate redundant prefill computation for system prompts, RAG context, or repeated preambles."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Prompt caching (also called prefix caching or KV cache reuse) is a server-side inference optimization that stores the key-value (KV) tensors computed during the prefill phase for a prompt prefix and reuses them across subsequent requests that share the same prefix. Without caching, every request — even if it shares a 2000-token system prompt with the previous one — recomputes all 2000 tokens from scratch. With caching, the server detects the shared prefix, loads its precomputed KV tensors from memory, and runs prefill only on the unique suffix. This eliminates O(L_shared * N_layers) transformer operations per request, where L_shared is the shared prefix length and N_layers is the number of transformer layers."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"KV cache memory layout: during a forward pass for a sequence of T tokens, each transformer layer l produces key matrix K_l ∈ ℝ^(T×d_k) and value matrix V_l ∈ ℝ^(T×d_v). These tensors are required by subsequent layers for attention computation. Standard autoregressive decoding caches KV tensors for previously generated tokens (the decode-phase KV cache) to avoid recomputing them each step. Prefix caching extends this idea to the prefill phase: KV tensors for the prompt prefix are stored after the first request and reloaded for subsequent requests. The memory cost of storing a prefix cache is 2 × T_prefix × N_layers × d_k × bytes_per_element. For a 7B model with 32 layers, d_k=128, and T_prefix=2000 tokens in float16: 2 × 2000 × 32 × 128 × 2 bytes = 32 MB — modest relative to the 14 GB model weights."},{"type":"heading","level":2,"content":"Prefix Caching Mechanics"},{"type":"text","content":"The mechanics of prefix caching require three components: (1) a cache store mapping token sequence hashes to KV tensors, (2) a prefix matching algorithm that finds the longest cached prefix of any incoming request, and (3) eviction logic to manage GPU memory when the cache fills. The cache key is typically the hash of the token ID sequence for the prefix. On a new request, the inference server hashes prefixes of increasing length and looks up the longest match. Computation then proceeds only for the uncached suffix. The boundary between cached and uncached tokens must align with a block boundary (typically 16 or 32 tokens) for memory management efficiency. Partial-block caching (handling prefixes that end mid-block) requires additional bookkeeping."},{"type":"code","language":"python","content":"import torch\nimport hashlib\nfrom typing import Optional, Dict, List, Tuple\nfrom dataclasses import dataclass, field\n\n@dataclass\nclass TrieNode:\n    children: Dict[int, \"TrieNode\"] = field(default_factory=dict)\n    kv_cache: Optional[torch.Tensor] = None\n\nclass RadixPrefixCache:\n    \"\"\"Trie-based KV prefix cache. Finds the longest cached prefix for any request.\"\"\"\n    def __init__(self):\n        self.root = TrieNode()\n        self.hits = 0\n        self.misses = 0\n\n    def find_prefix(self, tokens: List[int]) -\u003e Tuple[int, Optional[torch.Tensor]]:\n        \"\"\"Return (matched_length, kv_tensors) for the longest cached prefix.\"\"\"\n        node = self.root\n        matched, last_kv = 0, None\n        for tok in tokens:\n            if tok not in node.children:\n                self.misses += 1\n                break\n            node = node.children[tok]\n            matched += 1\n            last_kv = node.kv_cache\n        if matched \u003e 0:\n            self.hits += 1\n        return matched, last_kv\n\n    def store(self, tokens: List[int], kv: torch.Tensor) -\u003e None:\n        \"\"\"Insert a token sequence and its KV tensors into the trie.\"\"\"\n        node = self.root\n        for tok in tokens:\n            if tok not in node.children:\n                node.children[tok] = TrieNode()\n            node = node.children[tok]\n        node.kv_cache = kv\n\n    def hit_rate(self) -\u003e float:\n        total = self.hits + self.misses\n        return self.hits / total if total \u003e 0 else 0.0\n\n# Demo: two requests sharing a system prompt prefix\ncache = RadixPrefixCache()\nsystem_tokens = list(range(500))  # 500-token system prompt\ncache.store(system_tokens, torch.zeros(1, 500, 32, 128))  # fake KV\nrequest_tokens = system_tokens + [601, 702, 803]          # system + user query\nmatched, kv = cache.find_prefix(request_tokens)\nprint(f\"Prefix matched: {matched} tokens  KV reused: {kv is not None}\")\nprint(f\"Cache hit rate: {cache.hit_rate():.2%}\")"},{"type":"heading","level":2,"content":"Radix Attention Tree"},{"type":"text","content":"SGLang\u0027s RadixAttention (Zheng et al., 2023) generalizes prefix caching to a radix tree (compressed trie) that stores KV caches for arbitrary subtrees of request sequences, not just linear prefixes. This handles multi-turn conversations where each turn shares a growing prefix with previous turns, as well as tree-structured generation (e.g., beam search or parallel chain-of-thought sampling) where multiple continuations branch from the same root. The radix tree maintains a least-recently-used (LRU) eviction policy at the node level: when GPU memory runs low, the server evicts the deepest, least-recently-accessed nodes first, preserving the most frequently shared roots. RadixAttention achieves cache hit rates of 85–95% for chatbot workloads with shared system prompts, compared to 30–50% for hash-based linear prefix caches."},{"type":"heading","level":2,"content":"Cache Hit Rate Optimization"},{"type":"text","content":"Cache hit rate depends critically on request ordering and prompt structure. If requests with identical system prompts arrive interleaved with requests using different system prompts, cached KV tensors may be evicted before they can be reused. Batching requests by shared prefix maximizes hit rate: sort incoming requests so that requests sharing a prefix are processed consecutively. At the prompt level, content ordering matters: the shared prefix must be identical at the byte level — even whitespace differences invalidate the hash match. Placing all stable content (system instructions, RAG documents, few-shot examples) before dynamic content (user query, session ID) ensures the longest possible cached prefix. Anthropic\u0027s prompt caching API formalizes this: the developer explicitly marks stable blocks with cache_control, and the API guarantees caching for those blocks."},{"type":"code","language":"python","content":"import time\nfrom vllm import LLM, SamplingParams\n\ndef benchmark_vllm_prefix_cache(\n    model_name: str = \"mistralai/Mistral-7B-v0.1\",\n    n_requests: int = 50\n) -\u003e float:\n    \"\"\"Compare prefill time with and without prefix caching in vLLM.\"\"\"\n    system_prompt = (\n        \"You are a world-class AI assistant with deep expertise in mathematics, \"\n        \"physics, and computer science. Always reason step by step and show your work. \"\n        \"Provide rigorous proofs and numerical examples where relevant. \"\n    ) * 25  # approx 600-token shared system prompt\n    user_queries = [f\"Explain Fourier transform application #{i}.\" for i in range(n_requests)]\n    prompts = [system_prompt + \" User: \" + q + \" Assistant:\" for q in user_queries]\n    params = SamplingParams(temperature=0.0, max_tokens=64)\n    # Without prefix caching\n    llm_no = LLM(model=model_name, enable_prefix_caching=False, gpu_memory_utilization=0.8)\n    t0 = time.perf_counter()\n    out_no = llm_no.generate(prompts, params)\n    t_no = time.perf_counter() - t0\n    del llm_no\n    # With prefix caching enabled\n    llm_yes = LLM(model=model_name, enable_prefix_caching=True, gpu_memory_utilization=0.8)\n    t0 = time.perf_counter()\n    out_yes = llm_yes.generate(prompts, params)\n    t_yes = time.perf_counter() - t0\n    del llm_yes\n    print(f\"No cache:   {t_no:.2f}s for {n_requests} requests\")\n    print(f\"With cache: {t_yes:.2f}s for {n_requests} requests\")\n    print(f\"Prefill speedup: {t_no / t_yes:.2f}x\")\n    # Verify identical outputs\n    for a, b in zip(out_no, out_yes):\n        assert a.outputs[0].text == b.outputs[0].text\n    return t_no / t_yes"},{"type":"heading","level":2,"content":"Anthropic and OpenAI Prompt Caching APIs"},{"type":"text","content":"Both Anthropic and OpenAI expose prompt caching through their APIs, allowing developers to mark specific content blocks as cacheable. Anthropic\u0027s implementation uses cache_control: {type: ephemeral} on message content blocks; cached blocks are stored for 5 minutes by default. Usage statistics in the response indicate cache_creation_input_tokens (tokens written to cache on a miss) and cache_read_input_tokens (tokens served from cache on a hit). Cache reads are priced at roughly 10% of normal input token cost, making heavy system prompts (4K–32K tokens) extremely economical when reused across many turns. OpenAI\u0027s implementation is automatic for prompts sharing a common prefix of at least 1024 tokens, with no explicit cache_control markers required. Both APIs guarantee that cached computation does not affect output quality — the same guarantees as server-side prefix caching."},{"type":"code","language":"python","content":"import anthropic\nimport time\n\ndef demo_anthropic_prompt_cache(doc_text: str) -\u003e dict:\n    \"\"\"Show Anthropic prompt caching: mark stable content with cache_control.\"\"\"\n    client = anthropic.Anthropic()\n    messages_cached = [{\"role\": \"user\", \"content\": [\n        {\"type\": \"text\", \"text\": doc_text,\n         \"cache_control\": {\"type\": \"ephemeral\"}},\n        {\"type\": \"text\", \"text\": \"Summarize the key findings in 3 bullet points.\"}\n    ]}]\n    messages_no_cache = [{\"role\": \"user\", \"content\": doc_text +\n                          \" Summarize the key findings in 3 bullet points.\"}]\n    # First call: cold cache miss — full prefill billed at standard rate\n    t0 = time.perf_counter()\n    r1 = client.messages.create(model=\"claude-opus-4-5\", max_tokens=256,\n                                 messages=messages_cached)\n    t1 = time.perf_counter() - t0\n    # Second call: cache hit — only new tokens billed\n    t0 = time.perf_counter()\n    r2 = client.messages.create(model=\"claude-opus-4-5\", max_tokens=256,\n                                 messages=messages_cached)\n    t2 = time.perf_counter() - t0\n    print(f\"Call 1 — created: {r1.usage.cache_creation_input_tokens} cache tokens, read: {r1.usage.cache_read_input_tokens}, time: {t1:.2f}s\")\n    print(f\"Call 2 — created: {r2.usage.cache_creation_input_tokens} cache tokens, read: {r2.usage.cache_read_input_tokens}, time: {t2:.2f}s\")\n    print(f\"Latency reduction: {(t1 - t2) / t1 * 100:.1f}%\")\n    return {\"cold_time\": t1, \"warm_time\": t2, \"speedup\": t1 / t2}"},{"type":"heading","level":2,"content":"On-device Prefix Caching"},{"type":"text","content":"On-device inference (e.g., mobile or edge deployments using llama.cpp or MLC-LLM) can also benefit from prefix caching when the same system prompt or context is reused across multiple user sessions. llama.cpp\u0027s session file feature saves and loads the KV cache state for a given prompt prefix to/from disk, allowing the next inference session to skip prefill entirely for the cached portion. The challenge on device is memory: a 4-bit quantized 7B model\u0027s KV cache for 2000 tokens is approximately 16 MB, which is feasible on devices with 8+ GB RAM. The cache must be invalidated when the model weights change (e.g., after an app update). For conversational assistants where the system prompt is fixed and the user query is always appended at the end, disk-based KV cache persistence can eliminate system prompt prefill latency entirely on the second and subsequent turns."},{"type":"code","language":"python","content":"import hashlib\nfrom typing import List, Tuple\nfrom collections import defaultdict\n\ndef optimize_request_ordering(\n    prompts: List[str],\n    prefix_lengths: List[int] = [64, 128, 256, 512]\n) -\u003e Tuple[List[str], float]:\n    \"\"\"Sort prompts to maximize prefix cache hits (group by shared prefixes first).\"\"\"\n    def prefix_key(text: str, length: int) -\u003e str:\n        return hashlib.sha256(text[:length].encode()).hexdigest() if len(text) \u003e= length else \"\"\n    # Score each prompt by how many others share its prefixes\n    freq: defaultdict = defaultdict(int)\n    for p in prompts:\n        for L in prefix_lengths:\n            k = prefix_key(p, L)\n            if k:\n                freq[k] += 1\n    def score(p: str) -\u003e int:\n        return sum(freq[prefix_key(p, L)] for L in prefix_lengths if len(p) \u003e= L)\n    sorted_prompts = sorted(prompts, key=score, reverse=True)\n    # Estimate cache hit rate after sorting\n    seen_prefixes: set = set()\n    hits = 0\n    for p in sorted_prompts:\n        k = prefix_key(p, prefix_lengths[-1])\n        if k in seen_prefixes:\n            hits += 1\n        seen_prefixes.add(k)\n    hit_rate = hits / len(prompts) if prompts else 0.0\n    print(f\"Estimated cache hit rate after ordering: {hit_rate:.2%}\")\n    return sorted_prompts, hit_rate"},{"type":"heading","level":2,"content":"Cost Savings Analysis"},{"type":"text","content":"The economic impact of prompt caching is largest for workloads with long, shared prefixes and many requests. A RAG application with a fixed 8000-token knowledge base prefix sent with every query, serving 100,000 daily requests, would without caching pay for 8000 × 100,000 = 800M input tokens per day. With 90% cache hit rate, only 80M tokens need full prefill computation, with the remaining 720M served from cache at 10% of normal cost. The effective input token cost drops to 10% × 720M + 100% × 80M = 152M equivalent tokens — an 81% reduction in input-side compute costs. The savings are proportional to prefix length, request volume, and cache hit rate. Short prefixes or low request rates may not justify the engineering overhead of implementing prefix caching."},{"type":"table","headers":["Scenario","Prefix Length (tokens)","Cache Hit Rate","Prefill Savings","Effective Cost Reduction"],"rows":[["Shared system prompt (short)","200","90%","90% of prefix prefill skipped","45–60%"],["RAG with fixed document set","4000–8000","85%","85% of prefix prefill skipped","70–80%"],["Code context window","2000–4000","70%","70% of prefix prefill skipped","55–65%"],["Multi-turn conversational history","500–2000 (growing)","60%","60% of history prefill skipped","40–55%"],["Mixed workload (varied prefixes)","1000 avg","40%","40% of prefix prefill skipped","25–35%"]]},{"type":"callout","variant":"tip","title":"Structure Prompts for Maximum Cache Reuse","content":"Put your longest, most reused content at the beginning of the prompt (system instructions, RAG context, examples) and dynamic content at the end — prefix caches only match from the start of the sequence. Even a single character difference at position 1 invalidates the entire cache match for that request."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["Prefix caching stores KV tensors for shared prompt prefixes and reuses them across requests — eliminating redundant prefill computation entirely for cached tokens.","A trie (radix tree) structure enables efficient longest-prefix matching: each node stores KV tensors for a token sequence prefix, with LRU eviction for memory management.","vLLM enables prefix caching with a single flag: LLM(enable_prefix_caching=True); no other code changes are required.","Anthropic and OpenAI APIs expose prompt caching explicitly — mark stable content blocks with cache_control; cached tokens cost ~10% of normal input token price.","For maximum hit rate, always place stable content (system prompt, RAG context) before dynamic content (user query) in your prompt structure.","On-device inference can persist KV caches to disk between sessions using session files (llama.cpp) to skip system prompt prefill on warm starts.","Cache hit rate of 80–90% is achievable for chatbot workloads with a fixed system prompt; RAG with a fixed document set can achieve 85–95%."]},{"type":"divider"}]"
---
# Prompt Caching in LLM Inference

Prompt caching (also called prefix caching or KV cache reuse) is a server-side inference optimization that stores the key-value (KV) tensors computed during the prefill phase for a prompt prefix and reuses them across subsequent requests that share the same prefix. Without caching, every request — even if it shares a 2000-token system prompt with the previous one — recomputes all 2000 tokens from scratch. With caching, the server detects the shared prefix, loads its precomputed KV tensors from memory, and runs prefill only on the unique suffix. This eliminates O(L_shared * N_layers) transformer operations per request, where L_shared is the shared prefix length and N_layers is the number of transformer layers.

## Overview

KV cache memory layout: during a forward pass for a sequence of T tokens, each transformer layer l produces key matrix K_l ∈ ℝ^(T×d_k) and value matrix V_l ∈ ℝ^(T×d_v). These tensors are required by subsequent layers for attention computation. Standard autoregressive decoding caches KV tensors for previously generated tokens (the decode-phase KV cache) to avoid recomputing them each step. Prefix caching extends this idea to the prefill phase: KV tensors for the prompt prefix are stored after the first request and reloaded for subsequent requests. The memory cost of storing a prefix cache is 2 × T_prefix × N_layers × d_k × bytes_per_element. For a 7B model with 32 layers, d_k=128, and T_prefix=2000 tokens in float16: 2 × 2000 × 32 × 128 × 2 bytes = 32 MB — modest relative to the 14 GB model weights.

## Prefix Caching Mechanics

The mechanics of prefix caching require three components: (1) a cache store mapping token sequence hashes to KV tensors, (2) a prefix matching algorithm that finds the longest cached prefix of any incoming request, and (3) eviction logic to manage GPU memory when the cache fills. The cache key is typically the hash of the token ID sequence for the prefix. On a new request, the inference server hashes prefixes of increasing length and looks up the longest match. Computation then proceeds only for the uncached suffix. The boundary between cached and uncached tokens must align with a block boundary (typically 16 or 32 tokens) for memory management efficiency. Partial-block caching (handling prefixes that end mid-block) requires additional bookkeeping.

```python
import torch
import hashlib
from typing import Optional, Dict, List, Tuple
from dataclasses import dataclass, field

@dataclass
class TrieNode:
    children: Dict[int, "TrieNode"] = field(default_factory=dict)
    kv_cache: Optional[torch.Tensor] = None

class RadixPrefixCache:
    """Trie-based KV prefix cache. Finds the longest cached prefix for any request."""
    def __init__(self):
        self.root = TrieNode()
        self.hits = 0
        self.misses = 0

    def find_prefix(self, tokens: List[int]) -> Tuple[int, Optional[torch.Tensor]]:
        """Return (matched_length, kv_tensors) for the longest cached prefix."""
        node = self.root
        matched, last_kv = 0, None
        for tok in tokens:
            if tok not in node.children:
                self.misses += 1
                break
            node = node.children[tok]
            matched += 1
            last_kv = node.kv_cache
        if matched > 0:
            self.hits += 1
        return matched, last_kv

    def store(self, tokens: List[int], kv: torch.Tensor) -> None:
        """Insert a token sequence and its KV tensors into the trie."""
        node = self.root
        for tok in tokens:
            if tok not in node.children:
                node.children[tok] = TrieNode()
            node = node.children[tok]
        node.kv_cache = kv

    def hit_rate(self) -> float:
        total = self.hits + self.misses
        return self.hits / total if total > 0 else 0.0

# Demo: two requests sharing a system prompt prefix
cache = RadixPrefixCache()
system_tokens = list(range(500))  # 500-token system prompt
cache.store(system_tokens, torch.zeros(1, 500, 32, 128))  # fake KV
request_tokens = system_tokens + [601, 702, 803]          # system + user query
matched, kv = cache.find_prefix(request_tokens)
print(f"Prefix matched: {matched} tokens  KV reused: {kv is not None}")
print(f"Cache hit rate: {cache.hit_rate():.2%}")
```

## Radix Attention Tree

SGLang's RadixAttention (Zheng et al., 2023) generalizes prefix caching to a radix tree (compressed trie) that stores KV caches for arbitrary subtrees of request sequences, not just linear prefixes. This handles multi-turn conversations where each turn shares a growing prefix with previous turns, as well as tree-structured generation (e.g., beam search or parallel chain-of-thought sampling) where multiple continuations branch from the same root. The radix tree maintains a least-recently-used (LRU) eviction policy at the node level: when GPU memory runs low, the server evicts the deepest, least-recently-accessed nodes first, preserving the most frequently shared roots. RadixAttention achieves cache hit rates of 85–95% for chatbot workloads with shared system prompts, compared to 30–50% for hash-based linear prefix caches.

## Cache Hit Rate Optimization

Cache hit rate depends critically on request ordering and prompt structure. If requests with identical system prompts arrive interleaved with requests using different system prompts, cached KV tensors may be evicted before they can be reused. Batching requests by shared prefix maximizes hit rate: sort incoming requests so that requests sharing a prefix are processed consecutively. At the prompt level, content ordering matters: the shared prefix must be identical at the byte level — even whitespace differences invalidate the hash match. Placing all stable content (system instructions, RAG documents, few-shot examples) before dynamic content (user query, session ID) ensures the longest possible cached prefix. Anthropic's prompt caching API formalizes this: the developer explicitly marks stable blocks with cache_control, and the API guarantees caching for those blocks.

```python
import time
from vllm import LLM, SamplingParams

def benchmark_vllm_prefix_cache(
    model_name: str = "mistralai/Mistral-7B-v0.1",
    n_requests: int = 50
) -> float:
    """Compare prefill time with and without prefix caching in vLLM."""
    system_prompt = (
        "You are a world-class AI assistant with deep expertise in mathematics, "
        "physics, and computer science. Always reason step by step and show your work. "
        "Provide rigorous proofs and numerical examples where relevant. "
    ) * 25  # approx 600-token shared system prompt
    user_queries = [f"Explain Fourier transform application #{i}." for i in range(n_requests)]
    prompts = [system_prompt + " User: " + q + " Assistant:" for q in user_queries]
    params = SamplingParams(temperature=0.0, max_tokens=64)
    # Without prefix caching
    llm_no = LLM(model=model_name, enable_prefix_caching=False, gpu_memory_utilization=0.8)
    t0 = time.perf_counter()
    out_no = llm_no.generate(prompts, params)
    t_no = time.perf_counter() - t0
    del llm_no
    # With prefix caching enabled
    llm_yes = LLM(model=model_name, enable_prefix_caching=True, gpu_memory_utilization=0.8)
    t0 = time.perf_counter()
    out_yes = llm_yes.generate(prompts, params)
    t_yes = time.perf_counter() - t0
    del llm_yes
    print(f"No cache:   {t_no:.2f}s for {n_requests} requests")
    print(f"With cache: {t_yes:.2f}s for {n_requests} requests")
    print(f"Prefill speedup: {t_no / t_yes:.2f}x")
    # Verify identical outputs
    for a, b in zip(out_no, out_yes):
        assert a.outputs[0].text == b.outputs[0].text
    return t_no / t_yes
```

## Anthropic and OpenAI Prompt Caching APIs

Both Anthropic and OpenAI expose prompt caching through their APIs, allowing developers to mark specific content blocks as cacheable. Anthropic's implementation uses cache_control: {type: ephemeral} on message content blocks; cached blocks are stored for 5 minutes by default. Usage statistics in the response indicate cache_creation_input_tokens (tokens written to cache on a miss) and cache_read_input_tokens (tokens served from cache on a hit). Cache reads are priced at roughly 10% of normal input token cost, making heavy system prompts (4K–32K tokens) extremely economical when reused across many turns. OpenAI's implementation is automatic for prompts sharing a common prefix of at least 1024 tokens, with no explicit cache_control markers required. Both APIs guarantee that cached computation does not affect output quality — the same guarantees as server-side prefix caching.

```python
import anthropic
import time

def demo_anthropic_prompt_cache(doc_text: str) -> dict:
    """Show Anthropic prompt caching: mark stable content with cache_control."""
    client = anthropic.Anthropic()
    messages_cached = [{"role": "user", "content": [
        {"type": "text", "text": doc_text,
         "cache_control": {"type": "ephemeral"}},
        {"type": "text", "text": "Summarize the key findings in 3 bullet points."}
    ]}]
    messages_no_cache = [{"role": "user", "content": doc_text +
                          " Summarize the key findings in 3 bullet points."}]
    # First call: cold cache miss — full prefill billed at standard rate
    t0 = time.perf_counter()
    r1 = client.messages.create(model="claude-opus-4-5", max_tokens=256,
                                 messages=messages_cached)
    t1 = time.perf_counter() - t0
    # Second call: cache hit — only new tokens billed
    t0 = time.perf_counter()
    r2 = client.messages.create(model="claude-opus-4-5", max_tokens=256,
                                 messages=messages_cached)
    t2 = time.perf_counter() - t0
    print(f"Call 1 — created: {r1.usage.cache_creation_input_tokens} cache tokens, read: {r1.usage.cache_read_input_tokens}, time: {t1:.2f}s")
    print(f"Call 2 — created: {r2.usage.cache_creation_input_tokens} cache tokens, read: {r2.usage.cache_read_input_tokens}, time: {t2:.2f}s")
    print(f"Latency reduction: {(t1 - t2) / t1 * 100:.1f}%")
    return {"cold_time": t1, "warm_time": t2, "speedup": t1 / t2}
```

## On-device Prefix Caching

On-device inference (e.g., mobile or edge deployments using llama.cpp or MLC-LLM) can also benefit from prefix caching when the same system prompt or context is reused across multiple user sessions. llama.cpp's session file feature saves and loads the KV cache state for a given prompt prefix to/from disk, allowing the next inference session to skip prefill entirely for the cached portion. The challenge on device is memory: a 4-bit quantized 7B model's KV cache for 2000 tokens is approximately 16 MB, which is feasible on devices with 8+ GB RAM. The cache must be invalidated when the model weights change (e.g., after an app update). For conversational assistants where the system prompt is fixed and the user query is always appended at the end, disk-based KV cache persistence can eliminate system prompt prefill latency entirely on the second and subsequent turns.

```python
import hashlib
from typing import List, Tuple
from collections import defaultdict

def optimize_request_ordering(
    prompts: List[str],
    prefix_lengths: List[int] = [64, 128, 256, 512]
) -> Tuple[List[str], float]:
    """Sort prompts to maximize prefix cache hits (group by shared prefixes first)."""
    def prefix_key(text: str, length: int) -> str:
        return hashlib.sha256(text[:length].encode()).hexdigest() if len(text) >= length else ""
    # Score each prompt by how many others share its prefixes
    freq: defaultdict = defaultdict(int)
    for p in prompts:
        for L in prefix_lengths:
            k = prefix_key(p, L)
            if k:
                freq[k] += 1
    def score(p: str) -> int:
        return sum(freq[prefix_key(p, L)] for L in prefix_lengths if len(p) >= L)
    sorted_prompts = sorted(prompts, key=score, reverse=True)
    # Estimate cache hit rate after sorting
    seen_prefixes: set = set()
    hits = 0
    for p in sorted_prompts:
        k = prefix_key(p, prefix_lengths[-1])
        if k in seen_prefixes:
            hits += 1
        seen_prefixes.add(k)
    hit_rate = hits / len(prompts) if prompts else 0.0
    print(f"Estimated cache hit rate after ordering: {hit_rate:.2%}")
    return sorted_prompts, hit_rate
```

## Cost Savings Analysis

The economic impact of prompt caching is largest for workloads with long, shared prefixes and many requests. A RAG application with a fixed 8000-token knowledge base prefix sent with every query, serving 100,000 daily requests, would without caching pay for 8000 × 100,000 = 800M input tokens per day. With 90% cache hit rate, only 80M tokens need full prefill computation, with the remaining 720M served from cache at 10% of normal cost. The effective input token cost drops to 10% × 720M + 100% × 80M = 152M equivalent tokens — an 81% reduction in input-side compute costs. The savings are proportional to prefix length, request volume, and cache hit rate. Short prefixes or low request rates may not justify the engineering overhead of implementing prefix caching.

| Scenario | Prefix Length (tokens) | Cache Hit Rate | Prefill Savings | Effective Cost Reduction |
| --- | --- | --- | --- | --- |
| Shared system prompt (short) | 200 | 90% | 90% of prefix prefill skipped | 45–60% |
| RAG with fixed document set | 4000–8000 | 85% | 85% of prefix prefill skipped | 70–80% |
| Code context window | 2000–4000 | 70% | 70% of prefix prefill skipped | 55–65% |
| Multi-turn conversational history | 500–2000 (growing) | 60% | 60% of history prefill skipped | 40–55% |
| Mixed workload (varied prefixes) | 1000 avg | 40% | 40% of prefix prefill skipped | 25–35% |

> **Structure Prompts for Maximum Cache Reuse**: Put your longest, most reused content at the beginning of the prompt (system instructions, RAG context, examples) and dynamic content at the end — prefix caches only match from the start of the sequence. Even a single character difference at position 1 invalidates the entire cache match for that request.

## Key Takeaways

- Prefix caching stores KV tensors for shared prompt prefixes and reuses them across requests — eliminating redundant prefill computation entirely for cached tokens.
- A trie (radix tree) structure enables efficient longest-prefix matching: each node stores KV tensors for a token sequence prefix, with LRU eviction for memory management.
- vLLM enables prefix caching with a single flag: LLM(enable_prefix_caching=True); no other code changes are required.
- Anthropic and OpenAI APIs expose prompt caching explicitly — mark stable content blocks with cache_control; cached tokens cost ~10% of normal input token price.
- For maximum hit rate, always place stable content (system prompt, RAG context) before dynamic content (user query) in your prompt structure.
- On-device inference can persist KV caches to disk between sessions using session files (llama.cpp) to skip system prompt prefill on warm starts.
- Cache hit rate of 80–90% is achievable for chatbot workloads with a fixed system prompt; RAG with a fixed document set can achieve 85–95%.

---

