---
title: "Medusa: Multiple Decoding Heads for Parallel Token Generation"
slug: "medusa-decoding"
description: "Adding multiple lightweight prediction heads to a frozen LLM that each predict tokens several positions ahead, enabling parallel verification of multi-token continuations."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Medusa (Cai et al. 2024, Together AI) is a speculative decoding framework that replaces the separate draft model with multiple lightweight prediction heads appended to a frozen base LLM. Each head is a compact two-layer MLP sitting on top of the last transformer block\u0027s hidden states, independently predicting the token at offset +1, +2, up to +K positions ahead. Because the heads share the base model\u0027s rich representations, they can be trained to near-oracle acceptance rates with as little as 0.3% additional parameters. At inference time, all heads generate candidate tokens simultaneously in a single additional forward pass — no separate draft model call required — and the resulting tree of candidates is verified by the base model using a modified tree attention mask that scores all hypotheses in one batched forward pass. The practical result is a 2.2–2.8× throughput improvement on chat workloads with no measurable degradation in output quality."},{"type":"heading","level":2,"content":"Overview"},{"type":"text","content":"Standard autoregressive decoding generates one token per forward pass, making it memory-bandwidth bound: each step reads all model weights from HBM even though only a tiny fraction of total compute capacity is used. Speculative decoding sidesteps this by using a faster draft model to propose multiple tokens and the target model to verify them in parallel — but maintaining a separate draft model doubles deployment complexity and memory footprint. Medusa eliminates the draft model entirely: the prediction heads are trained once, frozen alongside the base model, and add negligible overhead to the standard inference graph. The typical acceptance rate for the first Medusa head is 60–80%, meaning most generated tokens are accepted, yielding measured speedups of 2.0–3.0× on chat workloads. The approach was popularised alongside Vicuna models and integrates directly with vLLM and SGLang inference servers."},{"type":"heading","level":2,"content":"Architecture: Multiple LM Heads"},{"type":"text","content":"Each Medusa head k (for k = 1, …, K) is a two-layer MLP with a LayerNorm applied to the last hidden state h_t before the first linear layer. The output of head k is a full vocabulary distribution over the token at position t+k. During a draft step, the base model generates the token at t+1 from its own logits (the standard LM head), while simultaneously all K Medusa heads produce candidate distributions for positions t+2 through t+K+1 — all computed from the same single forward pass over the current context. The heads are parameterised identically but trained independently, and there is no weight sharing between heads. This architecture ensures that head k specialises in predicting tokens k steps ahead given the base model\u0027s contextual representations."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom transformers import AutoModelForCausalLM, AutoConfig\nfrom typing import List, Tuple\n\nclass MedusaHead(nn.Module):\n    \"\"\"Two-layer MLP predicting token at position t+k from last hidden state.\"\"\"\n    def __init__(self, hidden_size: int, vocab_size: int):\n        super().__init__()\n        self.net = nn.Sequential(\n            nn.LayerNorm(hidden_size),\n            nn.Linear(hidden_size, hidden_size, bias=False),\n            nn.SiLU(),\n            nn.Linear(hidden_size, vocab_size, bias=False),\n        )\n\n    def forward(self, hidden: torch.Tensor) -\u003e torch.Tensor:\n        return self.net(hidden)  # (B, S, vocab_size)\n\nclass MedusaWithHeads(nn.Module):\n    \"\"\"Frozen base LLM plus K trainable Medusa heads for positions t+1 to t+K.\"\"\"\n    def __init__(self, model_name: str, num_heads: int = 5):\n        super().__init__()\n        self.base = AutoModelForCausalLM.from_pretrained(model_name)\n        for p in self.base.parameters():\n            p.requires_grad_(False)           # freeze all base model weights\n        H = self.base.config.hidden_size\n        V = self.base.config.vocab_size\n        self.medusa_heads = nn.ModuleList(\n            [MedusaHead(H, V) for _ in range(num_heads)]\n        )\n\n    def forward(self, input_ids: torch.Tensor) -\u003e Tuple[torch.Tensor, List[torch.Tensor]]:\n        outputs = self.base(input_ids, output_hidden_states=True)\n        last_hidden = outputs.hidden_states[-1]                      # (B, S, H)\n        medusa_logits = [head(last_hidden) for head in self.medusa_heads]  # K x (B,S,V)\n        return outputs.logits, medusa_logits"},{"type":"heading","level":2,"content":"Medusa Tree Attention"},{"type":"text","content":"Rather than verifying candidate tokens one by one, Medusa constructs a token tree from head predictions and verifies all branches simultaneously using a custom attention mask. For K heads each taking the top-p candidates, the tree has at most top-p^K leaves. The tree attention mask is a boolean matrix over all candidate positions: position j can attend to position i only if i is an ancestor of j in the tree. This mask replaces the standard causal mask during the verification forward pass, allowing the base model to score all candidate continuations in a single batched call — the same compute cost as verifying a single continuation. A path through the tree corresponds to a multi-token continuation hypothesis: if a path survives verification (each token matches the base model\u0027s greedy or sampled choice at that depth), all tokens on the path are accepted simultaneously, multiplying effective throughput."},{"type":"code","language":"python","content":"import torch\nimport itertools\nfrom typing import List, Tuple\n\ndef build_medusa_tree(\n    medusa_logits: List[torch.Tensor],\n    top_k: int = 3,\n) -\u003e Tuple[torch.Tensor, torch.Tensor]:\n    \"\"\"\n    Build candidate token tree and tree attention mask from Medusa head outputs.\n    medusa_logits: K tensors each (1, 1, V) — logits for positions t+1 .. t+K.\n    Returns (candidates, tree_mask): (N,) token ids and (N, N) bool attention mask.\n    \"\"\"\n    # Collect top-k token candidates from each head\n    head_topk = [\n        torch.topk(lg[0, -1], top_k).indices.tolist()\n        for lg in medusa_logits\n    ]\n    # Enumerate all paths through the tree (Cartesian product)\n    paths = list(itertools.product(*head_topk))  # list of K-tuples\n    N = len(paths)\n    # Tree attention mask: position j attends to i if path_i is a prefix of path_j\n    mask = torch.zeros(N, N, dtype=torch.bool)\n    for j, pj in enumerate(paths):\n        for i, pi in enumerate(paths):\n            depth = min(j + 1, i + 1)\n            if tuple(pi[:depth]) == tuple(pj[:depth]) and i \u003c= j:\n                mask[j, i] = True\n    # First token of each path is the candidate from head-1\n    candidates = torch.tensor([p[0] for p in paths])\n    return candidates, mask\n\ndummy_logits = [torch.randn(1, 1, 32000) for _ in range(3)]\ncands, tmask = build_medusa_tree(dummy_logits, top_k=3)\nprint(f\"Tree nodes: {len(cands)}, mask shape: {tuple(tmask.shape)}\")\nprint(f\"Non-zero mask entries: {tmask.sum().item()} of {tmask.numel()}\")"},{"type":"heading","level":2,"content":"Training the Medusa Heads"},{"type":"text","content":"Medusa heads are trained independently of the base model on instruction-tuning data. The training objective is per-head cross-entropy: head k minimises the cross-entropy loss between its predicted distribution and the ground truth token at offset k+1 in the sequence. Because each head predicts a different offset, they are trained with shifted target sequences — head-1 targets tokens shifted by 1, head-2 by 2, and so on. The base model is kept frozen throughout, so its hidden states serve as static, fixed features. Training converges in one to three epochs on moderate instruction datasets (ShareGPT, Alpaca, LMSYS-Chat-1M) and can be completed on a single A100 in under six hours for a 7B model. The per-head acceptance rate on a held-out validation set is the key metric to track: head-1 should reach 65–75%, with acceptance dropping roughly 15 percentage points per additional head."},{"type":"code","language":"python","content":"import torch\nimport torch.nn.functional as F\nfrom torch.utils.data import DataLoader\nfrom typing import List\n\ndef train_medusa_heads(\n    model,\n    train_loader: DataLoader,\n    num_heads: int = 5,\n    lr: float = 1e-3,\n    epochs: int = 1,\n) -\u003e List[float]:\n    \"\"\"Freeze base model, train Medusa heads with per-head cross-entropy losses.\"\"\"\n    optimizer = torch.optim.AdamW(\n        [p for p in model.parameters() if p.requires_grad],\n        lr=lr, weight_decay=0.01,\n    )\n    per_head_loss = [0.0] * num_heads\n    for epoch in range(epochs):\n        for batch in train_loader:\n            input_ids = batch[\u0027input_ids\u0027]\n            _, medusa_logits = model(input_ids)\n            total_loss = torch.tensor(0.0, requires_grad=True)\n            for k, head_logits in enumerate(medusa_logits):\n                target = input_ids[:, k + 1:]                  # shift target by k+1\n                pred   = head_logits[:, :-(k + 1), :]          # align sequence length\n                loss_k = F.cross_entropy(\n                    pred.reshape(-1, pred.size(-1)), target.reshape(-1), ignore_index=-100\n                )\n                total_loss = total_loss + loss_k\n                per_head_loss[k] += loss_k.item()\n            optimizer.zero_grad()\n            total_loss.backward()\n            optimizer.step()\n    per_head_loss = [l / (epochs * len(train_loader)) for l in per_head_loss]\n    for k, lv in enumerate(per_head_loss):\n        print(f\"  Head {k+1} (offset +{k+1}): avg CE loss = {lv:.4f}\")\n    return per_head_loss"},{"type":"heading","level":2,"content":"Acceptance with Typical Sampling"},{"type":"text","content":"Medusa uses a modified acceptance criterion based on typical sampling rather than the standard speculative decoding acceptance probability ratio. In standard speculative decoding, a candidate token c is accepted with probability min(1, p_target(c) / p_draft(c)), requiring explicit access to the draft distribution. Medusa replaces this with a posterior check based on the Medusa head logits and a temperature threshold: a candidate token is accepted if it falls within the typical set of the target distribution at that position, controlled by a posterior threshold hyperparameter (default 0.09). This avoids dependence on the draft distribution ratio, simplifies the acceptance check to a single comparison, and maintains output quality equivalent to sampling directly from the target model. The typical acceptance criterion accepts candidates with probability 0.6–0.9 for well-trained heads, without any need to store or compute draft model probabilities."},{"type":"callout","variant":"info","title":"Parameter Efficiency","content":"Medusa heads add \u003c1% parameters and can be trained in a few hours on a single GPU — the key constraint is that base model weights must remain frozen, making Medusa compatible with any quantized or fine-tuned checkpoint"},{"type":"heading","level":2,"content":"Self-Distillation Training"},{"type":"text","content":"Medusa-2 introduces self-distillation: instead of training heads to match one-hot ground truth tokens, the heads are trained to match the base model\u0027s own output distribution via KL divergence minimisation. Head k is distilled from the base LM head\u0027s probability distribution for position t+k+1 rather than the hard label. Self-distillation produces softer targets that capture the model\u0027s own uncertainty, leading to higher acceptance rates because the heads learn to predict the same distribution the verifier uses. This requires one additional forward pass over the training data to collect base model probability distributions, but substantially improves acceptance rates — head-1 improves from roughly 70% to over 80% with self-distillation. In practice self-distillation is applied jointly with the cross-entropy loss using a mixing coefficient lambda that weights the distillation objective relative to the hard-label loss."},{"type":"heading","level":2,"content":"Throughput Results"},{"type":"text","content":"Measured on Vicuna-7B and Vicuna-13B with an A100 80 GB GPU at batch size 1 (single-user chat latency regime), Medusa achieves 2.2–2.8× throughput improvement over standard autoregressive decoding. The speedup grows with the number of heads up to five or six heads, after which acceptance rates for farther-ahead predictions fall too low to contribute net throughput gain. On multi-batch inference the gains are reduced because the base model becomes compute-bound rather than bandwidth-bound, but Medusa still provides 1.5–1.8× improvement at batch sizes up to 8. Self-distillation (Medusa-2) pushes speedup to approximately 3.0× at batch size 1 by raising acceptance rates across all heads."},{"type":"table","headers":["Medusa heads","Acceptance rate (head 1)","Speedup vs AR","Added parameters","Training data needed"],"rows":[["1 head","70–78%","1.5–1.7×","~0.3% of base","50K instruction samples"],["3 heads","H1: 74%, H2: 55%, H3: 38%","1.9–2.2×","~0.8% of base","200K instruction samples"],["5 heads","H1: 74%, H2–H5: 55/38/26/18%","2.2–2.8×","~1.3% of base","500K instruction samples"],["8 heads","H1: 72%, drops steeply beyond H4","2.3–2.9×","~2.1% of base","1M+ instruction samples"]]},{"type":"code","language":"python","content":"from medusa.model.medusa_model import MedusaModel\nfrom transformers import AutoTokenizer\nimport torch\nimport time\n\ndef benchmark_medusa_vs_standard(\n    model_path: str,\n    prompts: list,\n    max_new_tokens: int = 128,\n) -\u003e dict:\n    \"\"\"Load Medusa model and compare throughput vs standard greedy autoregressive decode.\"\"\"\n    tokenizer = AutoTokenizer.from_pretrained(model_path)\n    model = MedusaModel.from_pretrained(model_path, torch_dtype=torch.float16)\n    model = model.cuda().eval()\n    results = {}\n    for label, use_medusa in [(\"standard\", False), (\"medusa\", True)]:\n        total_tokens, t0 = 0, time.perf_counter()\n        for prompt in prompts:\n            ids = tokenizer(prompt, return_tensors=\"pt\").input_ids.cuda()\n            if use_medusa:\n                out = model.medusa_generate(\n                    ids, max_new_tokens=max_new_tokens,\n                    temperature=0.0, posterior_threshold=0.09,\n                )\n            else:\n                out = model.generate(ids, max_new_tokens=max_new_tokens, do_sample=False)\n            total_tokens += out.shape[1] - ids.shape[1]\n        elapsed = time.perf_counter() - t0\n        results[label] = {\"tok_per_s\": total_tokens / elapsed, \"total_tokens\": total_tokens}\n    speedup = results[\"medusa\"][\"tok_per_s\"] / results[\"standard\"][\"tok_per_s\"]\n    print(f\"Standard: {results[\u0027standard\u0027][\u0027tok_per_s\u0027]:.1f} tok/s\")\n    print(f\"Medusa:   {results[\u0027medusa\u0027][\u0027tok_per_s\u0027]:.1f} tok/s  (speedup {speedup:.2f}x)\")\n    return {**results, \"speedup\": speedup}"},{"type":"heading","level":2,"content":"Key Takeaways"},{"type":"text","content":"Medusa is one of the most practically deployable speculative decoding approaches because it requires no changes to base model inference infrastructure and no separate draft model process. The heads are drop-in additions that can be trained on any existing instruction dataset in a few GPU-hours. The main limitation is that speedup is strongest at batch size 1 (latency-sensitive single-user chat) and diminishes as batch size grows because the bottleneck shifts from memory bandwidth to compute. For high-throughput batch inference, continuous batching with flash-attention remains more effective than speculative decoding. However, for latency-sensitive deployments — APIs targeting p50 latency below 500 ms — Medusa offers the most practical path to 2× speedup without additional infrastructure."},{"type":"list","ordered":false,"items":["Medusa heads are frozen alongside the base model — they are compatible with any quantized (GPTQ, AWQ) or fine-tuned checkpoint as long as the hidden size matches.","Tree attention verifies top-k^K candidate paths simultaneously in a single forward pass — same compute cost as verifying one candidate path.","Self-distillation (Medusa-2) improves acceptance rates by 8–12 percentage points versus training against hard one-hot labels.","Typical acceptance sampling is equivalent in output distribution to direct sampling from the target model — no quality degradation.","Five heads is the practical sweet spot: beyond that, acceptance rates for heads 6+ are too low to contribute net speedup.","Medusa speedups are largest at batch size 1 and diminish at batch sizes above 8 where the model becomes compute-bound rather than bandwidth-bound.","Pretrained Medusa heads for Vicuna-7B, Vicuna-13B, and Llama-2 are available in the FasterDecoding repository on Hugging Face."]},{"type":"divider"}]"
---
# Medusa: Multiple Decoding Heads for Parallel Token Generation

