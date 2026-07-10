---
title: "YaRN: Yet Another RoPE Extension Method"
slug: "yarn-rope-extension"
description: "A piecewise RoPE scaling strategy that applies different scaling to different frequency bands — no interpolation for high-frequency, linear for mid-frequency, NTK for low-frequency — achieving state-of-the-art long context with minimal fine-tuning."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"YaRN (Yet Another RoPE extensioN; Peng et al., 2023) is the current state-of-the-art method for extending LLM context windows with minimal fine-tuning. Where linear interpolation applies uniform position compression and NTK scaling applies graduated base rescaling, YaRN takes a more principled approach: it classifies each RoPE dimension pair into a frequency band and applies a different scaling strategy per band. High-frequency dimensions (those with wavelength shorter than a threshold) are left completely unscaled — they already extrapolate well. Low-frequency dimensions (wavelength longer than a second threshold) receive linear interpolation. Mid-frequency dimensions receive a smooth blend. This piecewise treatment, combined with an attention temperature correction, yields perplexity within 0.2–0.5 PPL of full retraining at context lengths up to 128K with only 400 fine-tuning steps."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"YaRN was introduced by Peng et al. (2023) specifically to address limitations of both linear interpolation and NTK-aware scaling. Linear interpolation hurts high-frequency dimensions; NTK scaling is theoretically motivated but does not optimally handle mid-frequency dimensions. YaRN introduces two innovations: (1) a piecewise scaling function that uses no scaling for high-frequency dimensions (wavelength \u003c 2π * beta_fast), linear scaling for low-frequency dimensions (wavelength \u003e 2π * beta_slow), and a smooth ramp blend for mid-frequency dimensions; and (2) an attention temperature correction that multiplies the softmax temperature by 1/sqrt(t) where t is derived from the scale factor. Together these innovations allow models like Llama-2-7B to operate at 64K or 128K context with only 400 gradient steps of fine-tuning and near-baseline perplexity."},{"type":"heading","level":2,"content":"Piecewise Scaling Strategy"},{"type":"text","content":"The core idea of YaRN is that different RoPE frequency components have different out-of-distribution (OOD) sensitivity. High-frequency components (large theta_i, short wavelength 2π/theta_i) naturally wrap around many times over a long sequence — their sin/cos values are densely distributed in [-1, 1] regardless of sequence length, so they generalise well. Low-frequency components (small theta_i, long wavelength) only execute a partial rotation over the training length; extending the sequence to 8x the training length requires the model to handle rotation angles it has never seen. These low-frequency components need strong interpolation. Mid-frequency components need a blend. YaRN implements this insight with a smooth ramp function alpha(i) that transitions from 0 (pure linear interpolation) to 1 (no interpolation) as wavelength decreases."},{"type":"math","display":true,"content":"\\tilde{\\theta}_i = \\alpha(i)\\,\\theta_i + (1-\\alpha(i))\\,\\frac{\\theta_i}{s}, \\quad \\alpha(i) = \\mathrm{clamp}\\!\\left(\\frac{\\lambda_i - 2\\pi\\beta_{\\mathrm{slow}}}{2\\pi(\\beta_{\\mathrm{fast}} - \\beta_{\\mathrm{slow}})},\\, 0,\\, 1\\right)"},{"type":"text","content":"In the YaRN formula, lambda_i = 2*pi/theta_i is the wavelength of dimension pair i. beta_fast and beta_slow are hyperparameters that define the frequency band boundaries; the paper uses beta_fast=32 and beta_slow=1 as defaults. When alpha(i) = 1, the dimension is high-frequency and receives no scaling: theta_tilde_i = theta_i. When alpha(i) = 0, the dimension is low-frequency and receives pure linear interpolation: theta_tilde_i = theta_i / s. The smooth ramp ensures no sharp discontinuities in the frequency spectrum. An alternative but equivalent formulation blends the original inverse frequency with the NTK-scaled inverse frequency using the same ramp."},{"type":"heading","level":2,"content":"Frequency Band Classification"},{"type":"text","content":"For Llama-2-7B with head dimension d=128 and beta_fast=32, beta_slow=1, the classification boundaries are: wavelength \u003c 2*pi*1 = 6.28 (high-frequency, no scaling) and wavelength \u003e 2*pi*32 = 201 (low-frequency, linear interpolation). Dimension pairs 0–5 have wavelengths in the range 6.28–42 and fall in the high-frequency regime (alpha ≈ 0.9–1.0). Dimension pairs 40–63 have wavelengths \u003e 201 and fall in the low-frequency regime (alpha ≈ 0). The mid-frequency band contains dimension pairs 6–39. Importantly, the exact thresholds beta_fast and beta_slow can be tuned for different model sizes and target context lengths; the paper provides default values that work well across Llama-2-7B through 70B."},{"type":"code","language":"python","content":"import torch\nimport math\n\ndef yarn_rope(dim: int, seq_len: int, scale: float,\n             base: int = 10000, beta_fast: int = 32,\n             beta_slow: int = 1) -\u003e torch.Tensor:\n    \"\"\"YaRN piecewise RoPE: different scaling per frequency band.\n    High-freq (short wavelength): no interpolation.\n    Low-freq  (long wavelength): linear interpolation.\n    Mid-freq: smooth blend via ramp function alpha(i).\"\"\"\n    d_half = torch.arange(0, dim, 2).float()\n    inv_freq_orig = 1.0 / (base ** (d_half / dim))    # original inv frequencies\n    wavelengths   = 2 * math.pi / inv_freq_orig        # per-dim wavelength (dim/2,)\n\n    # Band boundaries in wavelength space\n    lo = 2 * math.pi * beta_slow    # below lo: high-freq (no scaling)\n    hi = 2 * math.pi * beta_fast    # above hi: low-freq (linear interp)\n\n    # Ramp alpha(i): 1 = no interpolation (high-freq), 0 = full interpolation (low-freq)\n    alpha = ((wavelengths - lo) / (hi - lo)).clamp(0.0, 1.0)\n\n    # NTK base for the low-frequency blending component\n    ntk_base     = base * (scale ** (dim / (dim - 2)))\n    inv_freq_ntk = 1.0 / (ntk_base ** (d_half / dim))\n\n    # Blended inverse frequency: high-freq keeps original, low-freq uses NTK\n    inv_freq_yarn = alpha * inv_freq_orig + (1.0 - alpha) * inv_freq_ntk\n\n    t = torch.arange(seq_len, dtype=torch.float32)\n    freqs = torch.outer(t, inv_freq_yarn)\n    return torch.cat([freqs, freqs], dim=-1)\n\nemb = yarn_rope(128, 32768, scale=8.0)\nprint(f\"YaRN emb shape: {emb.shape}\")\nprint(f\"Max angle: {emb.max().item():.3f} | Min angle: {emb.min().item():.3f}\")"},{"type":"heading","level":2,"content":"Temperature Correction"},{"type":"text","content":"YaRN introduces a second innovation: attention temperature correction. When context length increases, the attention distribution over a longer key sequence becomes more diffuse — each query’s attention is spread over more tokens, reducing the average attention weight per token. This softening of attention can cause the model to lose focus on the most relevant context. YaRN addresses this by multiplying the attention scale factor by 1/sqrt(t), where t = 0.1 * ln(scale) + 1.0. This shrinks the softmax denominator, sharpening the attention distribution to compensate for the longer context. At scale=1 (original context), t=1 and the correction is neutral. At scale=8, t ≈ 1.208 and the attention scale is reduced by a factor of 1/sqrt(1.208) ≈ 0.91. The correction is applied uniformly across all heads and layers."},{"type":"code","language":"python","content":"import torch\nimport math\nfrom typing import Optional\n\ndef rotate_half(x: torch.Tensor) -\u003e torch.Tensor:\n    half = x.shape[-1] // 2\n    return torch.cat([-x[..., half:], x[..., :half]], dim=-1)\n\ndef apply_rope(x: torch.Tensor, freqs: torch.Tensor) -\u003e torch.Tensor:\n    cos = freqs.cos()[:x.shape[-2], :x.shape[-1]]\n    sin = freqs.sin()[:x.shape[-2], :x.shape[-1]]\n    return x * cos + rotate_half(x) * sin\n\ndef yarn_attention(q: torch.Tensor, k: torch.Tensor, v: torch.Tensor,\n                  rope_emb: torch.Tensor, scale: float) -\u003e torch.Tensor:\n    \"\"\"YaRN-style attention with temperature correction 1/sqrt(t).\n    Counteracts attention diffusion at extended sequence lengths.\"\"\"\n    q_r = apply_rope(q, rope_emb)\n    k_r = apply_rope(k, rope_emb)\n    # YaRN temperature: t \u003e= 1, increases with scale factor\n    t_yarn    = 0.1 * math.log(max(scale, 1.0)) + 1.0\n    attn_scale = 1.0 / (math.sqrt(q.shape[-1]) * math.sqrt(t_yarn))\n    scores    = torch.matmul(q_r, k_r.transpose(-2, -1)) * attn_scale\n    weights   = torch.softmax(scores, dim=-1)\n    return weights @ v\n\n# Show temperature factor across scale factors\nprint(f\"{\u0027Scale\u0027:\u003e8}  {\u0027t_yarn\u0027:\u003e8}  {\u00271/sqrt(t)\u0027:\u003e12}  {\u0027Std 1/sqrt(d)\u0027:\u003e15}\")\nfor s in [1.0, 2.0, 4.0, 8.0, 16.0]:\n    t = 0.1 * math.log(s) + 1.0 if s \u003e 1 else 1.0\n    d = 128\n    print(f\"{s:\u003e8.1f}  {t:\u003e8.4f}  {1/math.sqrt(t):\u003e12.6f}  {1/math.sqrt(d):\u003e15.6f}\")"},{"type":"heading","level":2,"content":"YaRN Fine-tuning Protocol"},{"type":"text","content":"YaRN achieves near-full-retrain quality with only 400 gradient steps on long documents. The recommended fine-tuning protocol is: (1) load a 4K-pretrained model with YaRN rope_scaling config; (2) fine-tune on a dataset of long documents sampled to the target context length; (3) use a cosine learning rate schedule with peak LR = 2e-5 (Llama-2-7B) or 1e-5 (Llama-2-13B); (4) run for 400 steps with batch size 1–2 per GPU and gradient accumulation to 8–16 effective batch size. The paper reports that 400 steps on the RedPajama dataset (sampled to 64K tokens) brings Llama-2-7B to 7.4 PPL at 64K context, compared to 7.2 PPL for 1000 steps. The fine-tuning data mix should include documents at the full target length — short documents padded or repeated do not help the model learn long-range dependencies."},{"type":"code","language":"python","content":"import torch\nfrom transformers import LlamaConfig, LlamaForCausalLM, Trainer, TrainingArguments\nfrom peft import LoraConfig, get_peft_model\n\ndef setup_yarn_finetune(\n        model_id: str = \"meta-llama/Llama-2-7b-hf\",\n        yarn_scale: float = 8.0,\n        target_len: int = 32768) -\u003e LlamaForCausalLM:\n    \"\"\"Configure YaRN-scaled Llama-2 for efficient long-context fine-tuning.\"\"\"\n    config = LlamaConfig.from_pretrained(model_id)\n    config.rope_scaling = {\n        \"type\": \"yarn\", \"factor\": yarn_scale,\n        \"original_max_position_embeddings\": 4096\n    }\n    config.max_position_embeddings = target_len\n    model = LlamaForCausalLM.from_pretrained(\n        model_id, config=config, torch_dtype=torch.bfloat16\n    )\n    return model\n\n# Simulated PPL at key context lengths before and after 400-step YaRN fine-tuning\nctx_lengths = [4096, 8192, 16384, 32768]\nbefore_ft   = [6.1,  8.9,  17.3,  42.1]   # zero-shot YaRN (no fine-tuning)\nafter_ft    = [6.1,  6.5,   6.9,   7.4]   # after 400 gradient steps\n\nprint(f\"{\u0027Context\u0027:\u003e10}  {\u0027Zero-shot YaRN\u0027:\u003e16}  {\u0027After 400 steps\u0027:\u003e17}\")\nfor ctx, b, a in zip(ctx_lengths, before_ft, after_ft):\n    improvement = b - a\n    print(f\"{ctx:\u003e10}  {b:\u003e16.1f}  {a:\u003e17.1f}  (gain: {improvement:.1f})\")"},{"type":"heading","level":2,"content":"Context Window Extension Results"},{"type":"text","content":"The YaRN paper reports results on Llama-2-7B and 13B extended to 64K and 128K tokens. At 64K context with 400 fine-tuning steps, Llama-2-7B achieves 7.4 PPL on the PG19 long-document benchmark, compared to 8.8 PPL for NTK-dynamic (zero-shot) and 147+ PPL for no-scaling. Passkey retrieval — a synthetic test that embeds a 5-digit key deep in a long document — is used to measure whether the model can actually access information at all positions. YaRN models achieve near-perfect passkey retrieval (\u003e99% accuracy) at all positions up to the target context length after fine-tuning, while NTK-dynamic models degrade below 50% retrieval accuracy at positions beyond 16K. The temperature correction is responsible for roughly 0.3–0.5 PPL improvement over ablations without it."},{"type":"code","language":"python","content":"import torch\nimport random\nimport string\nfrom transformers import AutoModelForCausalLM, AutoTokenizer\n\ndef passkey_retrieval_test(model, tokenizer, doc_len: int = 32768,\n                           key_pos_frac: float = 0.5) -\u003e bool:\n    \"\"\"Embed a 5-digit passkey in a long filler document and test retrieval.\"\"\"\n    key = \"\".join(random.choices(string.digits, k=5))\n    filler = \"The quick brown fox jumps over the lazy dog. \" * 500\n    words  = filler.split()\n    insert_idx = int(len(words) * key_pos_frac)\n    words.insert(insert_idx, f\"PASSKEY={key}.\")\n    question = \"What is the passkey? Answer with just the digits. Passkey:\"\n    prompt   = \" \".join(words) + \" \" + question\n    inputs   = tokenizer(prompt, return_tensors=\"pt\",\n                         truncation=True, max_length=doc_len).to(model.device)\n    seq_in   = inputs[\"input_ids\"].shape[-1]\n    with torch.no_grad():\n        out = model.generate(**inputs, max_new_tokens=8, do_sample=False)\n    answer  = tokenizer.decode(out[0, seq_in:], skip_special_tokens=True)\n    correct = key in answer\n    print(f\"pos_frac={key_pos_frac:.2f}  key={key}  answer={answer[:10]}  ok={correct}\")\n    return correct"},{"type":"heading","level":2,"content":"Comparison with Prior Methods"},{"type":"text","content":"YaRN is strictly better than linear interpolation and NTK-aware scaling on long-context benchmarks when fine-tuning is available. Without fine-tuning, YaRN’s zero-shot performance is slightly better than NTK-dynamic (due to the more precise piecewise classification) but the gap narrows. The key advantage of YaRN is its behaviour at very large scale factors (s=8–32): it can extend to 64K–128K context with only 400 steps of fine-tuning, while linear interpolation and NTK scaling degrade substantially at these scales even with fine-tuning. The temperature correction is unique to YaRN and accounts for a meaningful PPL improvement, particularly on tasks requiring the model to attend over very long spans. In practice, YaRN is the recommended method when the target context is 16K+ and a small fine-tuning budget is available."},{"type":"table","headers":["Method","Scaling type","PPL at 8K","PPL at 32K","Fine-tune steps","Llama-2 support"],"rows":[["Linear interpolation","Uniform position /s","8.9","52+","1000+ recommended","rope_scaling linear"],["NTK-dynamic","Graduated base scaling","7.8","18+","Not required (zero-shot)","rope_scaling dynamic"],["YaRN (64K target)","Piecewise per-dim + temp","6.8","7.4","400 steps","rope_scaling yarn"],["YaRN (128K target)","Piecewise per-dim + temp","7.1","7.6","400–1000 steps","rope_scaling yarn"],["Full retrain at 32K","N/A (native 32K)","6.3","6.5","Full training budget","N/A (would need full retrain)"]]},{"type":"callout","variant":"tip","title":"YaRN’s Core Insight","content":"YaRN’s key innovation is recognising that different RoPE frequency bands have fundamentally different OOD sensitivities. High-frequency dimensions (capturing local syntax within a few tokens) extrapolate well and need no interpolation. Low-frequency dimensions (capturing position across hundreds of tokens) are strongly OOD at extended lengths and need linear interpolation. The piecewise ramp applies the right treatment to each band, giving the best of both worlds. Add temperature correction (1/sqrt(t)) and 400 fine-tuning steps to get state-of-the-art long-context performance."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"YaRN is the recommended method for extending LLM context windows to 16K–128K when a small fine-tuning budget is available. Its piecewise frequency band classification avoids the core failures of linear interpolation (hurts high-frequency dims) and NTK scaling (imprecise mid-frequency handling). The attention temperature correction is a simple multiplicative factor that meaningfully improves performance at long range. YaRN is supported natively in HuggingFace Transformers for recent Llama and Mistral models. The 400-step fine-tuning protocol is practical even on consumer GPUs using QLoRA or full fine-tuning on a single A100. For zero-shot use without any fine-tuning, NTK-dynamic is preferred for its lower implementation complexity; YaRN’s advantage mainly manifests after fine-tuning."},{"type":"list","ordered":false,"items":["Piecewise scaling: no interpolation for high-freq dims (wavelength \u003c 2π×beta_fast), linear for low-freq dims","Temperature correction: multiply attention scale by 1/sqrt(0.1*ln(s)+1) to counteract attention diffusion","400 gradient steps on long documents achieves near-full-retrain quality at 64K context","Default hyperparameters: base=10000, beta_fast=32, beta_slow=1; tunable per model size","HuggingFace: rope_scaling={\u0027type\u0027: \u0027yarn\u0027, \u0027factor\u0027: s, \u0027original_max_position_embeddings\u0027: 4096}","Passkey retrieval accuracy \u003e99% at all positions up to target context after fine-tuning"]}]"
---
# YaRN: Yet Another RoPE Extension Method

