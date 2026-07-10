---
title: "Adapter Layers — Bottleneck Modules Between Transformer Layers"
slug: "adapter-layers"
description: "Adapter layers (Houlsby et al., 2019) insert small bottleneck FFN modules between transformer sub-layers. Covers the bottleneck architecture, near-identity initialization, serial vs parallel variants, Compacter, AdapterHub, adapter stacking, adapter fusion, and training procedure."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Adapter layers (Houlsby et al., 2019) are small bottleneck feed-forward modules inserted between sub-layers of a frozen pretrained transformer. Only the adapter parameters are trained; all original weights remain fixed. This allows a single large pretrained model to support many tasks simultaneously: different adapters are loaded per task while the backbone is shared. Adapters are the earliest and most widely studied PEFT method, predating LoRA, and their modular design has spawned an ecosystem of variants and tooling including AdapterHub, a public registry with 400+ pretrained adapters."},{"type":"heading","level":2,"content":"Bottleneck Architecture"},{"type":"text","content":"Each adapter applies the function: adapter(h) = h + W_up(σ(W_down(LayerNorm(h)))) where W_down ∈ ℝ^(d×m) is the down-projection and W_up ∈ ℝ^(m×d) is the up-projection. The bottleneck dimension m controls the capacity and parameter count. Typical values: m ∈ {8, 16, 32, 64}. The residual connection (h +) ensures that when W_up is initialized near zero, the adapter output is approximately h. For the Houlsby design, two adapters are inserted per transformer layer: one after the self-attention sub-layer and one after the FFN sub-layer. For BERT-base (d=768, 12 layers, m=64): params per adapter = 2×768×64 + 2×64 biases = 98,432; two adapters per layer × 12 layers = 2.36M total — about 0.9% of BERT-base\u0027s 110M parameters."},{"type":"heading","level":2,"content":"Near-Identity Initialization"},{"type":"text","content":"The near-identity initialization is not optional — it is the property that makes adapter insertion safe for a pretrained model. When W_up is initialized with values near zero (e.g., N(0, 0.001)), the adapter contribution W_up(σ(W_down(h))) ≈ 0, so the adapter output ≈ h. The pretrained model\u0027s predictions are preserved at the start of training. Without near-identity init, inserting adapters into a pretrained BERT and evaluating on any downstream task before training gives random outputs. This initialization also makes the adapter\u0027s optimization well-conditioned: the task loss starts at the pretrained model\u0027s loss, and the adapters gradually diverge toward a task-specific configuration."},{"type":"heading","level":2,"content":"Adapter Layer Implementation"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport math\n\nclass AdapterLayer(nn.Module):\n    \"\"\"\n    Bottleneck adapter: LayerNorm -\u003e down-project -\u003e activate -\u003e up-project -\u003e residual.\n    Near-identity at init: W_up initialized near zero.\n    \"\"\"\n\n    def __init__(self, d_model: int, bottleneck_dim: int,\n                 activation: str = \u0027gelu\u0027, dropout: float = 0.0):\n        super().__init__()\n        self.layer_norm = nn.LayerNorm(d_model)\n        self.down_proj = nn.Linear(d_model, bottleneck_dim)\n        self.up_proj   = nn.Linear(bottleneck_dim, d_model)\n        self.dropout   = nn.Dropout(dropout)\n        self.act = nn.GELU() if activation == \u0027gelu\u0027 else nn.ReLU()\n        self._near_identity_init()\n\n    def _near_identity_init(self):\n        \"\"\"Initialize W_up near zero so adapter output ≈ input at start.\"\"\"\n        nn.init.kaiming_uniform_(self.down_proj.weight, a=math.sqrt(5))\n        nn.init.zeros_(self.down_proj.bias)\n        nn.init.normal_(self.up_proj.weight, mean=0.0, std=1e-3)\n        nn.init.zeros_(self.up_proj.bias)\n\n    def forward(self, hidden: torch.Tensor) -\u003e torch.Tensor:\n        residual = hidden\n        h = self.layer_norm(hidden)\n        h = self.down_proj(h)\n        h = self.act(h)\n        h = self.dropout(h)\n        h = self.up_proj(h)\n        return residual + h\n\nadapter = AdapterLayer(d_model=768, bottleneck_dim=64)\nx = torch.randn(2, 10, 768)\nout = adapter(x)\nmax_diff = (out - x).abs().max().item()\nprint(f\u0027Max deviation from identity at init: {max_diff:.6f}\u0027)  # should be ~0\nprint(f\u0027Adapter trainable params: {sum(p.numel() for p in adapter.parameters()):,}\u0027)"},{"type":"heading","level":2,"content":"Injecting Adapters into a Transformer"},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom transformers import BertModel, BertConfig\n\nclass BertLayerWithAdapters(nn.Module):\n    \"\"\"Wrap a BERT layer to insert Houlsby-style adapters after attention and FFN.\"\"\"\n\n    def __init__(self, bert_layer, d_model: int = 768, bottleneck_dim: int = 64):\n        super().__init__()\n        self.bert_layer = bert_layer\n        for param in self.bert_layer.parameters():\n            param.requires_grad = False\n        self.adapter_attn = AdapterLayer(d_model, bottleneck_dim)\n        self.adapter_ffn  = AdapterLayer(d_model, bottleneck_dim)\n\n    def forward(self, hidden_states, attention_mask=None):\n        attn_out = self.bert_layer.attention(hidden_states, attention_mask)\n        hidden_states = self.adapter_attn(attn_out[0])\n        intermediate = self.bert_layer.intermediate(hidden_states)\n        ffn_out = self.bert_layer.output(intermediate, hidden_states)\n        hidden_states = self.adapter_ffn(ffn_out)\n        return (hidden_states,)\n\ndef inject_adapters(model_name: str = \u0027bert-base-uncased\u0027,\n                    bottleneck_dim: int = 64):\n    config = BertConfig.from_pretrained(model_name)\n    bert = BertModel.from_pretrained(model_name)\n    for i, layer in enumerate(bert.encoder.layer):\n        bert.encoder.layer[i] = BertLayerWithAdapters(\n            layer, config.hidden_size, bottleneck_dim\n        )\n    trainable = sum(p.numel() for p in bert.parameters() if p.requires_grad)\n    total = sum(p.numel() for p in bert.parameters())\n    print(f\u0027Trainable: {trainable:,} / {total:,} ({100*trainable/total:.2f}%)\u0027)\n    return bert\n\nprint(\u0027Houlsby design: 2 adapters per layer, freeze backbone, train adapters only.\u0027)"},{"type":"heading","level":2,"content":"AdapterHub Integration"},{"type":"code","language":"python","content":"import torch\nfrom transformers import AutoTokenizer\nfrom adapters import AutoAdapterModel\n\ndef load_pretrained_adapter(task: str = \u0027sentiment\u0027):\n    \"\"\"\n    Load a pretrained adapter from AdapterHub for a specific task.\n    AdapterHub hosts task-specific adapters for BERT, RoBERTa, T5, XLM-R.\n    \"\"\"\n    model = AutoAdapterModel.from_pretrained(\u0027bert-base-uncased\u0027)\n    tokenizer = AutoTokenizer.from_pretrained(\u0027bert-base-uncased\u0027)\n    adapter_name = model.load_adapter(\n        \u0027AdapterHub/bert-base-uncased-pf-sst2\u0027,\n        source=\u0027hf\u0027,\n        set_active=True\n    )\n    model.set_active_adapters(adapter_name)\n    trainable = sum(p.numel() for p in model.parameters() if p.requires_grad)\n    print(f\u0027Active adapter: {adapter_name}\u0027)\n    print(f\u0027Trainable params: {trainable:,}\u0027)\n    inputs = tokenizer(\u0027The film was a masterpiece.\u0027, return_tensors=\u0027pt\u0027)\n    with torch.no_grad():\n        logits = model(**inputs).logits\n    print(f\u0027Logits shape: {logits.shape}\u0027)\n    return model\n\nprint(\u0027AdapterHub: 400+ pretrained adapters; load in 2 lines of code.\u0027)"},{"type":"heading","level":2,"content":"Adapter Fusion"},{"type":"text","content":"Adapter fusion (Pfeiffer et al., 2021) combines outputs from K independently trained task-specific adapters via learned attention weights at inference time. Each adapter was trained on a different source task (e.g., NLI, QA, sentiment). For a new target task, the adapter weights are frozen and only the fusion attention weights are trained. This allows the model to learn which source-task adapters are most relevant for the new task. Fusion is applied at each transformer layer: a learned query-key attention over adapter outputs produces a weighted sum."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\nclass AdapterFusion(nn.Module):\n    \"\"\"\n    Combine K task-specific adapter outputs via learned attention weighting.\n    Adapter weights are frozen; only fusion attention weights are trained.\n    \"\"\"\n\n    def __init__(self, d_model: int, n_adapters: int):\n        super().__init__()\n        self.query = nn.Linear(d_model, d_model, bias=False)\n        self.keys = nn.Parameter(torch.randn(n_adapters, d_model) * 0.02)\n        self.scale = d_model ** -0.5\n\n    def forward(self, hidden: torch.Tensor,\n                adapter_outputs: list) -\u003e torch.Tensor:\n        q = self.query(hidden)                      # (bsz, seq, d)\n        scores = torch.einsum(\u0027bsd,nd-\u003ebsn\u0027, q, self.keys) * self.scale\n        weights = torch.softmax(scores, dim=-1)     # (bsz, seq, n_adapters)\n        stacked = torch.stack(adapter_outputs, dim=2)  # (bsz, seq, K, d)\n        fused = torch.einsum(\u0027bsn,bsnd-\u003ebsd\u0027, weights, stacked)\n        return hidden + fused\n\nbsz, seq, d, K = 2, 10, 768, 3\nfusion = AdapterFusion(d_model=d, n_adapters=K)\nhidden = torch.randn(bsz, seq, d)\nadapter_outs = [torch.randn(bsz, seq, d) for _ in range(K)]\nout = fusion(hidden, adapter_outs)\nprint(f\u0027Fusion output shape: {out.shape}\u0027)  # (2, 10, 768)\nfusion_trainable = sum(p.numel() for p in fusion.parameters())\nprint(f\u0027Fusion trainable params: {fusion_trainable:,}\u0027)"},{"type":"heading","level":2,"content":"Adapter Variants Comparison"},{"type":"table","headers":["Variant","Placement","Params per Layer","Quality vs Full FT","Modular (Swap at Inference)"],"rows":[["Houlsby (serial)","After attention + after FFN (2 per layer)","2 × 2dm","~99%","Yes"],["Pfeiffer (serial, single)","After FFN only (1 per layer)","2dm","~98%","Yes"],["Parallel adapter (PALs)","Parallel to attention sub-layer","2dm","~98%","Yes"],["Compacter","After FFN, Kronecker product weights","~4× smaller than Houlsby","~97%","Yes"],["LoRA-as-adapter","In Q, V weight matrices (additive)","2dr per matrix","~99%","Yes (merge or swap)"]]},{"type":"heading","level":2,"content":"Adapter Stacking and Composition"},{"type":"text","content":"Multiple adapters can be stacked within a single layer: the output of one adapter feeds into the next. This is useful for composing a general-domain adapter (e.g., trained on Wikipedia) with a task-specific adapter. AdapterHub supports stacking via adapter composition primitives: Stack([domain_adapter, task_adapter]) applies them sequentially. A simpler alternative is adapter averaging: take the element-wise average of two adapters\u0027 weight matrices when the tasks are related. This has been shown to outperform either single adapter on cross-lingual transfer tasks without any additional training."},{"type":"heading","level":2,"content":"Training Procedure and Hyperparameters"},{"type":"text","content":"Adapter training follows the same procedure as full fine-tuning but with two key differences: (1) the backbone optimizer group has learning rate 0 (frozen parameters do not receive gradient updates, but are included in the optimizer for compatibility with some schedulers), and (2) adapter parameters use a higher learning rate than full fine-tuning — typically 1e-4 to 5e-4 rather than 2e-5. Since adapters have far fewer parameters than the full model, they can afford more aggressive learning rates without instability. Training duration: adapter convergence typically requires 2–5 epochs, similar to full fine-tuning, as the loss landscape is smoother due to the near-identity initialization."},{"type":"callout","variant":"tip","title":"Prefer Pfeiffer Adapters","content":"Pfeiffer adapters (single adapter after FFN only, skipping post-attention) achieve 98% of Houlsby adapter performance with half the parameters — prefer Pfeiffer adapter architecture unless task-specific ablations favor the dual-adapter design."},{"type":"list","ordered":false,"items":["Near-identity init is critical: W_up ≈ 0 at start prevents adapter from disrupting pretrained performance.","Bottleneck dim m=64 is a good default; m=8–16 for extreme parameter efficiency with slight accuracy drop.","Pfeiffer \u003e Houlsby in params/performance ratio; use Houlsby only if ablations show clear benefit.","AdapterHub: 400+ pretrained adapters for BERT, RoBERTa, XLM-R across 30+ NLP tasks.","Adapter fusion: train fusion weights on target task after loading task-specific adapters from AdapterHub.","Parallel adapters are faster at inference (no sequential bottleneck) but require architecture changes.","Adapter learning rate: 1e-4 to 5e-4 (10× higher than full fine-tuning LR) is standard."]},{"type":"divider"}]"
---
# Adapter Layers — Bottleneck Modules Between Transformer Layers

