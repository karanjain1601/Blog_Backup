---
title: "Why Multiple Attention Heads — Different Subspace Specialisation"
slug: "why-multiple-attention-heads"
description: "Examine single-head limitations, the subspace specialisation argument, Clark et al. 2019 empirical evidence, gradient-based head importance scoring, and head pruning experiments."
tags: ["deep-learning", "transformers", "attention"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"A Transformer with a single attention head per layer learns one global attention pattern per layer — a single learned similarity function applied uniformly to all queries. Multiple heads allow the model to simultaneously route information through h different learned routing functions, each operating on a different linear projection of the same input. This is not merely redundancy: different heads tend to specialise on syntactic dependencies, coreference, positional structure, and semantic similarity simultaneously."},{"type":"heading","level":2,"content":"Single-Head Limitation"},{"type":"text","content":"With a single attention head of dimension d_model, every position computes a single query and compares it to a single set of keys. The output is one weighted combination of value vectors — a rank-1 routing. If the task requires simultaneously attending to multiple unrelated positions (e.g., the subject of a sentence and a distant pronoun that refers to it), a single head must trade off between them, achieving neither reliably. Multiple heads circumvent this by partitioning the capacity — head 1 can attend to syntactic dependencies while head 2 handles coreference without either interfering with the other."},{"type":"heading","level":2,"content":"Mathematical Justification — Subspace Representation"},{"type":"text","content":"The projection matrices WᵢQ and WᵢK map the full d_model-dimensional input into a dₖ-dimensional subspace. Different heads project into different subspaces, so they measure similarity along different directions. Formally, h heads produce h independent attention-weighted sums of value projections; concatenating them before Wᴼ allows the output projection to mix information from all h subspaces. The rank of the combined output is bounded by min(h·dv, d_model) — potentially far higher than the rank achievable with a single head of dimension d_model."},{"type":"text","content":"Superposition theory (Elhage et al. 2022) provides a complementary view: with enough heads, a Transformer layer can store and retrieve multiple approximately-orthogonal \u0027features\u0027 simultaneously. Each head acts on a different subspace in which distinct features are nearly orthogonal; interference between features is suppressed across heads even when it cannot be avoided within a single head. This allows the model to maintain more independent \u0027thoughts\u0027 per layer than its raw dimension would suggest."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ntorch.manual_seed(42)\nd_model, h = 256, 8\nmha = nn.MultiheadAttention(d_model, h, batch_first=True)\nWQ, WK, _ = mha.in_proj_weight.chunk(3, dim=0)\ndk = d_model // h\n\ntokens = [\u0027[CLS]\u0027, \u0027the\u0027, \u0027cat\u0027, \u0027sat\u0027, \u0027on\u0027, \u0027mat\u0027, \u0027[SEP]\u0027, \u0027.\u0027]\nseq_len = len(tokens)\nx = torch.randn(1, seq_len, d_model)\nx_flat = x.squeeze(0)\n\ndef head_attn(x_flat, i):\n    with torch.no_grad():\n        Q = (x_flat @ WQ.T)[:, i*dk:(i+1)*dk]\n        K = (x_flat @ WK.T)[:, i*dk:(i+1)*dk]\n        S = (Q @ K.T / dk**0.5).numpy()\n    S -= S.max(1, keepdims=True)\n    A = np.exp(S); A /= A.sum(1, keepdims=True)\n    return A\n\nprint(\u0027Head | \u0027 + \u0027 | \u0027.join(\u0027{:\u003e5}\u0027.format(t[:5]) for t in tokens))\nprint(\u0027-\u0027 * (7 + 8 * seq_len))\nfor i in range(h):\n    A = head_attn(x_flat, i)\n    peaks = [tokens[j][:5] for j in A.argmax(axis=1)]\n    ent = -(A * np.log(A + 1e-9)).sum(1).mean()\n    row = \u0027 | \u0027.join(\u0027{:\u003e5}\u0027.format(p) for p in peaks)\n    print(\u0027H{:\u003e2}  | {}  ent={:.2f}\u0027.format(i, row, ent))"},{"type":"heading","level":2,"content":"Empirical Evidence — Clark et al. 2019"},{"type":"text","content":"Clark et al. (2019) systematically analysed attention patterns across all 144 heads in BERT-base. They found clear functional specialisation: certain heads track direct object relationships, others attend to coreferent mentions, and a distinct class attends to the immediately preceding or following token. Crucially, some heads capture information highly correlated with the output of supervised dependency parsers — without any explicit supervision on syntax. This provides strong empirical evidence that multi-head attention spontaneously learns diverse, linguistically meaningful routing functions across heads."},{"type":"callout","variant":"info","title":"Clark et al. 2019 Key Findings","content":"In BERT-base (12 layers × 12 heads = 144 heads total): (1) Heads in layers 6–10 show the strongest syntactic behaviour. (2) A single head in layer 8 achieves 76.1% accuracy on a coreference task with no fine-tuning. (3) Certain heads attend almost exclusively to [SEP] or [CLS] tokens — acting as \u0027no-op\u0027 attention sinks. (4) Removing any single head causes \u003c1% performance drop; removing the top-5 most important heads causes ~3% drop. Attention patterns are sparse and interpretable at the head level."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ntorch.manual_seed(7)\nd_model, h, seq_len, batch = 128, 8, 20, 16\n\nclass TinyTransformerLayer(nn.Module):\n    def __init__(self):\n        super().__init__()\n        self.attn = nn.MultiheadAttention(d_model, h, batch_first=True)\n        self.norm = nn.LayerNorm(d_model)\n        self.proj = nn.Linear(d_model, 1)\n\n    def forward(self, x):\n        a, _ = self.attn(x, x, x)\n        x = self.norm(x + a)\n        return self.proj(x.mean(dim=1))\n\nmodel = TinyTransformerLayer()\nx = torch.randn(batch, seq_len, d_model)\ny = x.mean(dim=(1, 2)).unsqueeze(-1)\nloss = nn.functional.mse_loss(model(x), y)\nloss.backward()\n\nWQ_g, WK_g, WV_g = model.attn.in_proj_weight.grad.chunk(3, dim=0)\ndk = d_model // h\nprint(\u0027{:\u003e6} {:\u003e10} {:\u003e10} {:\u003e10} {:\u003e12}\u0027.format(\u0027Head\u0027, \u0027Q_grad\u0027, \u0027K_grad\u0027, \u0027V_grad\u0027, \u0027Importance\u0027))\nfor i in range(h):\n    qg = WQ_g[i*dk:(i+1)*dk].norm().item()\n    kg = WK_g[i*dk:(i+1)*dk].norm().item()\n    vg = WV_g[i*dk:(i+1)*dk].norm().item()\n    imp = (qg + kg + vg) / 3\n    print(\u0027{:\u003e6} {:\u003e10.4f} {:\u003e10.4f} {:\u003e10.4f} {:\u003e12.4f}\u0027.format(i, qg, kg, vg, imp))\nprint(\u0027Higher gradient norm -\u003e head contributes more to this task.\u0027)"},{"type":"heading","level":2,"content":"Head Pruning"},{"type":"text","content":"Michel et al. (2019) showed that most attention heads in BERT can be pruned at test time with minimal accuracy loss — for BERT-base on MNLI, only 16 of 144 heads are needed to retain 90% of performance. Voita et al. (2019) identified four head roles that are consistently preserved: positional (attend to adjacent token), syntactic (attend to syntactic dependents), rare-word (attend to low-frequency tokens), and coreference. Unimportant heads — those whose removal causes the smallest accuracy drop — can be zeroed out by setting the corresponding columns of Wᴼ to zero, which is equivalent to removing their contribution to the output."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport numpy as np\n\ntorch.manual_seed(0)\nd_model, h, n = 128, 8, 15\n\nmha = nn.MultiheadAttention(d_model, h, batch_first=True)\nx = torch.randn(4, n, d_model)\n\nwith torch.no_grad():\n    baseline, _ = mha(x, x, x)\n\n# Compute per-head importance: gradient of output L2 norm w.r.t. WV slice\nimportances = []\nfor i in range(h):\n    x_req = x.clone().requires_grad_(True)\n    out, _ = mha(x_req, x_req, x_req)\n    out.norm().backward()\n    WQ_g, WK_g, WV_g = mha.in_proj_weight.grad.chunk(3, dim=0) if mha.in_proj_weight.grad is not None else (torch.zeros(d_model,d_model),)*3\n    dk = d_model // h\n    importances.append(float(WV_g[i*dk:(i+1)*dk].norm()) if WV_g is not None else 0.0)\n    mha.zero_grad()\n\nimportances = np.array(importances)\nranked = np.argsort(importances)\nprint(\u0027Head importance ranking (least to most):\u0027, ranked.tolist())\nprint(\u0027Least important head (prune first): head\u0027, ranked[0])\n\n# Zero out the least important head in WO\nwith torch.no_grad():\n    dk = d_model // h\n    mha.out_proj.weight[:, ranked[0]*dk:(ranked[0]+1)*dk] = 0\n    pruned, _ = mha(x, x, x)\n\ndiff = (baseline - pruned).abs().mean().item()\nprint(\u0027Output change after pruning head {}: {:.4f}\u0027.format(ranked[0], diff))"},{"type":"heading","level":2,"content":"Single-Head vs Multi-Head Task Comparison"},{"type":"text","content":"A single attention head can represent at most one routing pattern per layer — it is limited to a rank-1 weighting of value vectors from a single subspace. Tasks requiring simultaneous attention to multiple diverse positions (subject+verb+object, or token+its coreference antecedent+sentence end) force a single head to compromise. Multi-head attention achieves a higher effective rank in its output transformation, enabling it to route through multiple independent pathways and combine them in the output projection."},{"type":"code","language":"python","content":"import numpy as np\n\ndef softmax(S):\n    S = S - S.max(axis=-1, keepdims=True)\n    e = np.exp(S); return e / e.sum(axis=-1, keepdims=True)\n\ndef single_head(Q, K, V, Wq, Wk, Wv, Wo):\n    A = softmax((Q @ Wq) @ (K @ Wk).T / np.sqrt(Wq.shape[1]))\n    return (A @ (V @ Wv)) @ Wo\n\ndef multi_head(Q, K, V, WQs, WKs, WVs, Wo):\n    heads = [(softmax((Q@Wq)@(K@Wk).T/np.sqrt(Wq.shape[1])))@(V@Wv)\n             for Wq, Wk, Wv in zip(WQs, WKs, WVs)]\n    return np.concatenate(heads, axis=-1) @ Wo\n\nnp.random.seed(1)\nn, d, h = 12, 64, 8\ndk = d // h\nQ = K = V = np.random.randn(n, d)\n\nWq1 = np.random.randn(d, d) * 0.1\nWk1 = np.random.randn(d, d) * 0.1\nWv1 = np.eye(d); Wo1 = np.eye(d)\nsh_out = single_head(Q, K, V, Wq1, Wk1, Wv1, Wo1)\n\nWQs = [np.random.randn(d, dk)*0.1 for _ in range(h)]\nWKs = [np.random.randn(d, dk)*0.1 for _ in range(h)]\nWVs = [np.eye(d)[:, i*dk:(i+1)*dk] for i in range(h)]\nWOm = np.random.randn(d, d) * 0.1\nmh_out = multi_head(Q, K, V, WQs, WKs, WVs, WOm)\n\nprint(\u0027Single-head output matrix rank:\u0027, np.linalg.matrix_rank(sh_out))\nprint(\u0027Multi-head output matrix rank: \u0027, np.linalg.matrix_rank(mh_out))\nprint(\u0027Multi-head achieves higher rank -\u003e richer representational capacity.\u0027)"},{"type":"heading","level":2,"content":"Diminishing Returns and Practical Guidance"},{"type":"text","content":"Empirical results show diminishing returns beyond 8–16 heads for most NLP tasks at standard model sizes. Beyond that, additional heads often converge to similar patterns or act as attention sinks. The optimal h balances representational diversity (favouring more heads) against per-head capacity (favouring fewer, wider heads). For very large models (d_model ≥ 4096) more heads help by splitting the enormous key space; for small models (d_model ≤ 256) fewer heads with larger dₖ typically work better."},{"type":"table","headers":["Head Type","What It Attends To","Example in BERT","Safely Prunable?"],"rows":[["Local / positional","Adjacent tokens (prev or next position)","Each word attending to its immediate neighbour","Often yes — low task relevance"],["Syntactic dependency","Head noun → modifier; subject → verb","Noun attending to its governing verb","No — task-critical"],["Coreference","Pronoun → its antecedent noun","\u0027it\u0027 attending to the entity it refers to","No — task-critical"],["Attention sink ([SEP]/[CLS])","Many tokens attend to special tokens","[SEP] acting as no-op information dump","Yes — minimal information transfer"],["Semantic similarity","Semantically related tokens across the sentence","Synonyms and co-hyponyms","Partially — depends on task"],["Rare-word","Low-frequency tokens attend globally","Unknown words gather broad context","Partially"]]},{"type":"list","ordered":false,"items":["Start with h = d_model / 64 as the default (dₖ = 64 per head): works well for d_model ∈ {256, 512, 768, 1024}","Grouped Query Attention (GQA): use fewer KV heads than Q heads to reduce KV cache at inference without much quality loss","Head pruning budget: for BERT-scale models, pruning 50% of heads typically costs \u003c 1% accuracy","Diagnostic: measure per-head entropy on a held-out set — heads with near-maximum entropy are candidates for pruning","Attention head analysis is most interpretable in the first few layers; deep layers exhibit less structured patterns"]},{"type":"divider"}]"
---
# Why Multiple Attention Heads — Different Subspace Specialisation

A Transformer with a single attention head per layer learns one global attention pattern per layer — a single learned similarity function applied uniformly to all queries. Multiple heads allow the model to simultaneously route information through h different learned routing functions, each operating on a different linear projection of the same input. This is not merely redundancy: different heads tend to specialise on syntactic dependencies, coreference, positional structure, and semantic similarity simultaneously.

## Single-Head Limitation

With a single attention head of dimension d_model, every position computes a single query and compares it to a single set of keys. The output is one weighted combination of value vectors — a rank-1 routing. If the task requires simultaneously attending to multiple unrelated positions (e.g., the subject of a sentence and a distant pronoun that refers to it), a single head must trade off between them, achieving neither reliably. Multiple heads circumvent this by partitioning the capacity — head 1 can attend to syntactic dependencies while head 2 handles coreference without either interfering with the other.

## Mathematical Justification — Subspace Representation

The projection matrices WᵢQ and WᵢK map the full d_model-dimensional input into a dₖ-dimensional subspace. Different heads project into different subspaces, so they measure similarity along different directions. Formally, h heads produce h independent attention-weighted sums of value projections; concatenating them before Wᴼ allows the output projection to mix information from all h subspaces. The rank of the combined output is bounded by min(h·dv, d_model) — potentially far higher than the rank achievable with a single head of dimension d_model.

Superposition theory (Elhage et al. 2022) provides a complementary view: with enough heads, a Transformer layer can store and retrieve multiple approximately-orthogonal 'features' simultaneously. Each head acts on a different subspace in which distinct features are nearly orthogonal; interference between features is suppressed across heads even when it cannot be avoided within a single head. This allows the model to maintain more independent 'thoughts' per layer than its raw dimension would suggest.

```python
import torch
import torch.nn as nn
import numpy as np

torch.manual_seed(42)
d_model, h = 256, 8
mha = nn.MultiheadAttention(d_model, h, batch_first=True)
WQ, WK, _ = mha.in_proj_weight.chunk(3, dim=0)
dk = d_model // h

tokens = ['[CLS]', 'the', 'cat', 'sat', 'on', 'mat', '[SEP]', '.']
seq_len = len(tokens)
x = torch.randn(1, seq_len, d_model)
x_flat = x.squeeze(0)

def head_attn(x_flat, i):
    with torch.no_grad():
        Q = (x_flat @ WQ.T)[:, i*dk:(i+1)*dk]
        K = (x_flat @ WK.T)[:, i*dk:(i+1)*dk]
        S = (Q @ K.T / dk**0.5).numpy()
    S -= S.max(1, keepdims=True)
    A = np.exp(S); A /= A.sum(1, keepdims=True)
    return A

print('Head | ' + ' | '.join('{:>5}'.format(t[:5]) for t in tokens))
print('-' * (7 + 8 * seq_len))
for i in range(h):
    A = head_attn(x_flat, i)
    peaks = [tokens[j][:5] for j in A.argmax(axis=1)]
    ent = -(A * np.log(A + 1e-9)).sum(1).mean()
    row = ' | '.join('{:>5}'.format(p) for p in peaks)
    print('H{:>2}  | {}  ent={:.2f}'.format(i, row, ent))
```

## Empirical Evidence — Clark et al. 2019

Clark et al. (2019) systematically analysed attention patterns across all 144 heads in BERT-base. They found clear functional specialisation: certain heads track direct object relationships, others attend to coreferent mentions, and a distinct class attends to the immediately preceding or following token. Crucially, some heads capture information highly correlated with the output of supervised dependency parsers — without any explicit supervision on syntax. This provides strong empirical evidence that multi-head attention spontaneously learns diverse, linguistically meaningful routing functions across heads.

> **Clark et al. 2019 Key Findings**: In BERT-base (12 layers × 12 heads = 144 heads total): (1) Heads in layers 6–10 show the strongest syntactic behaviour. (2) A single head in layer 8 achieves 76.1% accuracy on a coreference task with no fine-tuning. (3) Certain heads attend almost exclusively to [SEP] or [CLS] tokens — acting as 'no-op' attention sinks. (4) Removing any single head causes <1% performance drop; removing the top-5 most important heads causes ~3% drop. Attention patterns are sparse and interpretable at the head level.

```python
import torch
import torch.nn as nn

torch.manual_seed(7)
d_model, h, seq_len, batch = 128, 8, 20, 16

class TinyTransformerLayer(nn.Module):
    def __init__(self):
        super().__init__()
        self.attn = nn.MultiheadAttention(d_model, h, batch_first=True)
        self.norm = nn.LayerNorm(d_model)
        self.proj = nn.Linear(d_model, 1)

    def forward(self, x):
        a, _ = self.attn(x, x, x)
        x = self.norm(x + a)
        return self.proj(x.mean(dim=1))

model = TinyTransformerLayer()
x = torch.randn(batch, seq_len, d_model)
y = x.mean(dim=(1, 2)).unsqueeze(-1)
loss = nn.functional.mse_loss(model(x), y)
loss.backward()

WQ_g, WK_g, WV_g = model.attn.in_proj_weight.grad.chunk(3, dim=0)
dk = d_model // h
print('{:>6} {:>10} {:>10} {:>10} {:>12}'.format('Head', 'Q_grad', 'K_grad', 'V_grad', 'Importance'))
for i in range(h):
    qg = WQ_g[i*dk:(i+1)*dk].norm().item()
    kg = WK_g[i*dk:(i+1)*dk].norm().item()
    vg = WV_g[i*dk:(i+1)*dk].norm().item()
    imp = (qg + kg + vg) / 3
    print('{:>6} {:>10.4f} {:>10.4f} {:>10.4f} {:>12.4f}'.format(i, qg, kg, vg, imp))
print('Higher gradient norm -> head contributes more to this task.')
```

## Head Pruning

Michel et al. (2019) showed that most attention heads in BERT can be pruned at test time with minimal accuracy loss — for BERT-base on MNLI, only 16 of 144 heads are needed to retain 90% of performance. Voita et al. (2019) identified four head roles that are consistently preserved: positional (attend to adjacent token), syntactic (attend to syntactic dependents), rare-word (attend to low-frequency tokens), and coreference. Unimportant heads — those whose removal causes the smallest accuracy drop — can be zeroed out by setting the corresponding columns of Wᴼ to zero, which is equivalent to removing their contribution to the output.

```python
import torch
import torch.nn as nn
import numpy as np

torch.manual_seed(0)
d_model, h, n = 128, 8, 15

mha = nn.MultiheadAttention(d_model, h, batch_first=True)
x = torch.randn(4, n, d_model)

with torch.no_grad():
    baseline, _ = mha(x, x, x)

# Compute per-head importance: gradient of output L2 norm w.r.t. WV slice
importances = []
for i in range(h):
    x_req = x.clone().requires_grad_(True)
    out, _ = mha(x_req, x_req, x_req)
    out.norm().backward()
    WQ_g, WK_g, WV_g = mha.in_proj_weight.grad.chunk(3, dim=0) if mha.in_proj_weight.grad is not None else (torch.zeros(d_model,d_model),)*3
    dk = d_model // h
    importances.append(float(WV_g[i*dk:(i+1)*dk].norm()) if WV_g is not None else 0.0)
    mha.zero_grad()

importances = np.array(importances)
ranked = np.argsort(importances)
print('Head importance ranking (least to most):', ranked.tolist())
print('Least important head (prune first): head', ranked[0])

# Zero out the least important head in WO
with torch.no_grad():
    dk = d_model // h
    mha.out_proj.weight[:, ranked[0]*dk:(ranked[0]+1)*dk] = 0
    pruned, _ = mha(x, x, x)

diff = (baseline - pruned).abs().mean().item()
print('Output change after pruning head {}: {:.4f}'.format(ranked[0], diff))
```

## Single-Head vs Multi-Head Task Comparison

A single attention head can represent at most one routing pattern per layer — it is limited to a rank-1 weighting of value vectors from a single subspace. Tasks requiring simultaneous attention to multiple diverse positions (subject+verb+object, or token+its coreference antecedent+sentence end) force a single head to compromise. Multi-head attention achieves a higher effective rank in its output transformation, enabling it to route through multiple independent pathways and combine them in the output projection.

```python
import numpy as np

def softmax(S):
    S = S - S.max(axis=-1, keepdims=True)
    e = np.exp(S); return e / e.sum(axis=-1, keepdims=True)

def single_head(Q, K, V, Wq, Wk, Wv, Wo):
    A = softmax((Q @ Wq) @ (K @ Wk).T / np.sqrt(Wq.shape[1]))
    return (A @ (V @ Wv)) @ Wo

def multi_head(Q, K, V, WQs, WKs, WVs, Wo):
    heads = [(softmax((Q@Wq)@(K@Wk).T/np.sqrt(Wq.shape[1])))@(V@Wv)
             for Wq, Wk, Wv in zip(WQs, WKs, WVs)]
    return np.concatenate(heads, axis=-1) @ Wo

np.random.seed(1)
n, d, h = 12, 64, 8
dk = d // h
Q = K = V = np.random.randn(n, d)

Wq1 = np.random.randn(d, d) * 0.1
Wk1 = np.random.randn(d, d) * 0.1
Wv1 = np.eye(d); Wo1 = np.eye(d)
sh_out = single_head(Q, K, V, Wq1, Wk1, Wv1, Wo1)

WQs = [np.random.randn(d, dk)*0.1 for _ in range(h)]
WKs = [np.random.randn(d, dk)*0.1 for _ in range(h)]
WVs = [np.eye(d)[:, i*dk:(i+1)*dk] for i in range(h)]
WOm = np.random.randn(d, d) * 0.1
mh_out = multi_head(Q, K, V, WQs, WKs, WVs, WOm)

print('Single-head output matrix rank:', np.linalg.matrix_rank(sh_out))
print('Multi-head output matrix rank: ', np.linalg.matrix_rank(mh_out))
print('Multi-head achieves higher rank -> richer representational capacity.')
```

## Diminishing Returns and Practical Guidance

Empirical results show diminishing returns beyond 8–16 heads for most NLP tasks at standard model sizes. Beyond that, additional heads often converge to similar patterns or act as attention sinks. The optimal h balances representational diversity (favouring more heads) against per-head capacity (favouring fewer, wider heads). For very large models (d_model ≥ 4096) more heads help by splitting the enormous key space; for small models (d_model ≤ 256) fewer heads with larger dₖ typically work better.

| Head Type | What It Attends To | Example in BERT | Safely Prunable? |
| --- | --- | --- | --- |
| Local / positional | Adjacent tokens (prev or next position) | Each word attending to its immediate neighbour | Often yes — low task relevance |
| Syntactic dependency | Head noun → modifier; subject → verb | Noun attending to its governing verb | No — task-critical |
| Coreference | Pronoun → its antecedent noun | 'it' attending to the entity it refers to | No — task-critical |
| Attention sink ([SEP]/[CLS]) | Many tokens attend to special tokens | [SEP] acting as no-op information dump | Yes — minimal information transfer |
| Semantic similarity | Semantically related tokens across the sentence | Synonyms and co-hyponyms | Partially — depends on task |
| Rare-word | Low-frequency tokens attend globally | Unknown words gather broad context | Partially |

- Start with h = d_model / 64 as the default (dₖ = 64 per head): works well for d_model ∈ {256, 512, 768, 1024}
- Grouped Query Attention (GQA): use fewer KV heads than Q heads to reduce KV cache at inference without much quality loss
- Head pruning budget: for BERT-scale models, pruning 50% of heads typically costs < 1% accuracy
- Diagnostic: measure per-head entropy on a held-out set — heads with near-maximum entropy are candidates for pruning
- Attention head analysis is most interpretable in the first few layers; deep layers exhibit less structured patterns

---