YaRN (Yet Another RoPE extensioN; Peng et al., 2023) is the current state-of-the-art method for extending LLM context windows with minimal fine-tuning. Where linear interpolation applies uniform position compression and NTK scaling applies graduated base rescaling, YaRN takes a more principled approach: it classifies each RoPE dimension pair into a frequency band and applies a different scaling strategy per band. High-frequency dimensions (those with wavelength shorter than a threshold) are left completely unscaled — they already extrapolate well. Low-frequency dimensions (wavelength longer than a second threshold) receive linear interpolation. Mid-frequency dimensions receive a smooth blend. This piecewise treatment, combined with an attention temperature correction, yields perplexity within 0.2–0.5 PPL of full retraining at context lengths up to 128K with only 400 fine-tuning steps.

## Overview

YaRN was introduced by Peng et al. (2023) specifically to address limitations of both linear interpolation and NTK-aware scaling. Linear interpolation hurts high-frequency dimensions; NTK scaling is theoretically motivated but does not optimally handle mid-frequency dimensions. YaRN introduces two innovations: (1) a piecewise scaling function that uses no scaling for high-frequency dimensions (wavelength < 2π * beta_fast), linear scaling for low-frequency dimensions (wavelength > 2π * beta_slow), and a smooth ramp blend for mid-frequency dimensions; and (2) an attention temperature correction that multiplies the softmax temperature by 1/sqrt(t) where t is derived from the scale factor. Together these innovations allow models like Llama-2-7B to operate at 64K or 128K context with only 400 gradient steps of fine-tuning and near-baseline perplexity.