Adapter layers (Houlsby et al., 2019) are small bottleneck feed-forward modules inserted between sub-layers of a frozen pretrained transformer. Only the adapter parameters are trained; all original weights remain fixed. This allows a single large pretrained model to support many tasks simultaneously: different adapters are loaded per task while the backbone is shared. Adapters are the earliest and most widely studied PEFT method, predating LoRA, and their modular design has spawned an ecosystem of variants and tooling including AdapterHub, a public registry with 400+ pretrained adapters.

## Bottleneck Architecture

Each adapter applies the function: adapter(h) = h + W_up(σ(W_down(LayerNorm(h)))) where W_down ∈ ℝ^(d×m) is the down-projection and W_up ∈ ℝ^(m×d) is the up-projection. The bottleneck dimension m controls the capacity and parameter count. Typical values: m ∈ {8, 16, 32, 64}. The residual connection (h +) ensures that when W_up is initialized near zero, the adapter output is approximately h. For the Houlsby design, two adapters are inserted per transformer layer: one after the self-attention sub-layer and one after the FFN sub-layer. For BERT-base (d=768, 12 layers, m=64): params per adapter = 2×768×64 + 2×64 biases = 98,432; two adapters per layer × 12 layers = 2.36M total — about 0.9% of BERT-base's 110M parameters.