Medusa (Cai et al. 2024, Together AI) is a speculative decoding framework that replaces the separate draft model with multiple lightweight prediction heads appended to a frozen base LLM. Each head is a compact two-layer MLP sitting on top of the last transformer block's hidden states, independently predicting the token at offset +1, +2, up to +K positions ahead. Because the heads share the base model's rich representations, they can be trained to near-oracle acceptance rates with as little as 0.3% additional parameters. At inference time, all heads generate candidate tokens simultaneously in a single additional forward pass — no separate draft model call required — and the resulting tree of candidates is verified by the base model using a modified tree attention mask that scores all hypotheses in one batched forward pass. The practical result is a 2.2–2.8× throughput improvement on chat workloads with no measurable degradation in output quality.

## Overview

Standard autoregressive decoding generates one token per forward pass, making it memory-bandwidth bound: each step reads all model weights from HBM even though only a tiny fraction of total compute capacity is used. Speculative decoding sidesteps this by using a faster draft model to propose multiple tokens and the target model to verify them in parallel — but maintaining a separate draft model doubles deployment complexity and memory footprint. Medusa eliminates the draft model entirely: the prediction heads are trained once, frozen alongside the base model, and add negligible overhead to the standard inference graph. The typical acceptance rate for the first Medusa head is 60–80%, meaning most generated tokens are accepted, yielding measured speedups of 2.0–3.0× on chat workloads. The approach was popularised alongside Vicuna models and integrates directly with vLLM and SGLang inference servers.