## Piecewise Scaling Strategy

The core idea of YaRN is that different RoPE frequency components have different out-of-distribution (OOD) sensitivity. High-frequency components (large theta_i, short wavelength 2π/theta_i) naturally wrap around many times over a long sequence — their sin/cos values are densely distributed in [-1, 1] regardless of sequence length, so they generalise well. Low-frequency components (small theta_i, long wavelength) only execute a partial rotation over the training length; extending the sequence to 8x the training length requires the model to handle rotation angles it has never seen. These low-frequency components need strong interpolation. Mid-frequency components need a blend. YaRN implements this insight with a smooth ramp function alpha(i) that transitions from 0 (pure linear interpolation) to 1 (no interpolation) as wavelength decreases.

$$\tilde{\theta}_i = \alpha(i)\,\theta_i + (1-\alpha(i))\,\frac{\theta_i}{s}, \quad \alpha(i) = \mathrm{clamp}\!\left(\frac{\lambda_i - 2\pi\beta_{\mathrm{slow}}}{2\pi(\beta_{\mathrm{fast}} - \beta_{\mathrm{slow}})},\, 0,\, 1\right)$$

In the YaRN formula, lambda_i = 2*pi/theta_i is the wavelength of dimension pair i. beta_fast and beta_slow are hyperparameters that define the frequency band boundaries; the paper uses beta_fast=32 and beta_slow=1 as defaults. When alpha(i) = 1, the dimension is high-frequency and receives no scaling: theta_tilde_i = theta_i. When alpha(i) = 0, the dimension is low-frequency and receives pure linear interpolation: theta_tilde_i = theta_i / s. The smooth ramp ensures no sharp discontinuities in the frequency spectrum. An alternative but equivalent formulation blends the original inverse frequency with the NTK-scaled inverse frequency using the same ramp.