## Near-Identity Initialization

The near-identity initialization is not optional — it is the property that makes adapter insertion safe for a pretrained model. When W_up is initialized with values near zero (e.g., N(0, 0.001)), the adapter contribution W_up(σ(W_down(h))) ≈ 0, so the adapter output ≈ h. The pretrained model's predictions are preserved at the start of training. Without near-identity init, inserting adapters into a pretrained BERT and evaluating on any downstream task before training gives random outputs. This initialization also makes the adapter's optimization well-conditioned: the task loss starts at the pretrained model's loss, and the adapters gradually diverge toward a task-specific configuration.

## Adapter Layer Implementation

```python
import torch
import torch.nn as nn
import math

class AdapterLayer(nn.Module):
    """
    Bottleneck adapter: LayerNorm -> down-project -> activate -> up-project -> residual.
    Near-identity at init: W_up initialized near zero.
    """

    def __init__(self, d_model: int, bottleneck_dim: int,
                 activation: str = 'gelu', dropout: float = 0.0):
        super().__init__()
        self.layer_norm = nn.LayerNorm(d_model)
        self.down_proj = nn.Linear(d_model, bottleneck_dim)
        self.up_proj   = nn.Linear(bottleneck_dim, d_model)
        self.dropout   = nn.Dropout(dropout)
        self.act = nn.GELU() if activation == 'gelu' else nn.ReLU()
        self._near_identity_init()

    def _near_identity_init(self):
        """Initialize W_up near zero so adapter output ≈ input at start."""
        nn.init.kaiming_uniform_(self.down_proj.weight, a=math.sqrt(5))
        nn.init.zeros_(self.down_proj.bias)
        nn.init.normal_(self.up_proj.weight, mean=0.0, std=1e-3)
        nn.init.zeros_(self.up_proj.bias)

    def forward(self, hidden: torch.Tensor) -> torch.Tensor:
        residual = hidden
        h = self.layer_norm(hidden)
        h = self.down_proj(h)
        h = self.act(h)
        h = self.dropout(h)
        h = self.up_proj(h)
        return residual + h

adapter = AdapterLayer(d_model=768, bottleneck_dim=64)
x = torch.randn(2, 10, 768)
out = adapter(x)
max_diff = (out - x).abs().max().item()
print(f'Max deviation from identity at init: {max_diff:.6f}')  # should be ~0
print(f'Adapter trainable params: {sum(p.numel() for p in adapter.parameters()):,}')
```

