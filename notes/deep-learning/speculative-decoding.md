---
title: "Speculative Decoding"
slug: "speculative-decoding"
description: "Using a small draft model to propose multiple tokens that the large target model verifies in parallel, reducing wall-clock generation time without changing output distribution."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Speculative decoding (Chen et al., 2023; Leviathan et al., 2023) is a lossless inference acceleration technique that decouples token proposal from token verification. A small, fast draft model autoregressively generates k candidate tokens in sequence. The large target model then evaluates all k+1 positions in a single forward pass — producing its own probability distributions at each position. A rejection-sampling procedure accepts or rejects each draft token while provably preserving the target model\u0027s output distribution. The net effect: the target model processes multiple tokens per forward pass instead of one, reducing the total number of expensive target forward passes needed to generate a sequence."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Modern large language model inference is memory-bandwidth bound, not compute bound. At batch size 1, the GPU spends most of its time loading 70–140 GB of model weights from HBM to SRAM for each forward pass — the actual matrix multiplication is secondary. Speculative decoding exploits this asymmetry: since the target model\u0027s forward pass is latency-dominated by memory transfers rather than FLOPs, verifying k tokens in one pass takes only marginally more time than verifying 1. Meanwhile, the draft model is 10–100x smaller and can produce k proposals in a fraction of the time a single target forward pass takes. If the draft model\u0027s proposals are accepted at rate alpha, the expected tokens produced per target forward pass is (1 - alpha^(k+1)) / (1 - alpha), giving a theoretical speedup of that quantity divided by 1 (greedy baseline). At alpha=0.8 and k=5, this is roughly 3.5 tokens per target pass — a 3.5x throughput gain."},{"type":"heading","level":2,"content":"Draft-Verify Mechanism"},{"type":"text","content":"The draft-verify loop proceeds as follows. Given input context x_{1:t}, the draft model generates k tokens autoregressively: for each step i in 1..k, it samples x_{t+i} ~ q(. | x_{1:t+i-1}) where q is the draft model\u0027s distribution. This produces a sequence of k draft tokens and their associated draft probabilities q_i = q(x_{t+i} | x_{1:t+i-1}). Next, the target model is called once with the full candidate sequence x_{1:t+k} and returns logits for all t+k positions simultaneously. The target probabilities at each draft position are p_i = p(x_{t+i} | x_{1:t+i-1}). The rejection sampling loop then iterates i from 1 to k: if p_i / q_i \u003e= 1, token i is always accepted; otherwise token i is accepted with probability p_i / q_i and rejected with probability 1 - p_i / q_i. On rejection, a corrected token is sampled from the residual distribution max(0, p_i - q_i) / Z."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nfrom transformers import AutoModelForCausalLM\nfrom typing import Tuple, List\n\ndef speculative_decode(\n    target_model, draft_model, input_ids: torch.Tensor,\n    k: int = 5, temperature: float = 1.0\n) -\u003e Tuple[torch.Tensor, float]:\n    \"\"\"Draft proposes k tokens; target verifies all in one forward pass.\"\"\"\n    draft_input = input_ids.clone()\n    draft_tokens: List[torch.Tensor] = []\n    draft_probs: List[float] = []\n    for _ in range(k):\n        with torch.no_grad():\n            logits = draft_model(draft_input).logits[:, -1, :] / temperature\n            probs = F.softmax(logits, dim=-1)\n            tok = torch.multinomial(probs, 1)\n            draft_tokens.append(tok)\n            draft_probs.append(probs[0, tok.item()].item())\n            draft_input = torch.cat([draft_input, tok], dim=-1)\n    candidate_ids = torch.cat([input_ids] + draft_tokens, dim=-1)\n    with torch.no_grad():\n        target_logits = target_model(candidate_ids).logits\n    accepted: List[torch.Tensor] = []\n    n = len(input_ids[0])\n    for i, (tok, q_i) in enumerate(zip(draft_tokens, draft_probs)):\n        t_probs = F.softmax(target_logits[0, n - 1 + i] / temperature, dim=-1)\n        accept_prob = min(1.0, t_probs[tok.item()].item() / (q_i + 1e-9))\n        if torch.rand(1).item() \u003c accept_prob:\n            accepted.append(tok)\n        else:\n            # Sample from residual (corrected) distribution\n            q_dist = F.softmax(target_logits[0, n - 1 + i] / temperature, dim=-1)\n            adj = (t_probs - q_dist * q_i).clamp(min=0)\n            fallback = torch.multinomial(adj / (adj.sum() + 1e-9), 1).unsqueeze(0)\n            accepted.append(fallback)\n            break  # stop accepting after first rejection\n    return torch.cat([input_ids] + accepted, dim=-1), len(accepted) / k"},{"type":"heading","level":2,"content":"Acceptance Criterion"},{"type":"text","content":"The acceptance probability for draft token x_{t+i} is min(1, p(x_{t+i} | context) / q(x_{t+i} | context)). This is the same criterion used in importance sampling and the Metropolis-Hastings algorithm. When the draft model is well-aligned with the target (i.e., q ≈ p), acceptance rate alpha approaches 1. When they diverge (e.g., draft predicts a different token distribution for technical content), alpha drops. The corrected distribution on rejection is the normalized positive part of (p - q): we subtract the draft\u0027s contribution and re-normalize. This ensures that the marginal distribution over accepted tokens exactly matches p — the guarantee that speculative decoding is lossless. Unlike quantization or knowledge distillation, there is zero accuracy tradeoff: the output distribution is identical to greedy or sampled decoding from the target alone."},{"type":"heading","level":2,"content":"Speculative Sampling Math"},{"type":"text","content":"Let p(x|c) be the target distribution and q(x|c) be the draft distribution over the next token given context c. Define the acceptance probability a(x) = min(1, p(x|c) / q(x|c)). The expected number of tokens accepted per speculative step is E[accepted] = sum_x q(x) * a(x) = sum_x min(q(x), p(x)) = 1 - TV(p, q) where TV is total variation distance. When p = q exactly (perfect draft), all k tokens are always accepted. The expected speedup relative to greedy decoding (1 target call per token) is: speedup ≈ (1 - alpha^(k+1)) / ((1 - alpha) * C_draft) where alpha = E[a(x)] and C_draft is the relative cost of one draft forward pass as a fraction of the target cost. For a 68M draft against a 7B target, C_draft ≈ 0.01–0.05, making the draft overhead negligible."},{"type":"code","language":"python","content":"import torch\nimport time\nfrom transformers import AutoModelForCausalLM, AutoTokenizer\n\ndef benchmark_speculative_decoding(\n    target_name: str = \"meta-llama/Llama-2-7b-hf\",\n    draft_name: str = \"JackFram/llama-68m\",\n    n_prompts: int = 50,\n    max_new_tokens: int = 128,\n    k: int = 5\n) -\u003e dict:\n    \"\"\"Measure acceptance rate and wall-clock speedup vs greedy baseline.\"\"\"\n    tokenizer = AutoTokenizer.from_pretrained(target_name)\n    target = AutoModelForCausalLM.from_pretrained(\n        target_name, torch_dtype=torch.float16, device_map=\"auto\")\n    draft = AutoModelForCausalLM.from_pretrained(\n        draft_name, torch_dtype=torch.float16, device_map=\"auto\")\n    prompts = [\"Describe the architecture of a transformer model in detail.\"] * n_prompts\n    inputs = tokenizer(prompts[0], return_tensors=\"pt\").to(\"cuda\")\n    # Greedy baseline\n    t0 = time.perf_counter()\n    for _ in range(n_prompts):\n        target.generate(**inputs, max_new_tokens=max_new_tokens, do_sample=False)\n    greedy_time = time.perf_counter() - t0\n    # Speculative decoding\n    acceptance_rates = []\n    t0 = time.perf_counter()\n    for _ in range(n_prompts):\n        _, alpha = speculative_decode(target, draft, inputs.input_ids, k=k)\n        acceptance_rates.append(alpha)\n    spec_time = time.perf_counter() - t0\n    speedup = greedy_time / spec_time\n    mean_alpha = sum(acceptance_rates) / len(acceptance_rates)\n    print(f\"Greedy:      {greedy_time:.2f}s total\")\n    print(f\"Speculative: {spec_time:.2f}s total  (speedup={speedup:.2f}x)\")\n    print(f\"Mean acceptance rate alpha: {mean_alpha:.3f}\")\n    print(f\"Expected speedup from formula: {(1 - mean_alpha**(k+1)) / (1 - mean_alpha + 1e-9):.2f}x\")\n    return {\"speedup\": speedup, \"alpha\": mean_alpha}"},{"type":"heading","level":2,"content":"Choosing the Draft Model"},{"type":"text","content":"The draft model must satisfy two competing requirements: it must be fast enough that its k forward passes cost less than the target pass it replaces, and it must be accurate enough that acceptance rate alpha stays high. The key practical constraint is that the draft and target must share the same tokenizer vocabulary — the tokens proposed by the draft must be valid tokens from the target\u0027s vocabulary for the rejection sampling math to work. The best draft models are smaller members of the same model family trained with the same data distribution: for LLaMA-2-70B, use LLaMA-2-7B or TinyLLaMA-1.1B as the draft. Draft models from unrelated families (e.g., GPT-2 as draft for LLaMA) tend to have poor alignment and low alpha. Self-drafting — using early exit layers of the target model itself — avoids this problem by sharing the full embedding space, but requires model surgery. Medusa adds multiple prediction heads to the target model itself, trained to predict positions 2, 3, ... k ahead simultaneously."},{"type":"table","headers":["Draft Model","Acceptance Rate (alpha)","Effective Speedup","Extra Memory (GB)","Latency Reduction"],"rows":[["LLaMA-68M","0.65–0.70","1.8–2.2x","+0.1 GB","40–50%"],["LLaMA-160M","0.70–0.75","2.0–2.5x","+0.3 GB","45–55%"],["LLaMA-1B","0.78–0.83","2.5–3.0x","+2 GB","55–65%"],["LLaMA-3B","0.82–0.87","2.8–3.4x","+6 GB","60–70%"],["Self-draft (Medusa)","0.75–0.88","2.2–3.5x","+0.05 GB (heads only)","55–70%"]]},{"type":"heading","level":2,"content":"Self-Speculative and Medusa Variants"},{"type":"text","content":"Medusa (Cai et al., 2024) attaches k additional LM heads to the final hidden state of the target model. Each Medusa head i predicts the token at position t+i+1 given the current hidden state — all heads run in parallel during one target forward pass. A tree-structured verification then accepts consistent candidate paths. Unlike standard speculative decoding, Medusa requires no separate draft model and adds only a small fraction of parameters (the extra heads). The tradeoff is that Medusa heads must be trained, whereas standard speculative decoding works out-of-the-box with any compatible draft model. EAGLE (Li et al., 2024) is a further refinement where the draft model is an auto-regressive model that operates on target hidden states rather than raw tokens, achieving acceptance rates of 0.85–0.90 by directly modeling the target\u0027s representation space."},{"type":"code","language":"python","content":"import torch\nimport time\nfrom transformers import AutoModelForCausalLM, AutoTokenizer\n\ndef hf_assisted_generation_benchmark(\n    target_name: str = \"meta-llama/Llama-2-7b-hf\",\n    draft_name: str = \"JackFram/llama-68m\",\n    max_new_tokens: int = 200\n) -\u003e float:\n    \"\"\"Use HuggingFace built-in assisted generation (speculative decoding).\"\"\"\n    tokenizer = AutoTokenizer.from_pretrained(target_name)\n    target = AutoModelForCausalLM.from_pretrained(\n        target_name, torch_dtype=torch.float16, device_map=\"auto\")\n    draft = AutoModelForCausalLM.from_pretrained(\n        draft_name, torch_dtype=torch.float16, device_map=\"auto\")\n    prompt = \"The fundamental theorem of calculus states that\"\n    inputs = tokenizer(prompt, return_tensors=\"pt\").to(\"cuda\")\n    # Greedy baseline\n    t0 = time.perf_counter()\n    out_greedy = target.generate(**inputs, max_new_tokens=max_new_tokens, do_sample=False)\n    t_base = time.perf_counter() - t0\n    # Assisted generation: HuggingFace runs speculative decoding internally\n    t0 = time.perf_counter()\n    out_spec = target.generate(**inputs, max_new_tokens=max_new_tokens,\n                                do_sample=False, assistant_model=draft)\n    t_spec = time.perf_counter() - t0\n    speedup = t_base / t_spec\n    print(f\"Greedy:    {t_base:.2f}s   Assisted: {t_spec:.2f}s   Speedup: {speedup:.2f}x\")\n    # Verify identical outputs (speculative decoding is lossless)\n    assert out_greedy[0].tolist() == out_spec[0].tolist(), \"Output mismatch — bug!\"\n    print(\"Output distributions match: verified lossless.\")\n    return speedup"},{"type":"heading","level":2,"content":"Throughput Gains in Practice"},{"type":"text","content":"Real-world speedups depend heavily on task type and output length. Speculative decoding provides the largest gains on tasks where the output is predictable and the draft model aligns well: code completion (where token sequences follow strong syntactic patterns), summarization, and translation. It provides smaller gains on highly creative or stochastic tasks where the target model diverges frequently from the draft. In production deployments at batch size 1 (the latency-critical serving regime), speedups of 2–3x are typical with a well-matched draft model. At higher batch sizes, the target model becomes more compute-bound (rather than bandwidth-bound), reducing the relative benefit of speculative decoding. Most production inference servers (TGI, vLLM, TensorRT-LLM) implement speculative decoding with automatic draft model loading and configurable k."},{"type":"code","language":"python","content":"import torch\nimport numpy as np\nfrom typing import Dict\n\ndef sweep_k_for_optimal_acceptance(\n    target, draft, input_ids: torch.Tensor,\n    k_values=range(1, 11), n_runs: int = 30\n) -\u003e Dict[int, dict]:\n    \"\"\"Sweep draft steps k from 1 to 10; find optimal k for this draft/target pair.\"\"\"\n    results = {}\n    draft_cost_fraction = 0.04  # draft is ~4% cost of target forward pass\n    for k in k_values:\n        alphas = []\n        for _ in range(n_runs):\n            _, alpha = speculative_decode(target, draft, input_ids, k=k)\n            alphas.append(alpha)\n        mean_alpha = float(np.mean(alphas))\n        # Theoretical effective speedup formula\n        if mean_alpha \u003c 1.0:\n            eff_toks = (1 - mean_alpha ** (k + 1)) / (1 - mean_alpha)\n        else:\n            eff_toks = k + 1\n        eff_speedup = eff_toks / (1 + k * draft_cost_fraction)\n        results[k] = {\"alpha\": mean_alpha, \"eff_tokens\": eff_toks, \"speedup\": eff_speedup}\n        print(f\"k={k:2d}: alpha={mean_alpha:.3f}  eff_tokens={eff_toks:.2f}  speedup={eff_speedup:.2f}x\")\n    optimal_k = max(results, key=lambda x: results[x][\"speedup\"])\n    print(f\"\\nOptimal k={optimal_k} -\u003e speedup={results[optimal_k][\u0027speedup\u0027]:.2f}x\")\n    return results"},{"type":"callout","variant":"info","title":"Lossless Speedup Guarantee","content":"Speculative decoding is mathematically guaranteed to produce the same output distribution as the target model alone — it is a pure speedup with no accuracy tradeoff, unlike quantization or pruning. The rejection sampling criterion ensures that the marginal distribution over every accepted token exactly equals the target\u0027s conditional distribution at that position."},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"list","ordered":false,"items":["Speculative decoding exploits memory-bandwidth bottleneck: at batch size 1, the target model can verify k tokens in one pass for nearly the same cost as verifying 1.","Draft model must share the same tokenizer as the target; same-family smaller models (e.g., LLaMA-68M for LLaMA-7B) yield the highest acceptance rates.","Optimal k is typically 4–8; beyond k=8, rejection rate grows faster than the benefit of parallel verification for most draft/target pairs.","Acceptance rate alpha of 0.75–0.85 is realistic for well-matched pairs on natural language tasks; code tasks often achieve 0.85–0.92.","HuggingFace transformers supports assisted generation natively via assistant_model= parameter — zero code beyond model loading.","Medusa and EAGLE variants eliminate the need for a separate draft model by attaching prediction heads to the target, at the cost of a brief training step.","Speculative decoding is most impactful at batch size 1; for large batch serving, continuous batching and paged attention typically dominate."]},{"type":"divider"}]"
---
# Speculative Decoding