## Frequency Band Classification

For Llama-2-7B with head dimension d=128 and beta_fast=32, beta_slow=1, the classification boundaries are: wavelength < 2*pi*1 = 6.28 (high-frequency, no scaling) and wavelength > 2*pi*32 = 201 (low-frequency, linear interpolation). Dimension pairs 0–5 have wavelengths in the range 6.28–42 and fall in the high-frequency regime (alpha ≈ 0.9–1.0). Dimension pairs 40–63 have wavelengths > 201 and fall in the low-frequency regime (alpha ≈ 0). The mid-frequency band contains dimension pairs 6–39. Importantly, the exact thresholds beta_fast and beta_slow can be tuned for different model sizes and target context lengths; the paper provides default values that work well across Llama-2-7B through 70B.

```python
import torch
import math

def yarn_rope(dim: int, seq_len: int, scale: float,
             base: int = 10000, beta_fast: int = 32,
             beta_slow: int = 1) -> torch.Tensor:
    """YaRN piecewise RoPE: different scaling per frequency band.
    High-freq (short wavelength): no interpolation.
    Low-freq  (long wavelength): linear interpolation.
    Mid-freq: smooth blend via ramp function alpha(i)."""
    d_half = torch.arange(0, dim, 2).float()
    inv_freq_orig = 1.0 / (base ** (d_half / dim))    # original inv frequencies
    wavelengths   = 2 * math.pi / inv_freq_orig        # per-dim wavelength (dim/2,)

    # Band boundaries in wavelength space
    lo = 2 * math.pi * beta_slow    # below lo: high-freq (no scaling)
    hi = 2 * math.pi * beta_fast    # above hi: low-freq (linear interp)

    # Ramp alpha(i): 1 = no interpolation (high-freq), 0 = full interpolation (low-freq)
    alpha = ((wavelengths - lo) / (hi - lo)).clamp(0.0, 1.0)

    # NTK base for the low-frequency blending component
    ntk_base     = base * (scale ** (dim / (dim - 2)))
    inv_freq_ntk = 1.0 / (ntk_base ** (d_half / dim))

    # Blended inverse frequency: high-freq keeps original, low-freq uses NTK
    inv_freq_yarn = alpha * inv_freq_orig + (1.0 - alpha) * inv_freq_ntk

    t = torch.arange(seq_len, dtype=torch.float32)
    freqs = torch.outer(t, inv_freq_yarn)
    return torch.cat([freqs, freqs], dim=-1)

emb = yarn_rope(128, 32768, scale=8.0)
print(f"YaRN emb shape: {emb.shape}")
print(f"Max angle: {emb.max().item():.3f} | Min angle: {emb.min().item():.3f}")
```