## Injecting Adapters into a Transformer

```python
import torch
import torch.nn as nn
from transformers import BertModel, BertConfig

class BertLayerWithAdapters(nn.Module):
    """Wrap a BERT layer to insert Houlsby-style adapters after attention and FFN."""

    def __init__(self, bert_layer, d_model: int = 768, bottleneck_dim: int = 64):
        super().__init__()
        self.bert_layer = bert_layer
        for param in self.bert_layer.parameters():
            param.requires_grad = False
        self.adapter_attn = AdapterLayer(d_model, bottleneck_dim)
        self.adapter_ffn  = AdapterLayer(d_model, bottleneck_dim)

    def forward(self, hidden_states, attention_mask=None):
        attn_out = self.bert_layer.attention(hidden_states, attention_mask)
        hidden_states = self.adapter_attn(attn_out[0])
        intermediate = self.bert_layer.intermediate(hidden_states)
        ffn_out = self.bert_layer.output(intermediate, hidden_states)
        hidden_states = self.adapter_ffn(ffn_out)
        return (hidden_states,)

def inject_adapters(model_name: str = 'bert-base-uncased',
                    bottleneck_dim: int = 64):
    config = BertConfig.from_pretrained(model_name)
    bert = BertModel.from_pretrained(model_name)
    for i, layer in enumerate(bert.encoder.layer):
        bert.encoder.layer[i] = BertLayerWithAdapters(
            layer, config.hidden_size, bottleneck_dim
        )
    trainable = sum(p.numel() for p in bert.parameters() if p.requires_grad)
    total = sum(p.numel() for p in bert.parameters())
    print(f'Trainable: {trainable:,} / {total:,} ({100*trainable/total:.2f}%)')
    return bert

print('Houlsby design: 2 adapters per layer, freeze backbone, train adapters only.')
```

