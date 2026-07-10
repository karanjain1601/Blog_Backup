---
title: "Decoder-Only Transformers — GPT Architecture and Autoregressive LMs"
slug: "decoder-only-gpt"
description: "Deep dive into decoder-only transformer architecture: causal self-attention, GPT-1/2/3 evolution, weight tying, KV cache, and autoregressive sampling strategies."
tags: ["deep-learning", "transformers", "attention-efficiency"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Decoder-only transformers form the backbone of modern large language models. Unlike encoder-decoder architectures, they rely solely on causal (masked) self-attention — each position attends only to itself and positions to its left. This constraint makes them naturally suited for autoregressive generation: predict the next token given all previous tokens. The GPT family demonstrated that this simple architecture, when scaled, produces emergent capabilities ranging from coherent text generation to few-shot in-context learning without any task-specific fine-tuning."},{"type":"heading","level":2,"content":"Decoder-Only Architecture Overview"},{"type":"text","content":"A decoder-only transformer first maps each token to a dense vector via a token embedding matrix E ∈ ℝ^{V×d}, then adds positional embeddings P ∈ ℝ^{T×d}. This combined representation passes through L identical blocks, each containing: LayerNorm → Causal Multi-Head Attention → residual add → LayerNorm → Feed-Forward Network → residual add. After L blocks, a final LayerNorm projects through an output matrix (often tied to E^T) to logits over the vocabulary. Pre-norm placement (LayerNorm before each sublayer) is universal in modern implementations for training stability."},{"type":"heading","level":2,"content":"GPT Family: GPT-1, GPT-2, GPT-3"},{"type":"table","headers":["Model","Params","Layers","d_model","Heads","Trained Tokens","Capability Milestone"],"rows":[["GPT-1 (2018)","117M","12","768","12","~1B (BooksCorpus)","Supervised fine-tuning baseline; transfer learning for NLP"],["GPT-2 small (2019)","117M","12","768","12","~10B (WebText)","Coherent multi-paragraph generation; initially withheld"],["GPT-2 XL (2019)","1.5B","48","1600","25","~10B (WebText)","Zero-shot task performance; scaling demo"],["GPT-3 (2020)","175B","96","12288","96","~300B tokens","In-context learning; few-shot prompting emerges"]]},{"type":"heading","level":2,"content":"Transformer Block: Pre-Norm and Causal MHA"},{"type":"text","content":"Causal attention enforces the autoregressive constraint via an upper-triangular mask: the attention weight from position i to position j is set to −∞ before softmax whenever j \u003e i. Combined with pre-norm, each block computes x ← x + Attn(LN(x)) then x ← x + FFN(LN(x)). The FFN typically uses a 4× expansion ratio (d_ffn = 4d) with GELU activation. SwiGLU replaces GELU in LLaMA and PaLM: FFN(x) = (xW₁ ⊙ SiLU(xW_gate)) W₂, trading one matrix multiply for improved quality."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass CausalSelfAttention(nn.Module):\n    def __init__(self, d_model, n_heads, max_len=512):\n        super().__init__()\n        self.n_heads = n_heads\n        self.d_head = d_model // n_heads\n        self.qkv = nn.Linear(d_model, 3 * d_model, bias=False)\n        self.proj = nn.Linear(d_model, d_model, bias=False)\n        self.register_buffer(\u0027mask\u0027, torch.tril(torch.ones(max_len, max_len)))\n\n    def forward(self, x):\n        B, T, C = x.shape\n        q, k, v = self.qkv(x).split(C, dim=-1)\n        def reshape(t): return t.view(B, T, self.n_heads, self.d_head).transpose(1, 2)\n        q, k, v = reshape(q), reshape(k), reshape(v)\n        att = (q @ k.transpose(-2, -1)) * self.d_head ** -0.5\n        att = att.masked_fill(self.mask[:T, :T] == 0, float(\u0027-inf\u0027))\n        out = F.softmax(att, dim=-1) @ v\n        return self.proj(out.transpose(1, 2).contiguous().view(B, T, C))\n\nclass GPTBlock(nn.Module):\n    def __init__(self, d_model=768, n_heads=12, ffn_mult=4):\n        super().__init__()\n        self.ln1, self.ln2 = nn.LayerNorm(d_model), nn.LayerNorm(d_model)\n        self.attn = CausalSelfAttention(d_model, n_heads)\n        self.ffn = nn.Sequential(\n            nn.Linear(d_model, d_model * ffn_mult), nn.GELU(),\n            nn.Linear(d_model * ffn_mult, d_model)\n        )\n    def forward(self, x):\n        x = x + self.attn(self.ln1(x))\n        return x + self.ffn(self.ln2(x))\n\nblock = GPTBlock()\nx = torch.randn(2, 32, 768)\nprint(f\u0027Output: {block(x).shape}\u0027)  # torch.Size([2, 32, 768])\nprint(f\u0027Block params: {sum(p.numel() for p in block.parameters()):,}\u0027)"},{"type":"heading","level":2,"content":"Weight Tying: Shared Embedding and Output Projection"},{"type":"text","content":"Weight tying sets the output projection matrix equal to the transpose of the token embedding matrix: W_out = E^T, so that the same parameters govern both token lookup and vocabulary prediction. This reduces parameter count by V×d (≈38M for GPT-2 small with V=50257, d=768) and ensures that the geometric distances in embedding space are consistent between input and output. It also regularizes the model: tokens that appear in similar contexts will have similar embeddings and similar output probabilities."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass TiedGPT(nn.Module):\n    def __init__(self, vocab_size=50257, d_model=768, n_layers=12,\n                 n_heads=12, max_len=1024):\n        super().__init__()\n        self.tok_emb = nn.Embedding(vocab_size, d_model)\n        self.pos_emb = nn.Embedding(max_len, d_model)\n        self.blocks = nn.ModuleList([GPTBlock(d_model, n_heads) for _ in range(n_layers)])\n        self.ln_f = nn.LayerNorm(d_model)\n        self.head = nn.Linear(d_model, vocab_size, bias=False)\n        # Weight tying: output head shares weights with token embedding\n        self.head.weight = self.tok_emb.weight\n\n    def forward(self, idx):\n        B, T = idx.shape\n        pos = torch.arange(T, device=idx.device)\n        x = self.tok_emb(idx) + self.pos_emb(pos)\n        for block in self.blocks:\n            x = block(x)\n        return self.head(self.ln_f(x))  # (B, T, vocab_size)\n\nmodel = TiedGPT(n_layers=2)  # shallow for demo\ntotal = sum(p.numel() for p in model.parameters())\nuntied_total = total + model.tok_emb.weight.numel()\nprint(f\u0027Params with tying:    {total:,}\u0027)\nprint(f\u0027Params without tying: {untied_total:,}\u0027)\nprint(f\u0027Savings: {untied_total - total:,} ({100*(untied_total-total)/untied_total:.1f}%)\u0027)\nassert model.head.weight.data_ptr() == model.tok_emb.weight.data_ptr(), \u0027Weights not tied!\u0027"},{"type":"heading","level":2,"content":"Language Modeling Objective and Training"},{"type":"text","content":"The training objective is next-token prediction via cross-entropy loss applied at every position simultaneously. For a sequence [x₁, x₂, ..., x_T], the model predicts P(xₜ | x₁,...,xₜ₋₁) for all t in a single forward pass (teacher forcing). The loss is L = −(1/T) Σₜ log P(xₜ | x\u003ct). This parallelism over sequence positions is a fundamental advantage over RNNs: the entire sequence is processed in one forward-backward pass. Perplexity = exp(L) is the primary evaluation metric — lower is better, with well-trained models achieving perplexities in the single digits on held-out data."},{"type":"callout","variant":"info","title":"Pre-Norm vs Post-Norm","content":"Original attention (Vaswani 2017) used post-normalization: sublayer output → residual add → LayerNorm. GPT-2 and nearly all modern LLMs switched to pre-normalization: LayerNorm → sublayer → residual add. Pre-norm allows larger learning rates and scales more stably to hundreds of layers because gradients bypass LayerNorm through the residual stream. Post-norm can achieve marginally better final perplexity at small scale but diverges more easily."},{"type":"heading","level":2,"content":"Autoregressive Inference: Sampling Strategies"},{"type":"text","content":"During inference, the model generates one token per step. The logits z ∈ ℝ^V are converted to probabilities via softmax(z/τ) where τ is temperature. Greedy decoding (argmax) is deterministic but often produces repetitive text. Top-k sampling truncates to the k highest-probability tokens; top-p (nucleus) sampling picks the smallest token set whose cumulative probability exceeds p — more adaptive than top-k since it varies set size based on the distribution shape. Best practice is top-p=0.9 with temperature around 0.8 for open-ended generation."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\n\ndef top_p_filter(logits, top_p=0.9):\n    sorted_logits, sorted_idx = torch.sort(logits, descending=True)\n    cum_probs = sorted_logits.softmax(dim=-1).cumsum(dim=-1)\n    # Remove tokens once cumulative probability exceeds top_p\n    remove_mask = cum_probs - sorted_logits.softmax(dim=-1) \u003e top_p\n    sorted_logits[remove_mask] = float(\u0027-inf\u0027)\n    return torch.zeros_like(logits).scatter_(-1, sorted_idx, sorted_logits)\n\ndef sample_token(logits, temperature=0.8, top_k=50, top_p=0.9):\n    logits = logits.float() / max(temperature, 1e-8)\n    if top_k \u003e 0:\n        kth_val = torch.topk(logits, min(top_k, logits.size(-1)))[0][..., -1, None]\n        logits = logits.masked_fill(logits \u003c kth_val, float(\u0027-inf\u0027))\n    if top_p \u003c 1.0:\n        logits = top_p_filter(logits, top_p)\n    return torch.multinomial(F.softmax(logits, dim=-1), num_samples=1)\n\n# Compare entropy under different temperatures\ntorch.manual_seed(0)\nvocab_size, seq_len = 200, 10\nlogits = torch.randn(vocab_size)\nprint(f\u0027{\u0027Temp\u0027:\u003e6}  {\u0027Entropy\u0027:\u003e8}  {\u0027Max Prob\u0027:\u003e10}  {\u0027Effective Vocab\u0027:\u003e15}\u0027)\nfor temp in [0.3, 0.7, 1.0, 1.5, 2.0]:\n    p = F.softmax(logits / temp, dim=-1)\n    ent = -(p * p.log()).sum().item()\n    eff = torch.exp(torch.tensor(ent)).item()\n    print(f\u0027{temp:\u003e6.1f}  {ent:\u003e8.3f}  {p.max().item():\u003e10.4f}  {eff:\u003e15.1f}\u0027)"},{"type":"heading","level":2,"content":"KV Cache for Fast Inference"},{"type":"text","content":"Without a cache, generating T tokens requires O(T²) attention computations total. With a KV cache, previously computed K and V projections are stored and reused: each new step appends one row to the cache and runs attention over the full history. Per-step computation drops from O(T×d) to O(d) for the attention — the bottleneck becomes memory bandwidth rather than FLOPs. Cache memory per layer is 2 × T × d_model bytes (float16); for a 175B model with T=4096 that is 2 × 4096 × 12288 × 96 layers × 2 bytes ≈ 18 GB just for KV cache."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\n\nclass KVCacheAttention(nn.Module):\n    def __init__(self, d_model=512, n_heads=8):\n        super().__init__()\n        self.n_heads = n_heads\n        self.d_head = d_model // n_heads\n        self.qkv = nn.Linear(d_model, 3 * d_model, bias=False)\n        self.proj = nn.Linear(d_model, d_model, bias=False)\n        self.k_cache = self.v_cache = None\n\n    def reset_cache(self): self.k_cache = self.v_cache = None\n\n    def forward(self, x, use_cache=False):\n        B, T, C = x.shape\n        q, k, v = self.qkv(x).split(C, dim=-1)\n        def split(t): return t.view(B, T, self.n_heads, self.d_head).transpose(1, 2)\n        q, k, v = split(q), split(k), split(v)\n        if use_cache and self.k_cache is not None:\n            k = torch.cat([self.k_cache, k], dim=2)  # (B, H, T_past+T, d_head)\n            v = torch.cat([self.v_cache, v], dim=2)\n        if use_cache:\n            self.k_cache, self.v_cache = k.detach(), v.detach()\n        att = F.softmax((q @ k.transpose(-2, -1)) * self.d_head ** -0.5, dim=-1)\n        return self.proj((att @ v).transpose(1, 2).contiguous().view(B, T, C))\n\nattn = KVCacheAttention()\nx_prompt = torch.randn(1, 8, 512)   # prompt of length 8\nattn(x_prompt, use_cache=True)\nprint(f\u0027Cache after prompt:  k={attn.k_cache.shape}\u0027)  # (1, 8, 8, 64)\nfor step in range(3):\n    attn(torch.randn(1, 1, 512), use_cache=True)  # generate one token\nprint(f\u0027Cache after 3 steps: k={attn.k_cache.shape}\u0027)  # (1, 8, 11, 64)"},{"type":"heading","level":2,"content":"Why Decoder-Only Dominates Modern LLMs"},{"type":"text","content":"Encoder-decoder architectures require separate encoder and decoder stacks — nearly double the parameters for similar capability. Encoder-only models (BERT) cannot generate text autoregressively. Decoder-only is the simplest unified architecture where the same model handles pretraining, supervised fine-tuning, RLHF, and zero/few-shot inference. At scale, in-context learning eliminates the need for task-specific fine-tuning for many applications. Empirically, decoder-only models consistently match or exceed encoder-decoder models at comparable compute once scaled past roughly 10B parameters."},{"type":"list","ordered":false,"items":["Single unified architecture: pretraining, SFT, RLHF, and inference use the same forward pass.","In-context learning: GPT-3 showed that task specification via prompts replaces fine-tuning for many tasks.","Simpler training: one loss function (NLL over all positions), no cross-attention, no encoder-decoder alignment.","KV cache efficiency: causal attention caches naturally — bidirectional attention (BERT-style) cannot.","Predictable scaling: Kaplan and Chinchilla scaling laws are best characterized for decoder-only models.","Instruction following: RLHF + decoder-only is now the standard recipe for aligned LLMs (GPT-4, Claude, Gemini)."]},{"type":"divider"}]"
---
# Decoder-Only Transformers — GPT Architecture and Autoregressive LMs

Decoder-only transformers form the backbone of modern large language models. Unlike encoder-decoder architectures, they rely solely on causal (masked) self-attention — each position attends only to itself and positions to its left. This constraint makes them naturally suited for autoregressive generation: predict the next token given all previous tokens. The GPT family demonstrated that this simple architecture, when scaled, produces emergent capabilities ranging from coherent text generation to few-shot in-context learning without any task-specific fine-tuning.

## Decoder-Only Architecture Overview

A decoder-only transformer first maps each token to a dense vector via a token embedding matrix E ∈ ℝ^{V×d}, then adds positional embeddings P ∈ ℝ^{T×d}. This combined representation passes through L identical blocks, each containing: LayerNorm → Causal Multi-Head Attention → residual add → LayerNorm → Feed-Forward Network → residual add. After L blocks, a final LayerNorm projects through an output matrix (often tied to E^T) to logits over the vocabulary. Pre-norm placement (LayerNorm before each sublayer) is universal in modern implementations for training stability.

## GPT Family: GPT-1, GPT-2, GPT-3

| Model | Params | Layers | d_model | Heads | Trained Tokens | Capability Milestone |
| --- | --- | --- | --- | --- | --- | --- |
| GPT-1 (2018) | 117M | 12 | 768 | 12 | ~1B (BooksCorpus) | Supervised fine-tuning baseline; transfer learning for NLP |
| GPT-2 small (2019) | 117M | 12 | 768 | 12 | ~10B (WebText) | Coherent multi-paragraph generation; initially withheld |
| GPT-2 XL (2019) | 1.5B | 48 | 1600 | 25 | ~10B (WebText) | Zero-shot task performance; scaling demo |
| GPT-3 (2020) | 175B | 96 | 12288 | 96 | ~300B tokens | In-context learning; few-shot prompting emerges |

## Transformer Block: Pre-Norm and Causal MHA

Causal attention enforces the autoregressive constraint via an upper-triangular mask: the attention weight from position i to position j is set to −∞ before softmax whenever j > i. Combined with pre-norm, each block computes x ← x + Attn(LN(x)) then x ← x + FFN(LN(x)). The FFN typically uses a 4× expansion ratio (d_ffn = 4d) with GELU activation. SwiGLU replaces GELU in LLaMA and PaLM: FFN(x) = (xW₁ ⊙ SiLU(xW_gate)) W₂, trading one matrix multiply for improved quality.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class CausalSelfAttention(nn.Module):
    def __init__(self, d_model, n_heads, max_len=512):
        super().__init__()
        self.n_heads = n_heads
        self.d_head = d_model // n_heads
        self.qkv = nn.Linear(d_model, 3 * d_model, bias=False)
        self.proj = nn.Linear(d_model, d_model, bias=False)
        self.register_buffer('mask', torch.tril(torch.ones(max_len, max_len)))

    def forward(self, x):
        B, T, C = x.shape
        q, k, v = self.qkv(x).split(C, dim=-1)
        def reshape(t): return t.view(B, T, self.n_heads, self.d_head).transpose(1, 2)
        q, k, v = reshape(q), reshape(k), reshape(v)
        att = (q @ k.transpose(-2, -1)) * self.d_head ** -0.5
        att = att.masked_fill(self.mask[:T, :T] == 0, float('-inf'))
        out = F.softmax(att, dim=-1) @ v
        return self.proj(out.transpose(1, 2).contiguous().view(B, T, C))

class GPTBlock(nn.Module):
    def __init__(self, d_model=768, n_heads=12, ffn_mult=4):
        super().__init__()
        self.ln1, self.ln2 = nn.LayerNorm(d_model), nn.LayerNorm(d_model)
        self.attn = CausalSelfAttention(d_model, n_heads)
        self.ffn = nn.Sequential(
            nn.Linear(d_model, d_model * ffn_mult), nn.GELU(),
            nn.Linear(d_model * ffn_mult, d_model)
        )
    def forward(self, x):
        x = x + self.attn(self.ln1(x))
        return x + self.ffn(self.ln2(x))

block = GPTBlock()
x = torch.randn(2, 32, 768)
print(f'Output: {block(x).shape}')  # torch.Size([2, 32, 768])
print(f'Block params: {sum(p.numel() for p in block.parameters()):,}')
```

## Weight Tying: Shared Embedding and Output Projection

Weight tying sets the output projection matrix equal to the transpose of the token embedding matrix: W_out = E^T, so that the same parameters govern both token lookup and vocabulary prediction. This reduces parameter count by V×d (≈38M for GPT-2 small with V=50257, d=768) and ensures that the geometric distances in embedding space are consistent between input and output. It also regularizes the model: tokens that appear in similar contexts will have similar embeddings and similar output probabilities.

```python
import torch
import torch.nn as nn

class TiedGPT(nn.Module):
    def __init__(self, vocab_size=50257, d_model=768, n_layers=12,
                 n_heads=12, max_len=1024):
        super().__init__()
        self.tok_emb = nn.Embedding(vocab_size, d_model)
        self.pos_emb = nn.Embedding(max_len, d_model)
        self.blocks = nn.ModuleList([GPTBlock(d_model, n_heads) for _ in range(n_layers)])
        self.ln_f = nn.LayerNorm(d_model)
        self.head = nn.Linear(d_model, vocab_size, bias=False)
        # Weight tying: output head shares weights with token embedding
        self.head.weight = self.tok_emb.weight

    def forward(self, idx):
        B, T = idx.shape
        pos = torch.arange(T, device=idx.device)
        x = self.tok_emb(idx) + self.pos_emb(pos)
        for block in self.blocks:
            x = block(x)
        return self.head(self.ln_f(x))  # (B, T, vocab_size)

model = TiedGPT(n_layers=2)  # shallow for demo
total = sum(p.numel() for p in model.parameters())
untied_total = total + model.tok_emb.weight.numel()
print(f'Params with tying:    {total:,}')
print(f'Params without tying: {untied_total:,}')
print(f'Savings: {untied_total - total:,} ({100*(untied_total-total)/untied_total:.1f}%)')
assert model.head.weight.data_ptr() == model.tok_emb.weight.data_ptr(), 'Weights not tied!'
```

## Language Modeling Objective and Training

The training objective is next-token prediction via cross-entropy loss applied at every position simultaneously. For a sequence [x₁, x₂, ..., x_T], the model predicts P(xₜ | x₁,...,xₜ₋₁) for all t in a single forward pass (teacher forcing). The loss is L = −(1/T) Σₜ log P(xₜ | x<t). This parallelism over sequence positions is a fundamental advantage over RNNs: the entire sequence is processed in one forward-backward pass. Perplexity = exp(L) is the primary evaluation metric — lower is better, with well-trained models achieving perplexities in the single digits on held-out data.

> **Pre-Norm vs Post-Norm**: Original attention (Vaswani 2017) used post-normalization: sublayer output → residual add → LayerNorm. GPT-2 and nearly all modern LLMs switched to pre-normalization: LayerNorm → sublayer → residual add. Pre-norm allows larger learning rates and scales more stably to hundreds of layers because gradients bypass LayerNorm through the residual stream. Post-norm can achieve marginally better final perplexity at small scale but diverges more easily.

## Autoregressive Inference: Sampling Strategies

During inference, the model generates one token per step. The logits z ∈ ℝ^V are converted to probabilities via softmax(z/τ) where τ is temperature. Greedy decoding (argmax) is deterministic but often produces repetitive text. Top-k sampling truncates to the k highest-probability tokens; top-p (nucleus) sampling picks the smallest token set whose cumulative probability exceeds p — more adaptive than top-k since it varies set size based on the distribution shape. Best practice is top-p=0.9 with temperature around 0.8 for open-ended generation.

```python
import torch
import torch.nn.functional as F

def top_p_filter(logits, top_p=0.9):
    sorted_logits, sorted_idx = torch.sort(logits, descending=True)
    cum_probs = sorted_logits.softmax(dim=-1).cumsum(dim=-1)
    # Remove tokens once cumulative probability exceeds top_p
    remove_mask = cum_probs - sorted_logits.softmax(dim=-1) > top_p
    sorted_logits[remove_mask] = float('-inf')
    return torch.zeros_like(logits).scatter_(-1, sorted_idx, sorted_logits)

def sample_token(logits, temperature=0.8, top_k=50, top_p=0.9):
    logits = logits.float() / max(temperature, 1e-8)
    if top_k > 0:
        kth_val = torch.topk(logits, min(top_k, logits.size(-1)))[0][..., -1, None]
        logits = logits.masked_fill(logits < kth_val, float('-inf'))
    if top_p < 1.0:
        logits = top_p_filter(logits, top_p)
    return torch.multinomial(F.softmax(logits, dim=-1), num_samples=1)

# Compare entropy under different temperatures
torch.manual_seed(0)
vocab_size, seq_len = 200, 10
logits = torch.randn(vocab_size)
print(f'{'Temp':>6}  {'Entropy':>8}  {'Max Prob':>10}  {'Effective Vocab':>15}')
for temp in [0.3, 0.7, 1.0, 1.5, 2.0]:
    p = F.softmax(logits / temp, dim=-1)
    ent = -(p * p.log()).sum().item()
    eff = torch.exp(torch.tensor(ent)).item()
    print(f'{temp:>6.1f}  {ent:>8.3f}  {p.max().item():>10.4f}  {eff:>15.1f}')
```

## KV Cache for Fast Inference

Without a cache, generating T tokens requires O(T²) attention computations total. With a KV cache, previously computed K and V projections are stored and reused: each new step appends one row to the cache and runs attention over the full history. Per-step computation drops from O(T×d) to O(d) for the attention — the bottleneck becomes memory bandwidth rather than FLOPs. Cache memory per layer is 2 × T × d_model bytes (float16); for a 175B model with T=4096 that is 2 × 4096 × 12288 × 96 layers × 2 bytes ≈ 18 GB just for KV cache.

```python
import torch
import torch.nn as nn
import torch.nn.functional as F

class KVCacheAttention(nn.Module):
    def __init__(self, d_model=512, n_heads=8):
        super().__init__()
        self.n_heads = n_heads
        self.d_head = d_model // n_heads
        self.qkv = nn.Linear(d_model, 3 * d_model, bias=False)
        self.proj = nn.Linear(d_model, d_model, bias=False)
        self.k_cache = self.v_cache = None

    def reset_cache(self): self.k_cache = self.v_cache = None

    def forward(self, x, use_cache=False):
        B, T, C = x.shape
        q, k, v = self.qkv(x).split(C, dim=-1)
        def split(t): return t.view(B, T, self.n_heads, self.d_head).transpose(1, 2)
        q, k, v = split(q), split(k), split(v)
        if use_cache and self.k_cache is not None:
            k = torch.cat([self.k_cache, k], dim=2)  # (B, H, T_past+T, d_head)
            v = torch.cat([self.v_cache, v], dim=2)
        if use_cache:
            self.k_cache, self.v_cache = k.detach(), v.detach()
        att = F.softmax((q @ k.transpose(-2, -1)) * self.d_head ** -0.5, dim=-1)
        return self.proj((att @ v).transpose(1, 2).contiguous().view(B, T, C))

attn = KVCacheAttention()
x_prompt = torch.randn(1, 8, 512)   # prompt of length 8
attn(x_prompt, use_cache=True)
print(f'Cache after prompt:  k={attn.k_cache.shape}')  # (1, 8, 8, 64)
for step in range(3):
    attn(torch.randn(1, 1, 512), use_cache=True)  # generate one token
print(f'Cache after 3 steps: k={attn.k_cache.shape}')  # (1, 8, 11, 64)
```

## Why Decoder-Only Dominates Modern LLMs

Encoder-decoder architectures require separate encoder and decoder stacks — nearly double the parameters for similar capability. Encoder-only models (BERT) cannot generate text autoregressively. Decoder-only is the simplest unified architecture where the same model handles pretraining, supervised fine-tuning, RLHF, and zero/few-shot inference. At scale, in-context learning eliminates the need for task-specific fine-tuning for many applications. Empirically, decoder-only models consistently match or exceed encoder-decoder models at comparable compute once scaled past roughly 10B parameters.

- Single unified architecture: pretraining, SFT, RLHF, and inference use the same forward pass.
- In-context learning: GPT-3 showed that task specification via prompts replaces fine-tuning for many tasks.
- Simpler training: one loss function (NLL over all positions), no cross-attention, no encoder-decoder alignment.
- KV cache efficiency: causal attention caches naturally — bidirectional attention (BERT-style) cannot.
- Predictable scaling: Kaplan and Chinchilla scaling laws are best characterized for decoder-only models.
- Instruction following: RLHF + decoder-only is now the standard recipe for aligned LLMs (GPT-4, Claude, Gemini).

---