## Architecture: Multiple LM Heads

Each Medusa head k (for k = 1, …, K) is a two-layer MLP with a LayerNorm applied to the last hidden state h_t before the first linear layer. The output of head k is a full vocabulary distribution over the token at position t+k. During a draft step, the base model generates the token at t+1 from its own logits (the standard LM head), while simultaneously all K Medusa heads produce candidate distributions for positions t+2 through t+K+1 — all computed from the same single forward pass over the current context. The heads are parameterised identically but trained independently, and there is no weight sharing between heads. This architecture ensures that head k specialises in predicting tokens k steps ahead given the base model's contextual representations.

```python
import torch
import torch.nn as nn
from transformers import AutoModelForCausalLM, AutoConfig
from typing import List, Tuple

class MedusaHead(nn.Module):
    """Two-layer MLP predicting token at position t+k from last hidden state."""
    def __init__(self, hidden_size: int, vocab_size: int):
        super().__init__()
        self.net = nn.Sequential(
            nn.LayerNorm(hidden_size),
            nn.Linear(hidden_size, hidden_size, bias=False),
            nn.SiLU(),
            nn.Linear(hidden_size, vocab_size, bias=False),
        )

    def forward(self, hidden: torch.Tensor) -> torch.Tensor:
        return self.net(hidden)  # (B, S, vocab_size)

class MedusaWithHeads(nn.Module):
    """Frozen base LLM plus K trainable Medusa heads for positions t+1 to t+K."""
    def __init__(self, model_name: str, num_heads: int = 5):
        super().__init__()
        self.base = AutoModelForCausalLM.from_pretrained(model_name)
        for p in self.base.parameters():
            p.requires_grad_(False)           # freeze all base model weights
        H = self.base.config.hidden_size
        V = self.base.config.vocab_size
        self.medusa_heads = nn.ModuleList(
            [MedusaHead(H, V) for _ in range(num_heads)]
        )

    def forward(self, input_ids: torch.Tensor) -> Tuple[torch.Tensor, List[torch.Tensor]]:
        outputs = self.base(input_ids, output_hidden_states=True)
        last_hidden = outputs.hidden_states[-1]                      # (B, S, H)
        medusa_logits = [head(last_hidden) for head in self.medusa_heads]  # K x (B,S,V)
        return outputs.logits, medusa_logits
```