## AdapterHub Integration

```python
import torch
from transformers import AutoTokenizer
from adapters import AutoAdapterModel

def load_pretrained_adapter(task: str = 'sentiment'):
    """
    Load a pretrained adapter from AdapterHub for a specific task.
    AdapterHub hosts task-specific adapters for BERT, RoBERTa, T5, XLM-R.
    """
    model = AutoAdapterModel.from_pretrained('bert-base-uncased')
    tokenizer = AutoTokenizer.from_pretrained('bert-base-uncased')
    adapter_name = model.load_adapter(
        'AdapterHub/bert-base-uncased-pf-sst2',
        source='hf',
        set_active=True
    )
    model.set_active_adapters(adapter_name)
    trainable = sum(p.numel() for p in model.parameters() if p.requires_grad)
    print(f'Active adapter: {adapter_name}')
    print(f'Trainable params: {trainable:,}')
    inputs = tokenizer('The film was a masterpiece.', return_tensors='pt')
    with torch.no_grad():
        logits = model(**inputs).logits
    print(f'Logits shape: {logits.shape}')
    return model

print('AdapterHub: 400+ pretrained adapters; load in 2 lines of code.')
```

## Adapter Fusion

Adapter fusion (Pfeiffer et al., 2021) combines outputs from K independently trained task-specific adapters via learned attention weights at inference time. Each adapter was trained on a different source task (e.g., NLI, QA, sentiment). For a new target task, the adapter weights are frozen and only the fusion attention weights are trained. This allows the model to learn which source-task adapters are most relevant for the new task. Fusion is applied at each transformer layer: a learned query-key attention over adapter outputs produces a weighted sum.