## Temperature Correction

YaRN introduces a second innovation: attention temperature correction. When context length increases, the attention distribution over a longer key sequence becomes more diffuse — each query’s attention is spread over more tokens, reducing the average attention weight per token. This softening of attention can cause the model to lose focus on the most relevant context. YaRN addresses this by multiplying the attention scale factor by 1/sqrt(t), where t = 0.1 * ln(scale) + 1.0. This shrinks the softmax denominator, sharpening the attention distribution to compensate for the longer context. At scale=1 (original context), t=1 and the correction is neutral. At scale=8, t ≈ 1.208 and the attention scale is reduced by a factor of 1/sqrt(1.208) ≈ 0.91. The correction is applied uniformly across all heads and layers.

```python
import torch
import math
from typing import Optional

def rotate_half(x: torch.Tensor) -> torch.Tensor:
    half = x.shape[-1] // 2
    return torch.cat([-x[..., half:], x[..., :half]], dim=-1)

def apply_rope(x: torch.Tensor, freqs: torch.Tensor) -> torch.Tensor:
    cos = freqs.cos()[:x.shape[-2], :x.shape[-1]]
    sin = freqs.sin()[:x.shape[-2], :x.shape[-1]]
    return x * cos + rotate_half(x) * sin

def yarn_attention(q: torch.Tensor, k: torch.Tensor, v: torch.Tensor,
                  rope_emb: torch.Tensor, scale: float) -> torch.Tensor:
    """YaRN-style attention with temperature correction 1/sqrt(t).
    Counteracts attention diffusion at extended sequence lengths."""
    q_r = apply_rope(q, rope_emb)
    k_r = apply_rope(k, rope_emb)
    # YaRN temperature: t >= 1, increases with scale factor
    t_yarn    = 0.1 * math.log(max(scale, 1.0)) + 1.0
    attn_scale = 1.0 / (math.sqrt(q.shape[-1]) * math.sqrt(t_yarn))
    scores    = torch.matmul(q_r, k_r.transpose(-2, -1)) * attn_scale
    weights   = torch.softmax(scores, dim=-1)
    return weights @ v

# Show temperature factor across scale factors
print(f"{'Scale':>8}  {'t_yarn':>8}  {'1/sqrt(t)':>12}  {'Std 1/sqrt(d)':>15}")
for s in [1.0, 2.0, 4.0, 8.0, 16.0]:
    t = 0.1 * math.log(s) + 1.0 if s > 1 else 1.0
    d = 128
    print(f"{s:>8.1f}  {t:>8.4f}  {1/math.sqrt(t):>12.6f}  {1/math.sqrt(d):>15.6f}")
```

