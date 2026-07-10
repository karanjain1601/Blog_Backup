---
title: "Position Interpolation for Long Context LLMs"
slug: "positional-interpolation"
description: "The Position Interpolation (PI) paper's approach to extending context by fine-tuning with interpolated positions, establishing the recipe used by many long-context variants of Llama."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Position Interpolation (Chen et al., 2023) is a method for extending the context window of Rotary Position Embedding (RoPE)-based LLMs without full retraining. The core insight is that extrapolating beyond the trained maximum position causes catastrophic perplexity collapse: RoPE embeddings at unseen positions produce rotation angles that are entirely out-of-distribution for every attention head in every layer. Position Interpolation avoids this by down-scaling all token positions so they always lie within the original training range [0, L), then fine-tuning for a trivially small number of steps to re-adapt the model to the compressed scale. This paper established the foundational recipe that dozens of Llama variants — LongChat, LongAlpaca, CodeLlama, and LongLLaMA — adopted for affordable context extension at a fraction of the original pretraining cost."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Pre-trained RoPE models have a hard context ceiling: position indices 0 through L-1 (e.g., 0–2047 for LLaMA-1). When inference extends to position L or beyond, the RoPE rotation frequencies θ_i × p for those indices were never seen during training. The PI approach remaps position p to p_scaled = p × (L/L\u0027), where L is the original max length and L\u0027 is the target extended length. At the last valid position L\u0027-1, the remapped value is (L\u0027-1) × (L/L\u0027) ≈ L-1, keeping all positions in-distribution. A brief fine-tuning run of 200–1000 steps on mixed-length next-token prediction data adapts the model to the new scale. Extending LLaMA-7B from 2K to 32K costs roughly 0.01% of the original pretraining compute — a watershed result demonstrating that context extension is a cheap engineering problem."},{"type":"heading","level":2,"content":"The PI Formula"},{"type":"text","content":"RoPE encodes position p by rotating each pair of head dimensions (x_{2i}, x_{2i+1}) by angle p × θ_i, where θ_i = 10000^{-2i/d} and d is the head dimension. The query-key attention score contains terms proportional to cos((p-q) × θ_i) — a relative positional encoding. At positions beyond L, the angle differences (p-q) × θ_i involve values never seen during training, causing cosine/sine outputs to land in unexpected regions of the embedding space. PI replaces p with p_interp = p × (L/L\u0027) throughout all RoPE computations. The scale factor L/L\u0027 \u003c 1 compresses all positions into [0, L), preserving the model\u0027s learned rotational geometry. The relative angle difference for positions p and q becomes (p-q) × (L/L\u0027) × θ_i — smaller absolute differences but always within the trained distribution of angle magnitudes."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom transformers import LlamaForCausalLM\n\nclass PIRoPE(nn.Module):\n    # Rotary Position Embedding with Position Interpolation (Chen et al., 2023)\n    # Compresses position indices into [0, orig_max_len) via a fixed scale factor\n    def __init__(self, dim: int, orig_max_len: int = 2048, new_max_len: int = 32768):\n        super().__init__()\n        self.scale = orig_max_len / new_max_len  # \u003c 1.0 for any extension\n        inv_freq = 1.0 / (10000 ** (torch.arange(0, dim, 2).float() / dim))\n        self.register_buffer(\u0027inv_freq\u0027, inv_freq)\n\n    def forward(self, x: torch.Tensor, seq_len: int):\n        # Interpolated positions always stay in [0, orig_max_len) regardless of seq_len\n        t = torch.arange(seq_len, device=x.device).float() * self.scale\n        freqs = torch.outer(t, self.inv_freq)\n        emb = torch.cat((freqs, freqs), dim=-1)\n        return emb.cos().unsqueeze(0).unsqueeze(0), emb.sin().unsqueeze(0).unsqueeze(0)\n\ndef patch_rope_pi(model: LlamaForCausalLM, new_max_len: int = 32768) -\u003e LlamaForCausalLM:\n    # Replace all RoPE modules in-place with position-interpolating variants\n    orig = model.config.max_position_embeddings\n    for layer in model.model.layers:\n        head_dim = layer.self_attn.rotary_emb.dim\n        layer.self_attn.rotary_emb = PIRoPE(head_dim, orig, new_max_len)\n    model.config.max_position_embeddings = new_max_len\n    print(f\u0027PI patch: scale={orig/new_max_len:.4f}, context {orig} -\u003e {new_max_len}\u0027)\n    return model"},{"type":"heading","level":2,"content":"Training Protocol"},{"type":"text","content":"After applying the PI patch, a short fine-tuning run re-adapts the model to the compressed position scale. The Chen et al. protocol: fine-tune for 200–1000 steps with next-token prediction loss on documents up to the new maximum length. Documents shorter than the target length are concatenated to fill context windows; no padding is required. Training data should match the pretraining distribution — typically a mix of English web text and code from the same sources used for pretraining. Learning rate is set to 2e-5, consistent with standard instruction-tuning. The paper shows 200 steps suffices for 8× extension, and 1000 steps provides stability at 16×. With 8×A100 80GB GPUs and Flash Attention 2, fine-tuning LLaMA-7B to 32K context at 1000 steps takes 4–8 hours — trivial relative to thousands of GPU-hours for pretraining."},{"type":"code","language":"python","content":"import random\nimport torch\nfrom transformers import AutoTokenizer, AutoModelForCausalLM\n\ndef build_passkey_prompt(passkey: str, depth: float, reps: int = 200) -\u003e str:\n    # Place a secret passkey at fractional depth inside a long filler document\n    filler = \u0027Researchers observed no statistically significant effect in this condition. \u0027 * reps\n    pos = int(depth * len(filler))\n    needle = f\u0027 [THE SECRET PASSKEY IS: {passkey}] \u0027\n    return filler[:pos] + needle + filler[pos:] + \u0027\\nQuestion: What is the secret passkey? Answer:\u0027\n\ndef eval_passkey_retrieval(model, tokenizer, ctx_len: int,\n                           depths: list, n_each: int = 5) -\u003e dict:\n    # Measure retrieval accuracy at each depth fraction for the given context length\n    results = {}\n    for depth in depths:\n        hits = 0\n        for _ in range(n_each):\n            pk = str(random.randint(10000, 99999))\n            prompt = build_passkey_prompt(pk, depth)\n            ids = tokenizer(prompt, return_tensors=\u0027pt\u0027, truncation=True,\n                            max_length=ctx_len).input_ids.to(model.device)\n            with torch.no_grad():\n                out = model.generate(ids, max_new_tokens=10)\n            text = tokenizer.decode(out[0][ids.shape[1]:], skip_special_tokens=True)\n            hits += int(pk in text)\n        results[f\u0027{depth:.0%}\u0027] = hits / n_each\n        print(f\u0027  depth={depth:.0%}: {hits}/{n_each} correct\u0027)\n    return results\n\ndepths = [0.0, 0.25, 0.5, 0.75, 1.0]\nprint(f\u0027Passkey benchmark depths: {[f\"{d:.0%}\" for d in depths]}\u0027)"},{"type":"heading","level":2,"content":"Effective Context Length"},{"type":"text","content":"Perplexity is an unreliable proxy for effective context length. A model can achieve low perplexity at 32K tokens while failing to retrieve information from beyond 4K — because perplexity averages over all tokens and is dominated by local context. Passkey retrieval provides a precise binary signal: embed a random 5-digit number at a controlled fractional position in a long filler document, then query the model for it. PI-fine-tuned LLaMA-2-7B achieves near-perfect passkey retrieval up to its extended context length, while the baseline collapses beyond 4K regardless of depth. Effective context length is formally defined as the largest L at which retrieval accuracy exceeds 90% across all five depth positions (0%, 25%, 50%, 75%, 100%). This benchmark is now standard for long-context model evaluation."},{"type":"code","language":"python","content":"import numpy as np\n\ndef simulate_curriculum_mixing(base_max: int = 2048, target_max: int = 32768,\n                               total_steps: int = 1000, short_frac: float = 0.8):\n    # Curriculum: 80% short docs + 20% extended docs; extended length ramps up gradually\n    schedule = []\n    for step in range(total_steps):\n        progress = step / total_steps\n        # Extended doc length grows from 2x base to target_max over training\n        ext_len = int(base_max * 2 + progress * (target_max - base_max * 2))\n        ext_len = min(ext_len, target_max)\n        if np.random.rand() \u003c short_frac:\n            doc_len = int(np.random.randint(256, base_max))\n            label = \u0027short\u0027\n        else:\n            doc_len = ext_len\n            label = \u0027extended\u0027\n        schedule.append({\u0027step\u0027: step, \u0027len\u0027: doc_len, \u0027type\u0027: label})\n    ext_lens = [s[\u0027len\u0027] for s in schedule if s[\u0027type\u0027] == \u0027extended\u0027]\n    short_ct = sum(1 for s in schedule if s[\u0027type\u0027] == \u0027short\u0027)\n    print(f\u0027Short steps: {short_ct}, Extended steps: {len(ext_lens)}\u0027)\n    print(f\u0027Mean extended length at step 1000: {np.mean(ext_lens[-100:]):.0f} tokens\u0027)\n    return schedule"},{"type":"heading","level":2,"content":"Extension Ratios and Limits"},{"type":"text","content":"The extension ratio is L\u0027/L — the factor by which context is extended. PI is practically tested at 2×, 4×, 8×, 16×, and 32×. Without fine-tuning, PI achieves only marginal perplexity improvement over naive extrapolation at ratios ≥4×. With fine-tuning, 8× is stable and 16× shows modest PPL degradation. Beyond 32×, the interpolation scale becomes so small (scale \u003c 0.03 for 32× extension of a 2K model) that distinct positions within the extended window map to nearly identical angle values, making it impossible for the model to distinguish nearby positions. At this point, retrieval accuracy drops sharply regardless of fine-tuning budget. The practical ceiling for uniform PI is 16–32×; for larger windows, YaRN or LongRoPE significantly outperform uniform PI."},{"type":"code","language":"python","content":"import numpy as np\n\ndef extension_ratio_sweep() -\u003e None:\n    # Approximate LLaMA-7B results from Chen et al. (2023) on PG19 perplexity\n    ratios          = [1,    2,    4,    8,    16,    32    ]\n    ppl_no_finetune = [7.2,  9.8,  18.4, 42.1, 210.3, 8500.0]\n    ppl_finetuned   = [7.2,  7.4,  7.7,  8.1,  9.8,   24.5  ]\n    ppl_extrap      = [7.2,  15.6, 280.4, 5200, None,  None  ]\n    passkey_acc     = [1.00, 0.98, 0.95, 0.91, 0.74,  0.21  ]\n    print(f\u0027{\"Ratio\":\u003e7} | {\"No-FT PPL\":\u003e10} | {\"FT PPL\":\u003e8} | {\"PK Acc\":\u003e8}\u0027)\n    print(\u0027-\u0027 * 42)\n    for r, pno, pft, pk in zip(ratios, ppl_no_finetune, ppl_finetuned, passkey_acc):\n        print(f\u0027{r:\u003e6}x | {pno:\u003e10.1f} | {pft:\u003e8.1f} | {pk:\u003e8.2f}\u0027)\n    good = [r for r, pk in zip(ratios, passkey_acc) if pk \u003e= 0.90]\n    print(f\u0027\\nRatios with passkey accuracy \u003e= 90%: {good}\u0027)\n\nextension_ratio_sweep()"},{"type":"table","headers":["Extension Ratio","Fine-tune Steps","Training Data Max Len","PPL at 1x","PPL at Extension","Passkey Accuracy"],"rows":[["2x (2K → 4K)","200","4096 tokens","7.2","7.4","98%"],["4x (2K → 8K)","400","8192 tokens","7.2","7.7","95%"],["8x (2K → 16K)","800","16384 tokens","7.2","8.1","91%"],["16x (2K → 32K)","1000","32768 tokens","7.2","9.8","74%"],["32x (2K → 64K)","2000+","65536 tokens","7.2","24.5","21%"]]},{"type":"heading","level":2,"content":"Comparison with Extrapolation"},{"type":"text","content":"Naive RoPE extrapolation yields perplexity of ~280 at only 4× extension (versus 7.7 with PI fine-tuning) and diverges entirely beyond that. This is because RoPE frequency basis functions are periodic — at positions beyond the training window, patterns repeat with a different phase than expected, corrupting all attention scores simultaneously. ALiBi (Attention with Linear Biases, Press et al., 2022) enables extrapolation by replacing RoPE with a position-independent attention bias learned during pretraining; however ALiBi must be incorporated at pretraining time and cannot be patched into an existing RoPE model. YaRN (Peng et al., 2023) applies non-uniform interpolation: high-frequency RoPE components (small dimension index i, large θ_i) are scaled less aggressively than low-frequency ones, preserving short-range relative position sensitivity while extending long-range capacity. YaRN outperforms uniform PI at all extension ratios and has become the de-facto successor."},{"type":"callout","variant":"info","title":"PI Was a Watershed Result","content":"The PI paper showed that 1000 fine-tuning steps (trivial compute) with interpolated positions can extend context from 2K to 32K — this was a watershed result showing context extension is cheap relative to pretraining. Most long-context Llama derivatives (LongChat, LongAlpaca, CodeLlama) adopted this recipe directly."},{"type":"heading","level":2,"content":"LongLlama and Follow-on Work"},{"type":"text","content":"LongLLaMA (Tworkowski et al., 2023) combines PI with the Focused Transformer (FoT) architecture — a memory mechanism that retrieves relevant KV pairs from a large external memory store at each forward pass — achieving effective contexts of 256K tokens on PASSKEY benchmarks. LongChat (Dacheng Li et al., 2023) applied PI to LLaMA-1 at 16K and evaluated on multi-turn conversation topic retrieval tasks. LongAlpaca (Chen et al., 2023) added PI to LLaMA-2 with instruction-tuning on summarization data, demonstrating that instruction-following quality is preserved. CodeLlama (Rozière et al., 2023) extended to 100K context using PI with 16K fine-tuning data, achieving superior performance on repository-level code completion. YaRN and LongRoPE subsequently improved position scaling with non-uniform and per-dimension methods respectively."},{"type":"list","ordered":false,"items":["LongChat (2023): PI applied to LLaMA-1 at 16K tokens, evaluated on multi-turn topic retrieval.","LongAlpaca (2023): PI plus instruction tuning on summarization data at 32K with LLaMA-2 base.","LongLLaMA (2023): PI combined with Focused Transformer memory, effective 256K context on PASSKEY.","CodeLlama (2023): PI to 100K tokens for long-code generation on LLaMA-2 base.","YaRN (2023): Non-uniform position scaling; high-frequency RoPE components scaled less aggressively.","LongRoPE (2024): Learned per-dimension scaling factors for context extension up to 2M tokens."]},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Position Interpolation demonstrated that extending RoPE-based context windows is a low-cost engineering problem with a clean solution: compress positions into the trained range, then fine-tune briefly to re-adapt. The method requires no architecture changes — only the RoPE forward method is modified — making it trivially applicable to any pretrained RoPE model. Its practical ceiling is 16–32× extension with uniform scaling; YaRN and LongRoPE provide better results beyond that. PI remains the most widely deployed context extension technique due to its simplicity, strong open-source tooling, and the broad availability of PI-extended checkpoints for the LLaMA model family."},{"type":"list","ordered":false,"items":["PI formula: pos_interp(p) = p × (L/L\u0027), where L is the original max length and L\u0027 is the extended length.","Fine-tuning is mandatory: PI without fine-tuning provides minimal improvement over raw extrapolation.","200 steps sufficient for 8x extension; 1000 steps recommended for 16x extension stability.","Use mixed-length training data: 80% short docs + 20% extended docs during fine-tuning.","Passkey retrieval accuracy is the gold standard metric, not perplexity, for effective context length.","For 32x+ extension, prefer YaRN (non-uniform scaling) over uniform PI for better retrieval accuracy.","The PI patch is architecture-agnostic: swap the rotary_emb module with PIRoPE to enable extension."]},{"type":"divider"}]"
---
# Position Interpolation for Long Context LLMs

Position Interpolation (Chen et al., 2023) is a method for extending the context window of Rotary Position Embedding (RoPE)-based LLMs without full retraining. The core insight is that extrapolating beyond the trained maximum position causes catastrophic perplexity collapse: RoPE embeddings at unseen positions produce rotation angles that are entirely out-of-distribution for every attention head in every layer. Position Interpolation avoids this by down-scaling all token positions so they always lie within the original training range [0, L), then fine-tuning for a trivially small number of steps to re-adapt the model to the compressed scale. This paper established the foundational recipe that dozens of Llama variants — LongChat, LongAlpaca, CodeLlama, and LongLLaMA — adopted for affordable context extension at a fraction of the original pretraining cost.

## Overview

Pre-trained RoPE models have a hard context ceiling: position indices 0 through L-1 (e.g., 0–2047 for LLaMA-1). When inference extends to position L or beyond, the RoPE rotation frequencies θ_i × p for those indices were never seen during training. The PI approach remaps position p to p_scaled = p × (L/L'), where L is the original max length and L' is the target extended length. At the last valid position L'-1, the remapped value is (L'-1) × (L/L') ≈ L-1, keeping all positions in-distribution. A brief fine-tuning run of 200–1000 steps on mixed-length next-token prediction data adapts the model to the new scale. Extending LLaMA-7B from 2K to 32K costs roughly 0.01% of the original pretraining compute — a watershed result demonstrating that context extension is a cheap engineering problem.

## The PI Formula

RoPE encodes position p by rotating each pair of head dimensions (x_{2i}, x_{2i+1}) by angle p × θ_i, where θ_i = 10000^{-2i/d} and d is the head dimension. The query-key attention score contains terms proportional to cos((p-q) × θ_i) — a relative positional encoding. At positions beyond L, the angle differences (p-q) × θ_i involve values never seen during training, causing cosine/sine outputs to land in unexpected regions of the embedding space. PI replaces p with p_interp = p × (L/L') throughout all RoPE computations. The scale factor L/L' < 1 compresses all positions into [0, L), preserving the model's learned rotational geometry. The relative angle difference for positions p and q becomes (p-q) × (L/L') × θ_i — smaller absolute differences but always within the trained distribution of angle magnitudes.

```python
import torch
import torch.nn as nn
from transformers import LlamaForCausalLM

class PIRoPE(nn.Module):
    # Rotary Position Embedding with Position Interpolation (Chen et al., 2023)
    # Compresses position indices into [0, orig_max_len) via a fixed scale factor
    def __init__(self, dim: int, orig_max_len: int = 2048, new_max_len: int = 32768):
        super().__init__()
        self.scale = orig_max_len / new_max_len  # < 1.0 for any extension
        inv_freq = 1.0 / (10000 ** (torch.arange(0, dim, 2).float() / dim))
        self.register_buffer('inv_freq', inv_freq)

    def forward(self, x: torch.Tensor, seq_len: int):
        # Interpolated positions always stay in [0, orig_max_len) regardless of seq_len
        t = torch.arange(seq_len, device=x.device).float() * self.scale
        freqs = torch.outer(t, self.inv_freq)
        emb = torch.cat((freqs, freqs), dim=-1)
        return emb.cos().unsqueeze(0).unsqueeze(0), emb.sin().unsqueeze(0).unsqueeze(0)

def patch_rope_pi(model: LlamaForCausalLM, new_max_len: int = 32768) -> LlamaForCausalLM:
    # Replace all RoPE modules in-place with position-interpolating variants
    orig = model.config.max_position_embeddings
    for layer in model.model.layers:
        head_dim = layer.self_attn.rotary_emb.dim
        layer.self_attn.rotary_emb = PIRoPE(head_dim, orig, new_max_len)
    model.config.max_position_embeddings = new_max_len
    print(f'PI patch: scale={orig/new_max_len:.4f}, context {orig} -> {new_max_len}')
    return model
```

## Training Protocol

After applying the PI patch, a short fine-tuning run re-adapts the model to the compressed position scale. The Chen et al. protocol: fine-tune for 200–1000 steps with next-token prediction loss on documents up to the new maximum length. Documents shorter than the target length are concatenated to fill context windows; no padding is required. Training data should match the pretraining distribution — typically a mix of English web text and code from the same sources used for pretraining. Learning rate is set to 2e-5, consistent with standard instruction-tuning. The paper shows 200 steps suffices for 8× extension, and 1000 steps provides stability at 16×. With 8×A100 80GB GPUs and Flash Attention 2, fine-tuning LLaMA-7B to 32K context at 1000 steps takes 4–8 hours — trivial relative to thousands of GPU-hours for pretraining.

```python
import random
import torch
from transformers import AutoTokenizer, AutoModelForCausalLM

def build_passkey_prompt(passkey: str, depth: float, reps: int = 200) -> str:
    # Place a secret passkey at fractional depth inside a long filler document
    filler = 'Researchers observed no statistically significant effect in this condition. ' * reps
    pos = int(depth * len(filler))
    needle = f' [THE SECRET PASSKEY IS: {passkey}] '
    return filler[:pos] + needle + filler[pos:] + '\nQuestion: What is the secret passkey? Answer:'

def eval_passkey_retrieval(model, tokenizer, ctx_len: int,
                           depths: list, n_each: int = 5) -> dict:
    # Measure retrieval accuracy at each depth fraction for the given context length
    results = {}
    for depth in depths:
        hits = 0
        for _ in range(n_each):
            pk = str(random.randint(10000, 99999))
            prompt = build_passkey_prompt(pk, depth)
            ids = tokenizer(prompt, return_tensors='pt', truncation=True,
                            max_length=ctx_len).input_ids.to(model.device)
            with torch.no_grad():
                out = model.generate(ids, max_new_tokens=10)
            text = tokenizer.decode(out[0][ids.shape[1]:], skip_special_tokens=True)
            hits += int(pk in text)
        results[f'{depth:.0%}'] = hits / n_each
        print(f'  depth={depth:.0%}: {hits}/{n_each} correct')
    return results

depths = [0.0, 0.25, 0.5, 0.75, 1.0]
print(f'Passkey benchmark depths: {[f"{d:.0%}" for d in depths]}')
```

## Effective Context Length

Perplexity is an unreliable proxy for effective context length. A model can achieve low perplexity at 32K tokens while failing to retrieve information from beyond 4K — because perplexity averages over all tokens and is dominated by local context. Passkey retrieval provides a precise binary signal: embed a random 5-digit number at a controlled fractional position in a long filler document, then query the model for it. PI-fine-tuned LLaMA-2-7B achieves near-perfect passkey retrieval up to its extended context length, while the baseline collapses beyond 4K regardless of depth. Effective context length is formally defined as the largest L at which retrieval accuracy exceeds 90% across all five depth positions (0%, 25%, 50%, 75%, 100%). This benchmark is now standard for long-context model evaluation.

```python
import numpy as np

def simulate_curriculum_mixing(base_max: int = 2048, target_max: int = 32768,
                               total_steps: int = 1000, short_frac: float = 0.8):
    # Curriculum: 80% short docs + 20% extended docs; extended length ramps up gradually
    schedule = []
    for step in range(total_steps):
        progress = step / total_steps
        # Extended doc length grows from 2x base to target_max over training
        ext_len = int(base_max * 2 + progress * (target_max - base_max * 2))
        ext_len = min(ext_len, target_max)
        if np.random.rand() < short_frac:
            doc_len = int(np.random.randint(256, base_max))
            label = 'short'
        else:
            doc_len = ext_len
            label = 'extended'
        schedule.append({'step': step, 'len': doc_len, 'type': label})
    ext_lens = [s['len'] for s in schedule if s['type'] == 'extended']
    short_ct = sum(1 for s in schedule if s['type'] == 'short')
    print(f'Short steps: {short_ct}, Extended steps: {len(ext_lens)}')
    print(f'Mean extended length at step 1000: {np.mean(ext_lens[-100:]):.0f} tokens')
    return schedule
```

## Extension Ratios and Limits

The extension ratio is L'/L — the factor by which context is extended. PI is practically tested at 2×, 4×, 8×, 16×, and 32×. Without fine-tuning, PI achieves only marginal perplexity improvement over naive extrapolation at ratios ≥4×. With fine-tuning, 8× is stable and 16× shows modest PPL degradation. Beyond 32×, the interpolation scale becomes so small (scale < 0.03 for 32× extension of a 2K model) that distinct positions within the extended window map to nearly identical angle values, making it impossible for the model to distinguish nearby positions. At this point, retrieval accuracy drops sharply regardless of fine-tuning budget. The practical ceiling for uniform PI is 16–32×; for larger windows, YaRN or LongRoPE significantly outperform uniform PI.

```python
import numpy as np

def extension_ratio_sweep() -> None:
    # Approximate LLaMA-7B results from Chen et al. (2023) on PG19 perplexity
    ratios          = [1,    2,    4,    8,    16,    32    ]
    ppl_no_finetune = [7.2,  9.8,  18.4, 42.1, 210.3, 8500.0]
    ppl_finetuned   = [7.2,  7.4,  7.7,  8.1,  9.8,   24.5  ]
    ppl_extrap      = [7.2,  15.6, 280.4, 5200, None,  None  ]
    passkey_acc     = [1.00, 0.98, 0.95, 0.91, 0.74,  0.21  ]
    print(f'{"Ratio":>7} | {"No-FT PPL":>10} | {"FT PPL":>8} | {"PK Acc":>8}')
    print('-' * 42)
    for r, pno, pft, pk in zip(ratios, ppl_no_finetune, ppl_finetuned, passkey_acc):
        print(f'{r:>6}x | {pno:>10.1f} | {pft:>8.1f} | {pk:>8.2f}')
    good = [r for r, pk in zip(ratios, passkey_acc) if pk >= 0.90]
    print(f'\nRatios with passkey accuracy >= 90%: {good}')

extension_ratio_sweep()
```

| Extension Ratio | Fine-tune Steps | Training Data Max Len | PPL at 1x | PPL at Extension | Passkey Accuracy |
| --- | --- | --- | --- | --- | --- |
| 2x (2K → 4K) | 200 | 4096 tokens | 7.2 | 7.4 | 98% |
| 4x (2K → 8K) | 400 | 8192 tokens | 7.2 | 7.7 | 95% |
| 8x (2K → 16K) | 800 | 16384 tokens | 7.2 | 8.1 | 91% |
| 16x (2K → 32K) | 1000 | 32768 tokens | 7.2 | 9.8 | 74% |
| 32x (2K → 64K) | 2000+ | 65536 tokens | 7.2 | 24.5 | 21% |

## Comparison with Extrapolation

Naive RoPE extrapolation yields perplexity of ~280 at only 4× extension (versus 7.7 with PI fine-tuning) and diverges entirely beyond that. This is because RoPE frequency basis functions are periodic — at positions beyond the training window, patterns repeat with a different phase than expected, corrupting all attention scores simultaneously. ALiBi (Attention with Linear Biases, Press et al., 2022) enables extrapolation by replacing RoPE with a position-independent attention bias learned during pretraining; however ALiBi must be incorporated at pretraining time and cannot be patched into an existing RoPE model. YaRN (Peng et al., 2023) applies non-uniform interpolation: high-frequency RoPE components (small dimension index i, large θ_i) are scaled less aggressively than low-frequency ones, preserving short-range relative position sensitivity while extending long-range capacity. YaRN outperforms uniform PI at all extension ratios and has become the de-facto successor.

> **PI Was a Watershed Result**: The PI paper showed that 1000 fine-tuning steps (trivial compute) with interpolated positions can extend context from 2K to 32K — this was a watershed result showing context extension is cheap relative to pretraining. Most long-context Llama derivatives (LongChat, LongAlpaca, CodeLlama) adopted this recipe directly.

## LongLlama and Follow-on Work

LongLLaMA (Tworkowski et al., 2023) combines PI with the Focused Transformer (FoT) architecture — a memory mechanism that retrieves relevant KV pairs from a large external memory store at each forward pass — achieving effective contexts of 256K tokens on PASSKEY benchmarks. LongChat (Dacheng Li et al., 2023) applied PI to LLaMA-1 at 16K and evaluated on multi-turn conversation topic retrieval tasks. LongAlpaca (Chen et al., 2023) added PI to LLaMA-2 with instruction-tuning on summarization data, demonstrating that instruction-following quality is preserved. CodeLlama (Rozière et al., 2023) extended to 100K context using PI with 16K fine-tuning data, achieving superior performance on repository-level code completion. YaRN and LongRoPE subsequently improved position scaling with non-uniform and per-dimension methods respectively.

- LongChat (2023): PI applied to LLaMA-1 at 16K tokens, evaluated on multi-turn topic retrieval.
- LongAlpaca (2023): PI plus instruction tuning on summarization data at 32K with LLaMA-2 base.
- LongLLaMA (2023): PI combined with Focused Transformer memory, effective 256K context on PASSKEY.
- CodeLlama (2023): PI to 100K tokens for long-code generation on LLaMA-2 base.
- YaRN (2023): Non-uniform position scaling; high-frequency RoPE components scaled less aggressively.
- LongRoPE (2024): Learned per-dimension scaling factors for context extension up to 2M tokens.

## Key Takeaways

Position Interpolation demonstrated that extending RoPE-based context windows is a low-cost engineering problem with a clean solution: compress positions into the trained range, then fine-tune briefly to re-adapt. The method requires no architecture changes — only the RoPE forward method is modified — making it trivially applicable to any pretrained RoPE model. Its practical ceiling is 16–32× extension with uniform scaling; YaRN and LongRoPE provide better results beyond that. PI remains the most widely deployed context extension technique due to its simplicity, strong open-source tooling, and the broad availability of PI-extended checkpoints for the LLaMA model family.

- PI formula: pos_interp(p) = p × (L/L'), where L is the original max length and L' is the extended length.
- Fine-tuning is mandatory: PI without fine-tuning provides minimal improvement over raw extrapolation.
- 200 steps sufficient for 8x extension; 1000 steps recommended for 16x extension stability.
- Use mixed-length training data: 80% short docs + 20% extended docs during fine-tuning.
- Passkey retrieval accuracy is the gold standard metric, not perplexity, for effective context length.
- For 32x+ extension, prefer YaRN (non-uniform scaling) over uniform PI for better retrieval accuracy.
- The PI patch is architecture-agnostic: swap the rotary_emb module with PIRoPE to enable extension.

---