```python
import torch
import torch.nn as nn

class AdapterFusion(nn.Module):
    """
    Combine K task-specific adapter outputs via learned attention weighting.
    Adapter weights are frozen; only fusion attention weights are trained.
    """

    def __init__(self, d_model: int, n_adapters: int):
        super().__init__()
        self.query = nn.Linear(d_model, d_model, bias=False)
        self.keys = nn.Parameter(torch.randn(n_adapters, d_model) * 0.02)
        self.scale = d_model ** -0.5

    def forward(self, hidden: torch.Tensor,
                adapter_outputs: list) -> torch.Tensor:
        q = self.query(hidden)                      # (bsz, seq, d)
        scores = torch.einsum('bsd,nd->bsn', q, self.keys) * self.scale
        weights = torch.softmax(scores, dim=-1)     # (bsz, seq, n_adapters)
        stacked = torch.stack(adapter_outputs, dim=2)  # (bsz, seq, K, d)
        fused = torch.einsum('bsn,bsnd->bsd', weights, stacked)
        return hidden + fused

bsz, seq, d, K = 2, 10, 768, 3
fusion = AdapterFusion(d_model=d, n_adapters=K)
hidden = torch.randn(bsz, seq, d)
adapter_outs = [torch.randn(bsz, seq, d) for _ in range(K)]
out = fusion(hidden, adapter_outs)
print(f'Fusion output shape: {out.shape}')  # (2, 10, 768)
fusion_trainable = sum(p.numel() for p in fusion.parameters())
print(f'Fusion trainable params: {fusion_trainable:,}')
```

## Adapter Variants Comparison

| Variant | Placement | Params per Layer | Quality vs Full FT | Modular (Swap at Inference) |
| --- | --- | --- | --- | --- |
| Houlsby (serial) | After attention + after FFN (2 per layer) | 2 × 2dm | ~99% | Yes |
| Pfeiffer (serial, single) | After FFN only (1 per layer) | 2dm | ~98% | Yes |
| Parallel adapter (PALs) | Parallel to attention sub-layer | 2dm | ~98% | Yes |
| Compacter | After FFN, Kronecker product weights | ~4× smaller than Houlsby | ~97% | Yes |
| LoRA-as-adapter | In Q, V weight matrices (additive) | 2dr per matrix | ~99% | Yes (merge or swap) |

## Adapter Stacking and Composition

Multiple adapters can be stacked within a single layer: the output of one adapter feeds into the next. This is useful for composing a general-domain adapter (e.g., trained on Wikipedia) with a task-specific adapter. AdapterHub supports stacking via adapter composition primitives: Stack([domain_adapter, task_adapter]) applies them sequentially. A simpler alternative is adapter averaging: take the element-wise average of two adapters' weight matrices when the tasks are related. This has been shown to outperform either single adapter on cross-lingual transfer tasks without any additional training.

## Training Procedure and Hyperparameters

Adapter training follows the same procedure as full fine-tuning but with two key differences: (1) the backbone optimizer group has learning rate 0 (frozen parameters do not receive gradient updates, but are included in the optimizer for compatibility with some schedulers), and (2) adapter parameters use a higher learning rate than full fine-tuning — typically 1e-4 to 5e-4 rather than 2e-5. Since adapters have far fewer parameters than the full model, they can afford more aggressive learning rates without instability. Training duration: adapter convergence typically requires 2–5 epochs, similar to full fine-tuning, as the loss landscape is smoother due to the near-identity initialization.

> **Prefer Pfeiffer Adapters**: Pfeiffer adapters (single adapter after FFN only, skipping post-attention) achieve 98% of Houlsby adapter performance with half the parameters — prefer Pfeiffer adapter architecture unless task-specific ablations favor the dual-adapter design.

- Near-identity init is critical: W_up ≈ 0 at start prevents adapter from disrupting pretrained performance.
- Bottleneck dim m=64 is a good default; m=8–16 for extreme parameter efficiency with slight accuracy drop.
- Pfeiffer > Houlsby in params/performance ratio; use Houlsby only if ablations show clear benefit.
- AdapterHub: 400+ pretrained adapters for BERT, RoBERTa, XLM-R across 30+ NLP tasks.
- Adapter fusion: train fusion weights on target task after loading task-specific adapters from AdapterHub.
- Parallel adapters are faster at inference (no sequential bottleneck) but require architecture changes.
- Adapter learning rate: 1e-4 to 5e-4 (10× higher than full fine-tuning LR) is standard.

---