Speculative decoding (Chen et al., 2023; Leviathan et al., 2023) is a lossless inference acceleration technique that decouples token proposal from token verification. A small, fast draft model autoregressively generates k candidate tokens in sequence. The large target model then evaluates all k+1 positions in a single forward pass — producing its own probability distributions at each position. A rejection-sampling procedure accepts or rejects each draft token while provably preserving the target model's output distribution. The net effect: the target model processes multiple tokens per forward pass instead of one, reducing the total number of expensive target forward passes needed to generate a sequence.

## Overview

Modern large language model inference is memory-bandwidth bound, not compute bound. At batch size 1, the GPU spends most of its time loading 70–140 GB of model weights from HBM to SRAM for each forward pass — the actual matrix multiplication is secondary. Speculative decoding exploits this asymmetry: since the target model's forward pass is latency-dominated by memory transfers rather than FLOPs, verifying k tokens in one pass takes only marginally more time than verifying 1. Meanwhile, the draft model is 10–100x smaller and can produce k proposals in a fraction of the time a single target forward pass takes. If the draft model's proposals are accepted at rate alpha, the expected tokens produced per target forward pass is (1 - alpha^(k+1)) / (1 - alpha), giving a theoretical speedup of that quantity divided by 1 (greedy baseline). At alpha=0.8 and k=5, this is roughly 3.5 tokens per target pass — a 3.5x throughput gain.

