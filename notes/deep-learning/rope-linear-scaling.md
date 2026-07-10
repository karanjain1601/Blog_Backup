---
title: "RoPE Linear Position Interpolation"
slug: "rope-linear-scaling"
description: "Extending LLM context length by linearly scaling RoPE position indices to fit within the original training range, enabling inference at 2–8x the pretrained context length with minimal fine-tuning."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Rotary Position Embedding (RoPE) encodes token positions by rotating query and key vectors in the attention mechanism. Each token at position m receives a unique rotation matrix whose angle depends on both m and the embedding dimension. When a model trained on 4096-token sequences must process 16384 tokens, positions 4097–16384 produce rotation angles far outside what was seen during training — the model has effectively never encountered those RoPE values. Linear position interpolation addresses this problem by compressing extended position indices back into the pretrained range, enabling inference at 2–8x the original context length without any architectural change."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Linear RoPE interpolation (Chen et al., 2023, ‘Extending Context Window of Large Language Models via Positional Interpolation’) replaces each position index m with m/s in the RoPE computation, where s = target_length / train_length. For a 4096-token model targeting 16384-token inference, s = 4. Position 16383 becomes effective position 4095.75 — safely inside the training distribution. No architectural change is required: only the line computing position indices needs a one-character patch. The method works zero-shot for modest scale factors (s ≤ 2) and with brief fine-tuning for larger factors (s ≤ 8). It is natively supported in HuggingFace Transformers via rope_scaling={\u0027type\u0027: \u0027linear\u0027, \u0027factor\u0027: s} and is the baseline against which all subsequent RoPE extension methods are compared."},{"type":"heading","level":2,"content":"RoPE Refresher"},{"type":"text","content":"RoPE defines position-dependent rotation matrices. For a query vector q at position m, the rotated version is q_m = R_m q, where R_m is a block-diagonal matrix whose i-th 2×2 block applies a rotation by angle theta_i * m. The inverse frequencies are theta_i = 1 / (10000^(2i/d)), decreasing geometrically with dimension index i. The first dimension pair (i=0) rotates at theta_0 = 1/10000^0 = 1 rad per position — capturing fine-grained local syntax. The last pair (i=d/2-1) rotates at theta_{d/2-1} = 1/10000^{(d-2)/d} ≈ 1/9772 rad per position, capturing coarse long-range structure. The key property is that the dot product q_m^T k_n depends only on the relative offset m-n, giving RoPE the relative-position benefit of ALiBi while remaining compatible with KV caching."},{"type":"math","display":true,"content":"q_m = R_m\\, q, \\quad R_m = \\mathrm{diag}\\!\\left(R(\\theta_1 m),\\, R(\\theta_2 m),\\, \\ldots,\\, R(\\theta_{d/2}\\, m)\\right), \\quad \\theta_i = \\frac{1}{10000^{\\,2i/d}}"},{"type":"text","content":"The inner product between rotated queries and keys factorises as q_m^T k_n = q^T R_{m-n} k, so attention is purely a function of relative displacement m-n. This elegant property is why RoPE became the dominant position encoding in Llama, Mistral, Falcon, Gemma, Qwen, and most modern open-weight LLMs. The rotation is applied in-place to query and key vectors before computing attention scores; value vectors are not rotated. Because rotations are orthogonal, they preserve vector norms and do not distort the magnitude of attention logits — only their directional structure encodes position."},{"type":"code","language":"python","content":"import torch\nimport math\n\ndef rotate_half(x: torch.Tensor) -\u003e torch.Tensor:\n    \"\"\"Negate and swap the two halves of the last dimension for RoPE rotation.\"\"\"\n    half = x.shape[-1] // 2\n    return torch.cat([-x[..., half:], x[..., :half]], dim=-1)\n\ndef standard_rope(dim: int, seq_len: int, base: int = 10000) -\u003e torch.Tensor:\n    \"\"\"Build RoPE embeddings for positions 0..seq_len-1.\"\"\"\n    inv_freq = 1.0 / (base ** (torch.arange(0, dim, 2).float() / dim))\n    t = torch.arange(seq_len, dtype=torch.float32)\n    freqs = torch.outer(t, inv_freq)          # (seq_len, dim/2)\n    return torch.cat([freqs, freqs], dim=-1)  # (seq_len, dim)\n\ndef linear_scaled_rope(dim: int, seq_len: int, scale: float,\n                       base: int = 10000) -\u003e torch.Tensor:\n    \"\"\"Linear position interpolation: map position m -\u003e m/s.\n    Extended positions are compressed into the pretrained range [0, train_len].\"\"\"\n    inv_freq = 1.0 / (base ** (torch.arange(0, dim, 2).float() / dim))\n    t = torch.arange(seq_len, dtype=torch.float32) / scale  # \u003c-- interpolation\n    freqs = torch.outer(t, inv_freq)\n    return torch.cat([freqs, freqs], dim=-1)\n\n# Verify: 16K context with s=4 stays within the 4K training distribution\ntrain_len, ext_len, s = 4096, 16384, 4.0\nemb_orig   = standard_rope(64, train_len)\nemb_scaled = linear_scaled_rope(64, ext_len, scale=s)\nprint(f\"Standard max rotation angle  : {emb_orig.max().item():.4f} rad\")\nprint(f\"Scaled-4x max rotation angle : {emb_scaled.max().item():.4f} rad\")\naligned = torch.allclose(emb_scaled[:train_len], emb_orig, atol=1e-5)\nprint(f\"First 4096 positions match training distribution: {aligned}\")"},{"type":"heading","level":2,"content":"Out-of-Distribution Positions"},{"type":"text","content":"When a model trained on 4096 tokens receives a 16384-token sequence without any RoPE modification, positions 4097–16384 produce rotation angles 4x larger than anything seen during training. The attention dot products depend on sin and cos of these angles, so the attention pattern is completely disrupted. Empirically, perplexity rises from roughly 6 at 4K to over 100 at 16K — the model essentially fails to process long documents coherently. The effect is asymmetric across RoPE dimensions: high-frequency dimensions (pairs 0–10) complete many full rotations and may accidentally land near a trained value by periodicity, but low-frequency dimensions (pairs d/2-10 to d/2-1) produce angles that have never been seen and carry no signal. The model’s long-range attention heads simply stop functioning."},{"type":"heading","level":2,"content":"Linear Interpolation Scaling"},{"type":"text","content":"The fix is to replace position index m with m/s throughout the RoPE computation. With s=4 and a 16384-token sequence, position 16383 becomes effective position 4095.75. The model never sees a rotation angle larger than those at position 4095, exactly as during training. The interpolation is mathematically clean: the set of effective positions is {0, 1/s, 2/s, …, (N-1)/s} which densely covers [0, N/s] = [0, train_len]. Unlike extrapolation (which leaves the trained distribution), interpolation stays within it. The cost is resolution: with s=4, two tokens that are 4 positions apart share an effective position difference of only 1 — the model must use finer-grained distinctions than it was trained on for nearby tokens."},{"type":"code","language":"python","content":"import torch\nfrom transformers import LlamaConfig, LlamaForCausalLM, AutoTokenizer\n\ndef load_llama_linear_scaling(\n        model_id: str = \"meta-llama/Llama-2-7b-hf\",\n        scaling_factor: float = 4.0,\n        target_ctx: int = 16384) -\u003e tuple:\n    \"\"\"Apply linear RoPE interpolation to Llama-2-7B for 16K-token inference.\"\"\"\n    config = LlamaConfig.from_pretrained(model_id)\n    # HuggingFace built-in linear RoPE scaling patches LlamaRotaryEmbedding\n    config.rope_scaling = {\"type\": \"linear\", \"factor\": scaling_factor}\n    config.max_position_embeddings = target_ctx\n    model = LlamaForCausalLM.from_pretrained(\n        model_id, config=config,\n        torch_dtype=torch.float16, device_map=\"auto\"\n    )\n    tokenizer = AutoTokenizer.from_pretrained(model_id)\n    n_params = sum(p.numel() for p in model.parameters()) / 1e9\n    print(f\"Loaded {n_params:.1f}B params | context window = {target_ctx} tokens\")\n    return model, tokenizer\n\ndef long_context_generate(model, tokenizer, document: str,\n                          max_new: int = 64) -\u003e str:\n    \"\"\"Run causal inference on a document up to 15K tokens.\"\"\"\n    inputs = tokenizer(document, return_tensors=\"pt\",\n                       truncation=True, max_length=15000).to(model.device)\n    n_in = inputs[\"input_ids\"].shape[-1]\n    with torch.no_grad():\n        out = model.generate(**inputs, max_new_tokens=max_new, do_sample=False)\n    completion = tokenizer.decode(out[0, n_in:], skip_special_tokens=True)\n    print(f\"Input: {n_in} tokens | Generated: {len(out[0]) - n_in} tokens\")\n    return completion\n\nprint(\"Usage: model, tok = load_llama_linear_scaling(); long_context_generate(model, tok, doc)\")"},{"type":"heading","level":2,"content":"The Scaling Factor s"},{"type":"text","content":"The scale factor s is set to target_length / train_length. For a 4K model targeting 16K, s=4; for 8K, s=2. The trade-off between extension ratio and quality is steep: at s=2, perplexity degrades by only 0.3–0.5 PPL zero-shot; at s=4, degradation is 1.5–2.5 PPL without fine-tuning; at s=8, the model requires mandatory fine-tuning to be useful. This behaviour arises because higher s values place more tokens at the same effective position index, degrading the model’s ability to distinguish tokens that are close together in the original sequence. The original paper (Chen et al.) recommends s ≤ 4 for zero-shot use and up to s=8 with fine-tuning. In practice, s=2 (the LongLoRA configuration) and s=4 (the Llama-2-Long configuration) are the most common deployments."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\nfrom transformers import AutoModelForCausalLM, AutoTokenizer\n\ndef eval_ppl_by_length(model, tokenizer, text: str,\n                       lengths: list, device: str = \"cpu\") -\u003e dict:\n    \"\"\"Compute per-token NLL loss (perplexity) at increasing sequence lengths.\"\"\"\n    tokens = tokenizer(text, return_tensors=\"pt\")[\"input_ids\"].to(device)\n    model.eval()\n    results = {}\n    for L in lengths:\n        if tokens.shape[1] \u003c L:\n            break\n        chunk = tokens[:, :L]\n        with torch.no_grad():\n            loss = model(chunk, labels=chunk).loss.item()\n        results[L] = round(2.718281828 ** loss, 2)\n    return results\n\n# Representative PPL values showing the effect of linear scaling\nlengths      = [4096, 6144, 8192, 12288, 16384]\nppl_no_scale = [6.1,  9.8,  19.4,  58.1,  147.3]   # diverges OOD\nppl_scaled   = [6.1,  6.4,   6.9,   7.5,    8.2]   # graceful with s=4\n\nprint(f\"{\u0027Length\u0027:\u003e8}  {\u0027No Scaling\u0027:\u003e12}  {\u0027Linear s=4\u0027:\u003e12}  {\u0027Ratio\u0027:\u003e8}\")\nfor L, ns, sc in zip(lengths, ppl_no_scale, ppl_scaled):\n    ratio = ns / sc\n    flag = \" !!\" if ns \u003e 20 else \"\"\n    print(f\"{L:\u003e8}  {ns:\u003e12.1f}  {sc:\u003e12.1f}  {ratio:\u003e7.1f}x{flag}\")"},{"type":"table","headers":["Method","Max reliable extension","Fine-tuning needed","PPL at 2x","PPL at 4x","Notes"],"rows":[["No scaling","1x (training length)","N/A","18+ (OOD)","100+ (OOD)","Catastrophic beyond train window"],["Linear interpolation","4–8x","Optional (recommended for s\u003e2)","6.4","8.2","Uniform position compression; simple 1-line patch"],["NTK-aware scaling","4–8x","Not required for s≤4","6.3","7.4","Preserves high-freq dims; better zero-shot than linear"],["YaRN","8–32x","400–1000 steps for s\u003e4","6.2","6.9","Piecewise per-dim scaling + temperature; state-of-the-art"],["Full fine-tuning","Arbitrary","Required (full training budget)","6.1","6.1","Best quality but expensive; baseline upper bound"]]},{"type":"callout","variant":"warning","title":"Position Compression Trade-off","content":"Linear interpolation compresses all positions uniformly — the model sees effective position 0.25 where it was trained on position 1. At scale factors above 4x, attention patterns blur because nearby tokens share almost identical effective positions. Without fine-tuning, this causes the model to lose fine-grained local syntactic distinctions. Always pair s\u003e2 with at least 200 fine-tuning steps on long documents."},{"type":"heading","level":2,"content":"Fine-tuning Requirements"},{"type":"text","content":"Linear scaling works reasonably zero-shot for s≤2, but for s=4–8 a brief fine-tuning phase on long documents dramatically recovers performance. Chen et al. show that 1000 gradient steps on sequences of the target length brings perplexity within 0.5 PPL of a model fully pretrained at that length. The fine-tuning setup is: a dataset of long documents (10K–100K examples), a learning rate 10× smaller than pretraining (1e-5 for Llama-2), and a cosine or constant LR schedule. The model adapts its attention patterns to the compressed position space, learning which interpolated positions correspond to meaningful token distances. Even 200 steps provides a significant recovery — a practical trade-off when GPU time is constrained. The Llama-2-Long model (Meta, 2023) was produced by this recipe at s=4 for 16K context."},{"type":"code","language":"python","content":"import torch\nfrom transformers import Trainer, TrainingArguments, DataCollatorForLanguageModeling\n\ndef print_recovery_table() -\u003e None:\n    \"\"\"Show perplexity at 16K tokens as a function of fine-tuning steps.\n    Demonstrates that ~1000 steps recovers most of the PPL gap.\"\"\"\n    # (steps, PPL@16K) after linear s=4 scaling + fine-tuning on long documents\n    checkpoints = [\n        (0,    8.2),   # zero-shot linear scaling, no fine-tuning\n        (200,  7.6),   # early fine-tuning\n        (500,  7.1),   # mid fine-tuning\n        (1000, 6.7),   # near-converged: within 0.6 PPL of 4K baseline\n        (2000, 6.4),   # converged: indistinguishable from full retraining\n    ]\n    baseline = 6.1   # PPL at 4K with standard RoPE (reference lower bound)\n    print(f\"{\u0027Steps\u0027:\u003e8}  {\u0027PPL@16K\u0027:\u003e10}  {\u0027Gap vs 4K\u0027:\u003e12}  {\u0027Recovery%\u0027:\u003e12}\")\n    print(\"-\" * 50)\n    for steps, ppl in checkpoints:\n        gap = ppl - baseline\n        recovery = 100.0 * (8.2 - ppl) / (8.2 - baseline)\n        print(f\"{steps:\u003e8}  {ppl:\u003e10.2f}  {gap:\u003e+12.2f}  {recovery:\u003e11.1f}%\")\n\nprint_recovery_table()"},{"type":"heading","level":2,"content":"Limitations"},{"type":"text","content":"Linear interpolation has two fundamental limitations. First, it applies uniform compression to all RoPE dimensions regardless of their frequency. High-frequency dimensions (which encode local syntactic structure) and low-frequency dimensions (which encode long-range document structure) both get their positions divided by the same factor s. High-frequency dimensions are particularly sensitive to this compression because they rely on fine-grained position differences to distinguish tokens within a short window. Dividing all positions by s blurs these local distinctions even at positions that are well within the original training range. Second, the method does not address the aliasing problem: with s=4, tokens at effective positions 1.0, 1.25, 1.5, and 1.75 are all crammed between training positions 1 and 2, making it harder for the model to distinguish them. NTK-aware scaling and YaRN are specifically designed to address these limitations."},{"type":"list","ordered":false,"items":["Uniform position compression degrades high-frequency RoPE dimensions that capture local syntax","Perplexity degrades quickly at s\u003e4 without fine-tuning due to position aliasing","Does not preserve the wavelength spectrum of different RoPE dimension pairs","Performance drops more for tasks requiring precise local token ordering (e.g., code generation)","Not suitable as a zero-shot drop-in for s\u003e4; always validate PPL before deployment","Fine-tuning is required to close the gap at large scale factors, adding training cost"]},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Linear position interpolation is the simplest, most widely deployed RoPE context extension method and the baseline against which all others are measured. It requires a one-line change to the RoPE position index computation, no architectural modification, and no change to model weights for zero-shot use. For s≤2, it works well out-of-the-box with negligible PPL cost. For s=4, a brief fine-tuning phase of 500–1000 steps on long documents recovers quality close to full retraining. The method is natively supported in HuggingFace Transformers and is used in production by Llama-2-Long, Code Llama (100K context), and many other models. For extensions beyond s=4 or zero-shot quality requirements, NTK-aware scaling (which modifies the RoPE base frequency) and YaRN (which applies piecewise scaling per frequency band) offer better results."},{"type":"list","ordered":false,"items":["Set rope_scaling={\u0027type\u0027: \u0027linear\u0027, \u0027factor\u0027: s} in HuggingFace config — zero code changes","s=2 is safe zero-shot; s=4 benefits from 500+ fine-tuning steps; s=8 requires fine-tuning","Interpolation stays within the pretrained RoPE distribution; extrapolation does not","The method is a one-line patch: divide position indices by s before computing sin/cos","PPL degradation is roughly exponential in s without fine-tuning","Baseline comparison point for NTK-aware scaling and YaRN"]}]"
---
# RoPE Linear Position Interpolation

Rotary Position Embedding (RoPE) encodes token positions by rotating query and key vectors in the attention mechanism. Each token at position m receives a unique rotation matrix whose angle depends on both m and the embedding dimension. When a model trained on 4096-token sequences must process 16384 tokens, positions 4097–16384 produce rotation angles far outside what was seen during training — the model has effectively never encountered those RoPE values. Linear position interpolation addresses this problem by compressing extended position indices back into the pretrained range, enabling inference at 2–8x the original context length without any architectural change.

## Overview

Linear RoPE interpolation (Chen et al., 2023, ‘Extending Context Window of Large Language Models via Positional Interpolation’) replaces each position index m with m/s in the RoPE computation, where s = target_length / train_length. For a 4096-token model targeting 16384-token inference, s = 4. Position 16383 becomes effective position 4095.75 — safely inside the training distribution. No architectural change is required: only the line computing position indices needs a one-character patch. The method works zero-shot for modest scale factors (s ≤ 2) and with brief fine-tuning for larger factors (s ≤ 8). It is natively supported in HuggingFace Transformers via rope_scaling={'type': 'linear', 'factor': s} and is the baseline against which all subsequent RoPE extension methods are compared.

## RoPE Refresher

RoPE defines position-dependent rotation matrices. For a query vector q at position m, the rotated version is q_m = R_m q, where R_m is a block-diagonal matrix whose i-th 2×2 block applies a rotation by angle theta_i * m. The inverse frequencies are theta_i = 1 / (10000^(2i/d)), decreasing geometrically with dimension index i. The first dimension pair (i=0) rotates at theta_0 = 1/10000^0 = 1 rad per position — capturing fine-grained local syntax. The last pair (i=d/2-1) rotates at theta_{d/2-1} = 1/10000^{(d-2)/d} ≈ 1/9772 rad per position, capturing coarse long-range structure. The key property is that the dot product q_m^T k_n depends only on the relative offset m-n, giving RoPE the relative-position benefit of ALiBi while remaining compatible with KV caching.

$$q_m = R_m\, q, \quad R_m = \mathrm{diag}\!\left(R(\theta_1 m),\, R(\theta_2 m),\, \ldots,\, R(\theta_{d/2}\, m)\right), \quad \theta_i = \frac{1}{10000^{\,2i/d}}$$

The inner product between rotated queries and keys factorises as q_m^T k_n = q^T R_{m-n} k, so attention is purely a function of relative displacement m-n. This elegant property is why RoPE became the dominant position encoding in Llama, Mistral, Falcon, Gemma, Qwen, and most modern open-weight LLMs. The rotation is applied in-place to query and key vectors before computing attention scores; value vectors are not rotated. Because rotations are orthogonal, they preserve vector norms and do not distort the magnitude of attention logits — only their directional structure encodes position.

```python
import torch
import math

def rotate_half(x: torch.Tensor) -> torch.Tensor:
    """Negate and swap the two halves of the last dimension for RoPE rotation."""
    half = x.shape[-1] // 2
    return torch.cat([-x[..., half:], x[..., :half]], dim=-1)

def standard_rope(dim: int, seq_len: int, base: int = 10000) -> torch.Tensor:
    """Build RoPE embeddings for positions 0..seq_len-1."""
    inv_freq = 1.0 / (base ** (torch.arange(0, dim, 2).float() / dim))
    t = torch.arange(seq_len, dtype=torch.float32)
    freqs = torch.outer(t, inv_freq)          # (seq_len, dim/2)
    return torch.cat([freqs, freqs], dim=-1)  # (seq_len, dim)

def linear_scaled_rope(dim: int, seq_len: int, scale: float,
                       base: int = 10000) -> torch.Tensor:
    """Linear position interpolation: map position m -> m/s.
    Extended positions are compressed into the pretrained range [0, train_len]."""
    inv_freq = 1.0 / (base ** (torch.arange(0, dim, 2).float() / dim))
    t = torch.arange(seq_len, dtype=torch.float32) / scale  # <-- interpolation
    freqs = torch.outer(t, inv_freq)
    return torch.cat([freqs, freqs], dim=-1)

# Verify: 16K context with s=4 stays within the 4K training distribution
train_len, ext_len, s = 4096, 16384, 4.0
emb_orig   = standard_rope(64, train_len)
emb_scaled = linear_scaled_rope(64, ext_len, scale=s)
print(f"Standard max rotation angle  : {emb_orig.max().item():.4f} rad")
print(f"Scaled-4x max rotation angle : {emb_scaled.max().item():.4f} rad")
aligned = torch.allclose(emb_scaled[:train_len], emb_orig, atol=1e-5)
print(f"First 4096 positions match training distribution: {aligned}")
```

## Out-of-Distribution Positions

When a model trained on 4096 tokens receives a 16384-token sequence without any RoPE modification, positions 4097–16384 produce rotation angles 4x larger than anything seen during training. The attention dot products depend on sin and cos of these angles, so the attention pattern is completely disrupted. Empirically, perplexity rises from roughly 6 at 4K to over 100 at 16K — the model essentially fails to process long documents coherently. The effect is asymmetric across RoPE dimensions: high-frequency dimensions (pairs 0–10) complete many full rotations and may accidentally land near a trained value by periodicity, but low-frequency dimensions (pairs d/2-10 to d/2-1) produce angles that have never been seen and carry no signal. The model’s long-range attention heads simply stop functioning.

## Linear Interpolation Scaling

The fix is to replace position index m with m/s throughout the RoPE computation. With s=4 and a 16384-token sequence, position 16383 becomes effective position 4095.75. The model never sees a rotation angle larger than those at position 4095, exactly as during training. The interpolation is mathematically clean: the set of effective positions is {0, 1/s, 2/s, …, (N-1)/s} which densely covers [0, N/s] = [0, train_len]. Unlike extrapolation (which leaves the trained distribution), interpolation stays within it. The cost is resolution: with s=4, two tokens that are 4 positions apart share an effective position difference of only 1 — the model must use finer-grained distinctions than it was trained on for nearby tokens.

```python
import torch
from transformers import LlamaConfig, LlamaForCausalLM, AutoTokenizer

def load_llama_linear_scaling(
        model_id: str = "meta-llama/Llama-2-7b-hf",
        scaling_factor: float = 4.0,
        target_ctx: int = 16384) -> tuple:
    """Apply linear RoPE interpolation to Llama-2-7B for 16K-token inference."""
    config = LlamaConfig.from_pretrained(model_id)
    # HuggingFace built-in linear RoPE scaling patches LlamaRotaryEmbedding
    config.rope_scaling = {"type": "linear", "factor": scaling_factor}
    config.max_position_embeddings = target_ctx
    model = LlamaForCausalLM.from_pretrained(
        model_id, config=config,
        torch_dtype=torch.float16, device_map="auto"
    )
    tokenizer = AutoTokenizer.from_pretrained(model_id)
    n_params = sum(p.numel() for p in model.parameters()) / 1e9
    print(f"Loaded {n_params:.1f}B params | context window = {target_ctx} tokens")
    return model, tokenizer

def long_context_generate(model, tokenizer, document: str,
                          max_new: int = 64) -> str:
    """Run causal inference on a document up to 15K tokens."""
    inputs = tokenizer(document, return_tensors="pt",
                       truncation=True, max_length=15000).to(model.device)
    n_in = inputs["input_ids"].shape[-1]
    with torch.no_grad():
        out = model.generate(**inputs, max_new_tokens=max_new, do_sample=False)
    completion = tokenizer.decode(out[0, n_in:], skip_special_tokens=True)
    print(f"Input: {n_in} tokens | Generated: {len(out[0]) - n_in} tokens")
    return completion

print("Usage: model, tok = load_llama_linear_scaling(); long_context_generate(model, tok, doc)")
```

## The Scaling Factor s

The scale factor s is set to target_length / train_length. For a 4K model targeting 16K, s=4; for 8K, s=2. The trade-off between extension ratio and quality is steep: at s=2, perplexity degrades by only 0.3–0.5 PPL zero-shot; at s=4, degradation is 1.5–2.5 PPL without fine-tuning; at s=8, the model requires mandatory fine-tuning to be useful. This behaviour arises because higher s values place more tokens at the same effective position index, degrading the model’s ability to distinguish tokens that are close together in the original sequence. The original paper (Chen et al.) recommends s ≤ 4 for zero-shot use and up to s=8 with fine-tuning. In practice, s=2 (the LongLoRA configuration) and s=4 (the Llama-2-Long configuration) are the most common deployments.

```python
import torch
import numpy as np
from transformers import AutoModelForCausalLM, AutoTokenizer

def eval_ppl_by_length(model, tokenizer, text: str,
                       lengths: list, device: str = "cpu") -> dict:
    """Compute per-token NLL loss (perplexity) at increasing sequence lengths."""
    tokens = tokenizer(text, return_tensors="pt")["input_ids"].to(device)
    model.eval()
    results = {}
    for L in lengths:
        if tokens.shape[1] < L:
            break
        chunk = tokens[:, :L]
        with torch.no_grad():
            loss = model(chunk, labels=chunk).loss.item()
        results[L] = round(2.718281828 ** loss, 2)
    return results

# Representative PPL values showing the effect of linear scaling
lengths      = [4096, 6144, 8192, 12288, 16384]
ppl_no_scale = [6.1,  9.8,  19.4,  58.1,  147.3]   # diverges OOD
ppl_scaled   = [6.1,  6.4,   6.9,   7.5,    8.2]   # graceful with s=4

print(f"{'Length':>8}  {'No Scaling':>12}  {'Linear s=4':>12}  {'Ratio':>8}")
for L, ns, sc in zip(lengths, ppl_no_scale, ppl_scaled):
    ratio = ns / sc
    flag = " !!" if ns > 20 else ""
    print(f"{L:>8}  {ns:>12.1f}  {sc:>12.1f}  {ratio:>7.1f}x{flag}")
```

| Method | Max reliable extension | Fine-tuning needed | PPL at 2x | PPL at 4x | Notes |
| --- | --- | --- | --- | --- | --- |
| No scaling | 1x (training length) | N/A | 18+ (OOD) | 100+ (OOD) | Catastrophic beyond train window |
| Linear interpolation | 4–8x | Optional (recommended for s>2) | 6.4 | 8.2 | Uniform position compression; simple 1-line patch |
| NTK-aware scaling | 4–8x | Not required for s≤4 | 6.3 | 7.4 | Preserves high-freq dims; better zero-shot than linear |
| YaRN | 8–32x | 400–1000 steps for s>4 | 6.2 | 6.9 | Piecewise per-dim scaling + temperature; state-of-the-art |
| Full fine-tuning | Arbitrary | Required (full training budget) | 6.1 | 6.1 | Best quality but expensive; baseline upper bound |

> **Position Compression Trade-off**: Linear interpolation compresses all positions uniformly — the model sees effective position 0.25 where it was trained on position 1. At scale factors above 4x, attention patterns blur because nearby tokens share almost identical effective positions. Without fine-tuning, this causes the model to lose fine-grained local syntactic distinctions. Always pair s>2 with at least 200 fine-tuning steps on long documents.

## Fine-tuning Requirements

Linear scaling works reasonably zero-shot for s≤2, but for s=4–8 a brief fine-tuning phase on long documents dramatically recovers performance. Chen et al. show that 1000 gradient steps on sequences of the target length brings perplexity within 0.5 PPL of a model fully pretrained at that length. The fine-tuning setup is: a dataset of long documents (10K–100K examples), a learning rate 10× smaller than pretraining (1e-5 for Llama-2), and a cosine or constant LR schedule. The model adapts its attention patterns to the compressed position space, learning which interpolated positions correspond to meaningful token distances. Even 200 steps provides a significant recovery — a practical trade-off when GPU time is constrained. The Llama-2-Long model (Meta, 2023) was produced by this recipe at s=4 for 16K context.

```python
import torch
from transformers import Trainer, TrainingArguments, DataCollatorForLanguageModeling

def print_recovery_table() -> None:
    """Show perplexity at 16K tokens as a function of fine-tuning steps.
    Demonstrates that ~1000 steps recovers most of the PPL gap."""
    # (steps, PPL@16K) after linear s=4 scaling + fine-tuning on long documents
    checkpoints = [
        (0,    8.2),   # zero-shot linear scaling, no fine-tuning
        (200,  7.6),   # early fine-tuning
        (500,  7.1),   # mid fine-tuning
        (1000, 6.7),   # near-converged: within 0.6 PPL of 4K baseline
        (2000, 6.4),   # converged: indistinguishable from full retraining
    ]
    baseline = 6.1   # PPL at 4K with standard RoPE (reference lower bound)
    print(f"{'Steps':>8}  {'PPL@16K':>10}  {'Gap vs 4K':>12}  {'Recovery%':>12}")
    print("-" * 50)
    for steps, ppl in checkpoints:
        gap = ppl - baseline
        recovery = 100.0 * (8.2 - ppl) / (8.2 - baseline)
        print(f"{steps:>8}  {ppl:>10.2f}  {gap:>+12.2f}  {recovery:>11.1f}%")

print_recovery_table()
```

## Limitations

Linear interpolation has two fundamental limitations. First, it applies uniform compression to all RoPE dimensions regardless of their frequency. High-frequency dimensions (which encode local syntactic structure) and low-frequency dimensions (which encode long-range document structure) both get their positions divided by the same factor s. High-frequency dimensions are particularly sensitive to this compression because they rely on fine-grained position differences to distinguish tokens within a short window. Dividing all positions by s blurs these local distinctions even at positions that are well within the original training range. Second, the method does not address the aliasing problem: with s=4, tokens at effective positions 1.0, 1.25, 1.5, and 1.75 are all crammed between training positions 1 and 2, making it harder for the model to distinguish them. NTK-aware scaling and YaRN are specifically designed to address these limitations.

- Uniform position compression degrades high-frequency RoPE dimensions that capture local syntax
- Perplexity degrades quickly at s>4 without fine-tuning due to position aliasing
- Does not preserve the wavelength spectrum of different RoPE dimension pairs
- Performance drops more for tasks requiring precise local token ordering (e.g., code generation)
- Not suitable as a zero-shot drop-in for s>4; always validate PPL before deployment
- Fine-tuning is required to close the gap at large scale factors, adding training cost

## Key Takeaways

Linear position interpolation is the simplest, most widely deployed RoPE context extension method and the baseline against which all others are measured. It requires a one-line change to the RoPE position index computation, no architectural modification, and no change to model weights for zero-shot use. For s≤2, it works well out-of-the-box with negligible PPL cost. For s=4, a brief fine-tuning phase of 500–1000 steps on long documents recovers quality close to full retraining. The method is natively supported in HuggingFace Transformers and is used in production by Llama-2-Long, Code Llama (100K context), and many other models. For extensions beyond s=4 or zero-shot quality requirements, NTK-aware scaling (which modifies the RoPE base frequency) and YaRN (which applies piecewise scaling per frequency band) offer better results.

- Set rope_scaling={'type': 'linear', 'factor': s} in HuggingFace config — zero code changes
- s=2 is safe zero-shot; s=4 benefits from 500+ fine-tuning steps; s=8 requires fine-tuning
- Interpolation stays within the pretrained RoPE distribution; extrapolation does not
- The method is a one-line patch: divide position indices by s before computing sin/cos
- PPL degradation is roughly exponential in s without fine-tuning
- Baseline comparison point for NTK-aware scaling and YaRN