## YaRN Fine-tuning Protocol

YaRN achieves near-full-retrain quality with only 400 gradient steps on long documents. The recommended fine-tuning protocol is: (1) load a 4K-pretrained model with YaRN rope_scaling config; (2) fine-tune on a dataset of long documents sampled to the target context length; (3) use a cosine learning rate schedule with peak LR = 2e-5 (Llama-2-7B) or 1e-5 (Llama-2-13B); (4) run for 400 steps with batch size 1–2 per GPU and gradient accumulation to 8–16 effective batch size. The paper reports that 400 steps on the RedPajama dataset (sampled to 64K tokens) brings Llama-2-7B to 7.4 PPL at 64K context, compared to 7.2 PPL for 1000 steps. The fine-tuning data mix should include documents at the full target length — short documents padded or repeated do not help the model learn long-range dependencies.

```python
import torch
from transformers import LlamaConfig, LlamaForCausalLM, Trainer, TrainingArguments
from peft import LoraConfig, get_peft_model

def setup_yarn_finetune(
        model_id: str = "meta-llama/Llama-2-7b-hf",
        yarn_scale: float = 8.0,
        target_len: int = 32768) -> LlamaForCausalLM:
    """Configure YaRN-scaled Llama-2 for efficient long-context fine-tuning."""
    config = LlamaConfig.from_pretrained(model_id)
    config.rope_scaling = {
        "type": "yarn", "factor": yarn_scale,
        "original_max_position_embeddings": 4096
    }
    config.max_position_embeddings = target_len
    model = LlamaForCausalLM.from_pretrained(
        model_id, config=config, torch_dtype=torch.bfloat16
    )
    return model

# Simulated PPL at key context lengths before and after 400-step YaRN fine-tuning
ctx_lengths = [4096, 8192, 16384, 32768]
before_ft   = [6.1,  8.9,  17.3,  42.1]   # zero-shot YaRN (no fine-tuning)
after_ft    = [6.1,  6.5,   6.9,   7.4]   # after 400 gradient steps

print(f"{'Context':>10}  {'Zero-shot YaRN':>16}  {'After 400 steps':>17}")
for ctx, b, a in zip(ctx_lengths, before_ft, after_ft):
    improvement = b - a
    print(f"{ctx:>10}  {b:>16.1f}  {a:>17.1f}  (gain: {improvement:.1f})")
```