## Draft-Verify Mechanism

The draft-verify loop proceeds as follows. Given input context x_{1:t}, the draft model generates k tokens autoregressively: for each step i in 1..k, it samples x_{t+i} ~ q(. | x_{1:t+i-1}) where q is the draft model's distribution. This produces a sequence of k draft tokens and their associated draft probabilities q_i = q(x_{t+i} | x_{1:t+i-1}). Next, the target model is called once with the full candidate sequence x_{1:t+k} and returns logits for all t+k positions simultaneously. The target probabilities at each draft position are p_i = p(x_{t+i} | x_{1:t+i-1}). The rejection sampling loop then iterates i from 1 to k: if p_i / q_i >= 1, token i is always accepted; otherwise token i is accepted with probability p_i / q_i and rejected with probability 1 - p_i / q_i. On rejection, a corrected token is sampled from the residual distribution max(0, p_i - q_i) / Z.

```python
import torch
import torch.nn.functional as F
from transformers import AutoModelForCausalLM
from typing import Tuple, List

def speculative_decode(
    target_model, draft_model, input_ids: torch.Tensor,
    k: int = 5, temperature: float = 1.0
) -> Tuple[torch.Tensor, float]:
    """Draft proposes k tokens; target verifies all in one forward pass."""
    draft_input = input_ids.clone()
    draft_tokens: List[torch.Tensor] = []
    draft_probs: List[float] = []
    for _ in range(k):
        with torch.no_grad():
            logits = draft_model(draft_input).logits[:, -1, :] / temperature
            probs = F.softmax(logits, dim=-1)
            tok = torch.multinomial(probs, 1)
            draft_tokens.append(tok)
            draft_probs.append(probs[0, tok.item()].item())
            draft_input = torch.cat([draft_input, tok], dim=-1)
    candidate_ids = torch.cat([input_ids] + draft_tokens, dim=-1)
    with torch.no_grad():
        target_logits = target_model(candidate_ids).logits
    accepted: List[torch.Tensor] = []
    n = len(input_ids[0])
    for i, (tok, q_i) in enumerate(zip(draft_tokens, draft_probs)):
        t_probs = F.softmax(target_logits[0, n - 1 + i] / temperature, dim=-1)
        accept_prob = min(1.0, t_probs[tok.item()].item() / (q_i + 1e-9))
        if torch.rand(1).item() < accept_prob:
            accepted.append(tok)
        else:
            # Sample from residual (corrected) distribution
            q_dist = F.softmax(target_logits[0, n - 1 + i] / temperature, dim=-1)
            adj = (t_probs - q_dist * q_i).clamp(min=0)
            fallback = torch.multinomial(adj / (adj.sum() + 1e-9), 1).unsqueeze(0)
            accepted.append(fallback)
            break  # stop accepting after first rejection
    return torch.cat([input_ids] + accepted, dim=-1), len(accepted) / k
```