## Medusa Tree Attention

Rather than verifying candidate tokens one by one, Medusa constructs a token tree from head predictions and verifies all branches simultaneously using a custom attention mask. For K heads each taking the top-p candidates, the tree has at most top-p^K leaves. The tree attention mask is a boolean matrix over all candidate positions: position j can attend to position i only if i is an ancestor of j in the tree. This mask replaces the standard causal mask during the verification forward pass, allowing the base model to score all candidate continuations in a single batched call — the same compute cost as verifying a single continuation. A path through the tree corresponds to a multi-token continuation hypothesis: if a path survives verification (each token matches the base model's greedy or sampled choice at that depth), all tokens on the path are accepted simultaneously, multiplying effective throughput.

```python
import torch
import itertools
from typing import List, Tuple

def build_medusa_tree(
    medusa_logits: List[torch.Tensor],
    top_k: int = 3,
) -> Tuple[torch.Tensor, torch.Tensor]:
    """
    Build candidate token tree and tree attention mask from Medusa head outputs.
    medusa_logits: K tensors each (1, 1, V) — logits for positions t+1 .. t+K.
    Returns (candidates, tree_mask): (N,) token ids and (N, N) bool attention mask.
    """
    # Collect top-k token candidates from each head
    head_topk = [
        torch.topk(lg[0, -1], top_k).indices.tolist()
        for lg in medusa_logits
    ]
    # Enumerate all paths through the tree (Cartesian product)
    paths = list(itertools.product(*head_topk))  # list of K-tuples
    N = len(paths)
    # Tree attention mask: position j attends to i if path_i is a prefix of path_j
    mask = torch.zeros(N, N, dtype=torch.bool)
    for j, pj in enumerate(paths):
        for i, pi in enumerate(paths):
            depth = min(j + 1, i + 1)
            if tuple(pi[:depth]) == tuple(pj[:depth]) and i <= j:
                mask[j, i] = True
    # First token of each path is the candidate from head-1
    candidates = torch.tensor([p[0] for p in paths])
    return candidates, mask

dummy_logits = [torch.randn(1, 1, 32000) for _ in range(3)]
cands, tmask = build_medusa_tree(dummy_logits, top_k=3)
print(f"Tree nodes: {len(cands)}, mask shape: {tuple(tmask.shape)}")
print(f"Non-zero mask entries: {tmask.sum().item()} of {tmask.numel()}")
```

## Training the Medusa Heads

Medusa heads are trained independently of the base model on instruction-tuning data. The training objective is per-head cross-entropy: head k minimises the cross-entropy loss between its predicted distribution and the ground truth token at offset k+1 in the sequence. Because each head predicts a different offset, they are trained with shifted target sequences — head-1 targets tokens shifted by 1, head-2 by 2, and so on. The base model is kept frozen throughout, so its hidden states serve as static, fixed features. Training converges in one to three epochs on moderate instruction datasets (ShareGPT, Alpaca, LMSYS-Chat-1M) and can be completed on a single A100 in under six hours for a 7B model. The per-head acceptance rate on a held-out validation set is the key metric to track: head-1 should reach 65–75%, with acceptance dropping roughly 15 percentage points per additional head.

```python
import torch
import torch.nn.functional as F
from torch.utils.data import DataLoader
from typing import List

def train_medusa_heads(
    model,
    train_loader: DataLoader,
    num_heads: int = 5,
    lr: float = 1e-3,
    epochs: int = 1,
) -> List[float]:
    """Freeze base model, train Medusa heads with per-head cross-entropy losses."""
    optimizer = torch.optim.AdamW(
        [p for p in model.parameters() if p.requires_grad],
        lr=lr, weight_decay=0.01,
    )
    per_head_loss = [0.0] * num_heads
    for epoch in range(epochs):
        for batch in train_loader:
            input_ids = batch['input_ids']
            _, medusa_logits = model(input_ids)
            total_loss = torch.tensor(0.0, requires_grad=True)
            for k, head_logits in enumerate(medusa_logits):
                target = input_ids[:, k + 1:]                  # shift target by k+1
                pred   = head_logits[:, :-(k + 1), :]          # align sequence length
                loss_k = F.cross_entropy(
                    pred.reshape(-1, pred.size(-1)), target.reshape(-1), ignore_index=-100
                )
                total_loss = total_loss + loss_k
                per_head_loss[k] += loss_k.item()
            optimizer.zero_grad()
            total_loss.backward()
            optimizer.step()
    per_head_loss = [l / (epochs * len(train_loader)) for l in per_head_loss]
    for k, lv in enumerate(per_head_loss):
        print(f"  Head {k+1} (offset +{k+1}): avg CE loss = {lv:.4f}")
    return per_head_loss
```

## Acceptance with Typical Sampling

Medusa uses a modified acceptance criterion based on typical sampling rather than the standard speculative decoding acceptance probability ratio. In standard speculative decoding, a candidate token c is accepted with probability min(1, p_target(c) / p_draft(c)), requiring explicit access to the draft distribution. Medusa replaces this with a posterior check based on the Medusa head logits and a temperature threshold: a candidate token is accepted if it falls within the typical set of the target distribution at that position, controlled by a posterior threshold hyperparameter (default 0.09). This avoids dependence on the draft distribution ratio, simplifies the acceptance check to a single comparison, and maintains output quality equivalent to sampling directly from the target model. The typical acceptance criterion accepts candidates with probability 0.6–0.9 for well-trained heads, without any need to store or compute draft model probabilities.

> **Parameter Efficiency**: Medusa heads add <1% parameters and can be trained in a few hours on a single GPU — the key constraint is that base model weights must remain frozen, making Medusa compatible with any quantized or fine-tuned checkpoint

## Self-Distillation Training

Medusa-2 introduces self-distillation: instead of training heads to match one-hot ground truth tokens, the heads are trained to match the base model's own output distribution via KL divergence minimisation. Head k is distilled from the base LM head's probability distribution for position t+k+1 rather than the hard label. Self-distillation produces softer targets that capture the model's own uncertainty, leading to higher acceptance rates because the heads learn to predict the same distribution the verifier uses. This requires one additional forward pass over the training data to collect base model probability distributions, but substantially improves acceptance rates — head-1 improves from roughly 70% to over 80% with self-distillation. In practice self-distillation is applied jointly with the cross-entropy loss using a mixing coefficient lambda that weights the distillation objective relative to the hard-label loss.

## Throughput Results

Measured on Vicuna-7B and Vicuna-13B with an A100 80 GB GPU at batch size 1 (single-user chat latency regime), Medusa achieves 2.2–2.8× throughput improvement over standard autoregressive decoding. The speedup grows with the number of heads up to five or six heads, after which acceptance rates for farther-ahead predictions fall too low to contribute net throughput gain. On multi-batch inference the gains are reduced because the base model becomes compute-bound rather than bandwidth-bound, but Medusa still provides 1.5–1.8× improvement at batch sizes up to 8. Self-distillation (Medusa-2) pushes speedup to approximately 3.0× at batch size 1 by raising acceptance rates across all heads.

| Medusa heads | Acceptance rate (head 1) | Speedup vs AR | Added parameters | Training data needed |
| --- | --- | --- | --- | --- |
| 1 head | 70–78% | 1.5–1.7× | ~0.3% of base | 50K instruction samples |
| 3 heads | H1: 74%, H2: 55%, H3: 38% | 1.9–2.2× | ~0.8% of base | 200K instruction samples |
| 5 heads | H1: 74%, H2–H5: 55/38/26/18% | 2.2–2.8× | ~1.3% of base | 500K instruction samples |
| 8 heads | H1: 72%, drops steeply beyond H4 | 2.3–2.9× | ~2.1% of base | 1M+ instruction samples |

```python
from medusa.model.medusa_model import MedusaModel
from transformers import AutoTokenizer
import torch
import time

def benchmark_medusa_vs_standard(
    model_path: str,
    prompts: list,
    max_new_tokens: int = 128,
) -> dict:
    """Load Medusa model and compare throughput vs standard greedy autoregressive decode."""
    tokenizer = AutoTokenizer.from_pretrained(model_path)
    model = MedusaModel.from_pretrained(model_path, torch_dtype=torch.float16)
    model = model.cuda().eval()
    results = {}
    for label, use_medusa in [("standard", False), ("medusa", True)]:
        total_tokens, t0 = 0, time.perf_counter()
        for prompt in prompts:
            ids = tokenizer(prompt, return_tensors="pt").input_ids.cuda()
            if use_medusa:
                out = model.medusa_generate(
                    ids, max_new_tokens=max_new_tokens,
                    temperature=0.0, posterior_threshold=0.09,
                )
            else:
                out = model.generate(ids, max_new_tokens=max_new_tokens, do_sample=False)
            total_tokens += out.shape[1] - ids.shape[1]
        elapsed = time.perf_counter() - t0
        results[label] = {"tok_per_s": total_tokens / elapsed, "total_tokens": total_tokens}
    speedup = results["medusa"]["tok_per_s"] / results["standard"]["tok_per_s"]
    print(f"Standard: {results['standard']['tok_per_s']:.1f} tok/s")
    print(f"Medusa:   {results['medusa']['tok_per_s']:.1f} tok/s  (speedup {speedup:.2f}x)")
    return {**results, "speedup": speedup}
```

## Key Takeaways

Medusa is one of the most practically deployable speculative decoding approaches because it requires no changes to base model inference infrastructure and no separate draft model process. The heads are drop-in additions that can be trained on any existing instruction dataset in a few GPU-hours. The main limitation is that speedup is strongest at batch size 1 (latency-sensitive single-user chat) and diminishes as batch size grows because the bottleneck shifts from memory bandwidth to compute. For high-throughput batch inference, continuous batching with flash-attention remains more effective than speculative decoding. However, for latency-sensitive deployments — APIs targeting p50 latency below 500 ms — Medusa offers the most practical path to 2× speedup without additional infrastructure.

- Medusa heads are frozen alongside the base model — they are compatible with any quantized (GPTQ, AWQ) or fine-tuned checkpoint as long as the hidden size matches.
- Tree attention verifies top-k^K candidate paths simultaneously in a single forward pass — same compute cost as verifying one candidate path.
- Self-distillation (Medusa-2) improves acceptance rates by 8–12 percentage points versus training against hard one-hot labels.
- Typical acceptance sampling is equivalent in output distribution to direct sampling from the target model — no quality degradation.
- Five heads is the practical sweet spot: beyond that, acceptance rates for heads 6+ are too low to contribute net speedup.
- Medusa speedups are largest at batch size 1 and diminish at batch sizes above 8 where the model becomes compute-bound rather than bandwidth-bound.
- Pretrained Medusa heads for Vicuna-7B, Vicuna-13B, and Llama-2 are available in the FasterDecoding repository on Hugging Face.

---