## Context Window Extension Results

The YaRN paper reports results on Llama-2-7B and 13B extended to 64K and 128K tokens. At 64K context with 400 fine-tuning steps, Llama-2-7B achieves 7.4 PPL on the PG19 long-document benchmark, compared to 8.8 PPL for NTK-dynamic (zero-shot) and 147+ PPL for no-scaling. Passkey retrieval — a synthetic test that embeds a 5-digit key deep in a long document — is used to measure whether the model can actually access information at all positions. YaRN models achieve near-perfect passkey retrieval (>99% accuracy) at all positions up to the target context length after fine-tuning, while NTK-dynamic models degrade below 50% retrieval accuracy at positions beyond 16K. The temperature correction is responsible for roughly 0.3–0.5 PPL improvement over ablations without it.

```python
import torch
import random
import string
from transformers import AutoModelForCausalLM, AutoTokenizer

def passkey_retrieval_test(model, tokenizer, doc_len: int = 32768,
                           key_pos_frac: float = 0.5) -> bool:
    """Embed a 5-digit passkey in a long filler document and test retrieval."""
    key = "".join(random.choices(string.digits, k=5))
    filler = "The quick brown fox jumps over the lazy dog. " * 500
    words  = filler.split()
    insert_idx = int(len(words) * key_pos_frac)
    words.insert(insert_idx, f"PASSKEY={key}.")
    question = "What is the passkey? Answer with just the digits. Passkey:"
    prompt   = " ".join(words) + " " + question
    inputs   = tokenizer(prompt, return_tensors="pt",
                         truncation=True, max_length=doc_len).to(model.device)
    seq_in   = inputs["input_ids"].shape[-1]
    with torch.no_grad():
        out = model.generate(**inputs, max_new_tokens=8, do_sample=False)
    answer  = tokenizer.decode(out[0, seq_in:], skip_special_tokens=True)
    correct = key in answer
    print(f"pos_frac={key_pos_frac:.2f}  key={key}  answer={answer[:10]}  ok={correct}")
    return correct
```