## Acceptance Criterion

The acceptance probability for draft token x_{t+i} is min(1, p(x_{t+i} | context) / q(x_{t+i} | context)). This is the same criterion used in importance sampling and the Metropolis-Hastings algorithm. When the draft model is well-aligned with the target (i.e., q ≈ p), acceptance rate alpha approaches 1. When they diverge (e.g., draft predicts a different token distribution for technical content), alpha drops. The corrected distribution on rejection is the normalized positive part of (p - q): we subtract the draft's contribution and re-normalize. This ensures that the marginal distribution over accepted tokens exactly matches p — the guarantee that speculative decoding is lossless. Unlike quantization or knowledge distillation, there is zero accuracy tradeoff: the output distribution is identical to greedy or sampled decoding from the target alone.

## Speculative Sampling Math

Let p(x|c) be the target distribution and q(x|c) be the draft distribution over the next token given context c. Define the acceptance probability a(x) = min(1, p(x|c) / q(x|c)). The expected number of tokens accepted per speculative step is E[accepted] = sum_x q(x) * a(x) = sum_x min(q(x), p(x)) = 1 - TV(p, q) where TV is total variation distance. When p = q exactly (perfect draft), all k tokens are always accepted. The expected speedup relative to greedy decoding (1 target call per token) is: speedup ≈ (1 - alpha^(k+1)) / ((1 - alpha) * C_draft) where alpha = E[a(x)] and C_draft is the relative cost of one draft forward pass as a fraction of the target cost. For a 68M draft against a 7B target, C_draft ≈ 0.01–0.05, making the draft overhead negligible.

```python
import torch
import time
from transformers import AutoModelForCausalLM, AutoTokenizer

def benchmark_speculative_decoding(
    target_name: str = "meta-llama/Llama-2-7b-hf",
    draft_name: str = "JackFram/llama-68m",
    n_prompts: int = 50,
    max_new_tokens: int = 128,
    k: int = 5
) -> dict:
    """Measure acceptance rate and wall-clock speedup vs greedy baseline."""
    tokenizer = AutoTokenizer.from_pretrained(target_name)
    target = AutoModelForCausalLM.from_pretrained(
        target_name, torch_dtype=torch.float16, device_map="auto")
    draft = AutoModelForCausalLM.from_pretrained(
        draft_name, torch_dtype=torch.float16, device_map="auto")
    prompts = ["Describe the architecture of a transformer model in detail."] * n_prompts
    inputs = tokenizer(prompts[0], return_tensors="pt").to("cuda")
    # Greedy baseline
    t0 = time.perf_counter()
    for _ in range(n_prompts):
        target.generate(**inputs, max_new_tokens=max_new_tokens, do_sample=False)
    greedy_time = time.perf_counter() - t0
    # Speculative decoding
    acceptance_rates = []
    t0 = time.perf_counter()
    for _ in range(n_prompts):
        _, alpha = speculative_decode(target, draft, inputs.input_ids, k=k)
        acceptance_rates.append(alpha)
    spec_time = time.perf_counter() - t0
    speedup = greedy_time / spec_time
    mean_alpha = sum(acceptance_rates) / len(acceptance_rates)
    print(f"Greedy:      {greedy_time:.2f}s total")
    print(f"Speculative: {spec_time:.2f}s total  (speedup={speedup:.2f}x)")
    print(f"Mean acceptance rate alpha: {mean_alpha:.3f}")
    print(f"Expected speedup from formula: {(1 - mean_alpha**(k+1)) / (1 - mean_alpha + 1e-9):.2f}x")
    return {"speedup": speedup, "alpha": mean_alpha}
```