## Comparison with Prior Methods

YaRN is strictly better than linear interpolation and NTK-aware scaling on long-context benchmarks when fine-tuning is available. Without fine-tuning, YaRN’s zero-shot performance is slightly better than NTK-dynamic (due to the more precise piecewise classification) but the gap narrows. The key advantage of YaRN is its behaviour at very large scale factors (s=8–32): it can extend to 64K–128K context with only 400 steps of fine-tuning, while linear interpolation and NTK scaling degrade substantially at these scales even with fine-tuning. The temperature correction is unique to YaRN and accounts for a meaningful PPL improvement, particularly on tasks requiring the model to attend over very long spans. In practice, YaRN is the recommended method when the target context is 16K+ and a small fine-tuning budget is available.

| Method | Scaling type | PPL at 8K | PPL at 32K | Fine-tune steps | Llama-2 support |
| --- | --- | --- | --- | --- | --- |
| Linear interpolation | Uniform position /s | 8.9 | 52+ | 1000+ recommended | rope_scaling linear |
| NTK-dynamic | Graduated base scaling | 7.8 | 18+ | Not required (zero-shot) | rope_scaling dynamic |
| YaRN (64K target) | Piecewise per-dim + temp | 6.8 | 7.4 | 400 steps | rope_scaling yarn |
| YaRN (128K target) | Piecewise per-dim + temp | 7.1 | 7.6 | 400–1000 steps | rope_scaling yarn |
| Full retrain at 32K | N/A (native 32K) | 6.3 | 6.5 | Full training budget | N/A (would need full retrain) |

> **YaRN’s Core Insight**: YaRN’s key innovation is recognising that different RoPE frequency bands have fundamentally different OOD sensitivities. High-frequency dimensions (capturing local syntax within a few tokens) extrapolate well and need no interpolation. Low-frequency dimensions (capturing position across hundreds of tokens) are strongly OOD at extended lengths and need linear interpolation. The piecewise ramp applies the right treatment to each band, giving the best of both worlds. Add temperature correction (1/sqrt(t)) and 400 fine-tuning steps to get state-of-the-art long-context performance.

## Key Takeaways

YaRN is the recommended method for extending LLM context windows to 16K–128K when a small fine-tuning budget is available. Its piecewise frequency band classification avoids the core failures of linear interpolation (hurts high-frequency dims) and NTK scaling (imprecise mid-frequency handling). The attention temperature correction is a simple multiplicative factor that meaningfully improves performance at long range. YaRN is supported natively in HuggingFace Transformers for recent Llama and Mistral models. The 400-step fine-tuning protocol is practical even on consumer GPUs using QLoRA or full fine-tuning on a single A100. For zero-shot use without any fine-tuning, NTK-dynamic is preferred for its lower implementation complexity; YaRN’s advantage mainly manifests after fine-tuning.

- Piecewise scaling: no interpolation for high-freq dims (wavelength < 2π×beta_fast), linear for low-freq dims
- Temperature correction: multiply attention scale by 1/sqrt(0.1*ln(s)+1) to counteract attention diffusion
- 400 gradient steps on long documents achieves near-full-retrain quality at 64K context
- Default hyperparameters: base=10000, beta_fast=32, beta_slow=1; tunable per model size
- HuggingFace: rope_scaling={'type': 'yarn', 'factor': s, 'original_max_position_embeddings': 4096}
- Passkey retrieval accuracy >99% at all positions up to target context after fine-tuning