## Choosing the Draft Model

The draft model must satisfy two competing requirements: it must be fast enough that its k forward passes cost less than the target pass it replaces, and it must be accurate enough that acceptance rate alpha stays high. The key practical constraint is that the draft and target must share the same tokenizer vocabulary — the tokens proposed by the draft must be valid tokens from the target's vocabulary for the rejection sampling math to work. The best draft models are smaller members of the same model family trained with the same data distribution: for LLaMA-2-70B, use LLaMA-2-7B or TinyLLaMA-1.1B as the draft. Draft models from unrelated families (e.g., GPT-2 as draft for LLaMA) tend to have poor alignment and low alpha. Self-drafting — using early exit layers of the target model itself — avoids this problem by sharing the full embedding space, but requires model surgery. Medusa adds multiple prediction heads to the target model itself, trained to predict positions 2, 3, ... k ahead simultaneously.

| Draft Model | Acceptance Rate (alpha) | Effective Speedup | Extra Memory (GB) | Latency Reduction |
| --- | --- | --- | --- | --- |
| LLaMA-68M | 0.65–0.70 | 1.8–2.2x | +0.1 GB | 40–50% |
| LLaMA-160M | 0.70–0.75 | 2.0–2.5x | +0.3 GB | 45–55% |
| LLaMA-1B | 0.78–0.83 | 2.5–3.0x | +2 GB | 55–65% |
| LLaMA-3B | 0.82–0.87 | 2.8–3.4x | +6 GB | 60–70% |
| Self-draft (Medusa) | 0.75–0.88 | 2.2–3.5x | +0.05 GB (heads only) | 55–70% |

## Self-Speculative and Medusa Variants

Medusa (Cai et al., 2024) attaches k additional LM heads to the final hidden state of the target model. Each Medusa head i predicts the token at position t+i+1 given the current hidden state — all heads run in parallel during one target forward pass. A tree-structured verification then accepts consistent candidate paths. Unlike standard speculative decoding, Medusa requires no separate draft model and adds only a small fraction of parameters (the extra heads). The tradeoff is that Medusa heads must be trained, whereas standard speculative decoding works out-of-the-box with any compatible draft model. EAGLE (Li et al., 2024) is a further refinement where the draft model is an auto-regressive model that operates on target hidden states rather than raw tokens, achieving acceptance rates of 0.85–0.90 by directly modeling the target's representation space.

```python
import torch
import time
from transformers import AutoModelForCausalLM, AutoTokenizer

def hf_assisted_generation_benchmark(
    target_name: str = "meta-llama/Llama-2-7b-hf",
    draft_name: str = "JackFram/llama-68m",
    max_new_tokens: int = 200
) -> float:
    """Use HuggingFace built-in assisted generation (speculative decoding)."""
    tokenizer = AutoTokenizer.from_pretrained(target_name)
    target = AutoModelForCausalLM.from_pretrained(
        target_name, torch_dtype=torch.float16, device_map="auto")
    draft = AutoModelForCausalLM.from_pretrained(
        draft_name, torch_dtype=torch.float16, device_map="auto")
    prompt = "The fundamental theorem of calculus states that"
    inputs = tokenizer(prompt, return_tensors="pt").to("cuda")
    # Greedy baseline
    t0 = time.perf_counter()
    out_greedy = target.generate(**inputs, max_new_tokens=max_new_tokens, do_sample=False)
    t_base = time.perf_counter() - t0
    # Assisted generation: HuggingFace runs speculative decoding internally
    t0 = time.perf_counter()
    out_spec = target.generate(**inputs, max_new_tokens=max_new_tokens,
                                do_sample=False, assistant_model=draft)
    t_spec = time.perf_counter() - t0
    speedup = t_base / t_spec
    print(f"Greedy:    {t_base:.2f}s   Assisted: {t_spec:.2f}s   Speedup: {speedup:.2f}x")
    # Verify identical outputs (speculative decoding is lossless)
    assert out_greedy[0].tolist() == out_spec[0].tolist(), "Output mismatch — bug!"
    print("Output distributions match: verified lossless.")
    return speedup
```

## Throughput Gains in Practice

Real-world speedups depend heavily on task type and output length. Speculative decoding provides the largest gains on tasks where the output is predictable and the draft model aligns well: code completion (where token sequences follow strong syntactic patterns), summarization, and translation. It provides smaller gains on highly creative or stochastic tasks where the target model diverges frequently from the draft. In production deployments at batch size 1 (the latency-critical serving regime), speedups of 2–3x are typical with a well-matched draft model. At higher batch sizes, the target model becomes more compute-bound (rather than bandwidth-bound), reducing the relative benefit of speculative decoding. Most production inference servers (TGI, vLLM, TensorRT-LLM) implement speculative decoding with automatic draft model loading and configurable k.

```python
import torch
import numpy as np
from typing import Dict

def sweep_k_for_optimal_acceptance(
    target, draft, input_ids: torch.Tensor,
    k_values=range(1, 11), n_runs: int = 30
) -> Dict[int, dict]:
    """Sweep draft steps k from 1 to 10; find optimal k for this draft/target pair."""
    results = {}
    draft_cost_fraction = 0.04  # draft is ~4% cost of target forward pass
    for k in k_values:
        alphas = []
        for _ in range(n_runs):
            _, alpha = speculative_decode(target, draft, input_ids, k=k)
            alphas.append(alpha)
        mean_alpha = float(np.mean(alphas))
        # Theoretical effective speedup formula
        if mean_alpha < 1.0:
            eff_toks = (1 - mean_alpha ** (k + 1)) / (1 - mean_alpha)
        else:
            eff_toks = k + 1
        eff_speedup = eff_toks / (1 + k * draft_cost_fraction)
        results[k] = {"alpha": mean_alpha, "eff_tokens": eff_toks, "speedup": eff_speedup}
        print(f"k={k:2d}: alpha={mean_alpha:.3f}  eff_tokens={eff_toks:.2f}  speedup={eff_speedup:.2f}x")
    optimal_k = max(results, key=lambda x: results[x]["speedup"])
    print(f"\nOptimal k={optimal_k} -> speedup={results[optimal_k]['speedup']:.2f}x")
    return results
```

> **Lossless Speedup Guarantee**: Speculative decoding is mathematically guaranteed to produce the same output distribution as the target model alone — it is a pure speedup with no accuracy tradeoff, unlike quantization or pruning. The rejection sampling criterion ensures that the marginal distribution over every accepted token exactly equals the target's conditional distribution at that position.

## Key Takeaways

- Speculative decoding exploits memory-bandwidth bottleneck: at batch size 1, the target model can verify k tokens in one pass for nearly the same cost as verifying 1.
- Draft model must share the same tokenizer as the target; same-family smaller models (e.g., LLaMA-68M for LLaMA-7B) yield the highest acceptance rates.
- Optimal k is typically 4–8; beyond k=8, rejection rate grows faster than the benefit of parallel verification for most draft/target pairs.
- Acceptance rate alpha of 0.75–0.85 is realistic for well-matched pairs on natural language tasks; code tasks often achieve 0.85–0.92.
- HuggingFace transformers supports assisted generation natively via assistant_model= parameter — zero code beyond model loading.
- Medusa and EAGLE variants eliminate the need for a separate draft model by attaching prediction heads to the target, at the cost of a brief training step.
- Speculative decoding is most impactful at batch size 1; for large batch serving, continuous batching and paged attention typically dominate.

---

