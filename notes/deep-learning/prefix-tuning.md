---
title: "Prefix Tuning — Virtual Token Prepending to Each Layer's KV Cache"
slug: "prefix-tuning"
description: "Prefix tuning (Li & Liang, 2021) prepends learned virtual token vectors to the key and value tensors at every transformer attention layer, giving each layer independent task conditioning while freezing all base model weights."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Prompt tuning prepends learned tokens to the input embedding layer only — these soft tokens must propagate their influence through all attention layers via the residual stream. Prefix tuning (Li \u0026 Liang, 2021) is more direct: it prepends learned prefix vectors P_K^l and P_V^l directly to the key and value matrices at every transformer layer l. This gives every layer independent, direct control over attention patterns regardless of how information flows through intermediate layers. The prefix vectors are the only trainable parameters; all transformer weights remain frozen."},{"type":"heading","level":2,"content":"Prefix vs Prompt Tuning"},{"type":"text","content":"Prompt tuning adds P tokens to the input embedding. These tokens attend to actual content tokens but are themselves attended to only at later layers through the residual. Prefix tuning adds P_K and P_V vectors directly to the K and V matrices of every attention layer. The content tokens can attend to the prefix at every layer — much stronger and more direct conditioning. The cost is proportionally more parameters (one prefix pair per layer vs one embedding block) and P consumed context positions."},{"type":"heading","level":2,"content":"Prefix Tuning Forward Pass"},{"type":"text","content":"For an attention layer with head dimension d_head and P prefix tokens, the key matrix becomes K = concat([P_K, K_input]) ∈ ℝ^{(P+T)×d_head} and similarly V = concat([P_V, V_input]) ∈ ℝ^{(P+T)×d_head}, where T is the sequence length. The query Q ∈ ℝ^{T×d_head} attends over all P+T positions. Causal masking is applied only to the input token positions; prefix tokens are always visible to all input positions (like a prefix that predates the sequence)."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.nn.functional as F\nimport math\n\nclass PrefixAttentionLayer(nn.Module):\n    \"\"\"Single multi-head attention layer with prefix tuning.\"\"\"\n\n    def __init__(self, d_model: int, n_heads: int, prefix_len: int):\n        super().__init__()\n        self.n_heads = n_heads\n        self.d_head = d_model // n_heads\n        self.prefix_len = prefix_len\n        self.W_q = nn.Linear(d_model, d_model, bias=False)\n        self.W_k = nn.Linear(d_model, d_model, bias=False)\n        self.W_v = nn.Linear(d_model, d_model, bias=False)\n        self.W_o = nn.Linear(d_model, d_model, bias=False)\n        # Learnable prefix key and value vectors (one per head)\n        self.prefix_k = nn.Parameter(torch.randn(1, prefix_len, d_model) * 0.02)\n        self.prefix_v = nn.Parameter(torch.randn(1, prefix_len, d_model) * 0.02)\n        # Freeze all non-prefix params\n        for p in [self.W_q.weight, self.W_k.weight, self.W_v.weight, self.W_o.weight]:\n            p.requires_grad_(False)\n\n    def forward(self, x: torch.Tensor) -\u003e torch.Tensor:\n        B, T, D = x.shape\n        Q = self.W_q(x).reshape(B, T, self.n_heads, self.d_head).transpose(1, 2)\n        K_input = self.W_k(x).reshape(B, T, self.n_heads, self.d_head).transpose(1, 2)\n        V_input = self.W_v(x).reshape(B, T, self.n_heads, self.d_head).transpose(1, 2)\n        # Expand prefix K and V to match batch and reshape for heads\n        P_K = self.W_k(self.prefix_k.expand(B, -1, -1)).reshape(B, self.prefix_len, self.n_heads, self.d_head).transpose(1, 2)\n        P_V = self.W_v(self.prefix_v.expand(B, -1, -1)).reshape(B, self.prefix_len, self.n_heads, self.d_head).transpose(1, 2)\n        K = torch.cat([P_K, K_input], dim=2)  # (B, H, P+T, d_head)\n        V = torch.cat([P_V, V_input], dim=2)\n        scale = math.sqrt(self.d_head)\n        attn = torch.softmax(Q @ K.transpose(-2, -1) / scale, dim=-1)\n        out = (attn @ V).transpose(1, 2).reshape(B, T, D)\n        return self.W_o(out)\n\nlayer = PrefixAttentionLayer(d_model=64, n_heads=4, prefix_len=10)\nx = torch.randn(2, 8, 64)\nprint(f\u0027Output shape: {layer(x).shape}\u0027)\ntrainable = sum(p.numel() for p in layer.parameters() if p.requires_grad)\nprint(f\u0027Trainable prefix params: {trainable}\u0027)"},{"type":"heading","level":2,"content":"MLP Reparameterization for Training Stability"},{"type":"text","content":"Li \u0026 Liang found that directly optimizing the prefix vectors P_K and P_V is unstable — the prefix tends to collapse to a degenerate solution in early training. To stabilize, they propose reparameterization: the actual prefix vectors are produced by a small MLP that takes a compact set of free parameters as input. After training, the MLP is discarded and only the output prefix vectors (the fixed-point of the MLP) are stored. This reparameterization is used only during training; at inference, the prefix vectors are materialized and cached."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nimport torch.optim as optim\n\nclass PrefixMLP(nn.Module):\n    \"\"\"MLP reparameterization for prefix tuning (used only during training).\"\"\"\n\n    def __init__(self, prefix_len: int, d_model: int, n_layers: int,\n                 bottleneck_dim: int = 512):\n        super().__init__()\n        self.prefix_len = prefix_len\n        self.d_model = d_model\n        self.n_layers = n_layers\n        # Free parameters: compact embedding for each prefix position\n        self.free_params = nn.Parameter(\n            torch.randn(prefix_len, bottleneck_dim) * 0.01\n        )\n        # MLP that expands free params to full prefix K and V for each layer\n        self.mlp = nn.Sequential(\n            nn.Linear(bottleneck_dim, bottleneck_dim * 2),\n            nn.Tanh(),\n            nn.Linear(bottleneck_dim * 2, n_layers * 2 * d_model),  # K and V per layer\n        )\n\n    def forward(self) -\u003e torch.Tensor:\n        \"\"\"Returns prefix tensor of shape (n_layers, 2, prefix_len, d_model).\"\"\"\n        out = self.mlp(self.free_params)  # (prefix_len, n_layers*2*d_model)\n        out = out.view(self.prefix_len, self.n_layers, 2, self.d_model)\n        return out.permute(1, 2, 0, 3)  # (n_layers, 2, prefix_len, d_model)\n\n    def materialize(self) -\u003e torch.Tensor:\n        \"\"\"Call after training to extract fixed prefix (MLP no longer needed).\"\"\"\n        with torch.no_grad():\n            return self()\n\n# Training setup\nprefix_mlp = PrefixMLP(prefix_len=20, d_model=768, n_layers=12, bottleneck_dim=256)\noptimizer = optim.AdamW(prefix_mlp.parameters(), lr=5e-3)\nprefixes = prefix_mlp()\nprint(f\u0027Prefix tensor shape: {prefixes.shape}\u0027)  # (12 layers, 2 for K/V, 20 tokens, 768 dim)\nprint(f\u0027MLP trainable params: {sum(p.numel() for p in prefix_mlp.parameters()):,}\u0027)\nmaterialized = prefix_mlp.materialize()\nprint(f\u0027Materialized prefix: {materialized.shape}\u0027)"},{"type":"heading","level":2,"content":"Full Model with Prefix Injection"},{"type":"text","content":"A complete prefix-tuned LLM wraps the base transformer to intercept each attention layer\u0027s key and value computation. The wrapper stores prefix vectors indexed by layer number and injects them during the forward pass. All base model parameters have requires_grad=False; only the prefix parameters are optimized."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom typing import Optional\n\nclass PrefixTunedModel(nn.Module):\n    \"\"\"Wraps a transformer to inject per-layer prefix vectors.\"\"\"\n\n    def __init__(self, base_model: nn.Module, n_layers: int,\n                 d_model: int, prefix_len: int = 20):\n        super().__init__()\n        self.base = base_model\n        self.prefix_len = prefix_len\n        # Freeze all base model parameters\n        for param in self.base.parameters():\n            param.requires_grad_(False)\n        # Learnable prefix K and V for every layer (shape: [n_layers, 2, P, d_model])\n        self.prefix = nn.Parameter(\n            torch.zeros(n_layers, 2, prefix_len, d_model)\n        )\n        nn.init.normal_(self.prefix, std=0.02)\n\n    def get_prefix_kv(self, layer_idx: int):\n        \"\"\"Return (prefix_K, prefix_V) for a given layer.\"\"\"\n        return self.prefix[layer_idx, 0], self.prefix[layer_idx, 1]\n\n    def forward(self, input_ids: torch.Tensor,\n                attention_mask: Optional[torch.Tensor] = None):\n        # Prepend prefix attention mask (all ones — prefix is always visible)\n        B = input_ids.shape[0]\n        if attention_mask is not None:\n            prefix_mask = torch.ones(B, self.prefix_len, device=input_ids.device)\n            attention_mask = torch.cat([prefix_mask, attention_mask], dim=1)\n        return self.base(input_ids, attention_mask=attention_mask,\n                         past_key_values=None)\n\n# Trainable parameter count\nn_layers, d_model, prefix_len = 12, 768, 20\nparams = n_layers * 2 * prefix_len * d_model\nprint(f\u0027Prefix trainable params: {params:,}\u0027)\nprint(f\u0027Approx. for GPT2-medium (24 layers, d=1024, P=100): \u0027\n      f\u0027{24*2*100*1024:,}\u0027)"},{"type":"heading","level":2,"content":"Multi-Task Prefix Storage and Routing"},{"type":"text","content":"Since prefix tuning only adds a small tensor per task, multiple tasks can be served from a single frozen base model by storing one prefix per task and loading the appropriate prefix at inference time. This is a form of task-conditional computation: the same model weights produce different behaviors based purely on which prefix is prepended to the KV cache."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\nfrom pathlib import Path\n\nclass PrefixStore:\n    \"\"\"Store and load task-specific prefixes for multi-task inference routing.\"\"\"\n\n    def __init__(self, save_dir: str):\n        self.save_dir = Path(save_dir)\n        self.save_dir.mkdir(parents=True, exist_ok=True)\n        self._cache: dict = {}\n\n    def save_prefix(self, task_name: str, prefix: torch.Tensor):\n        path = self.save_dir / f\u0027{task_name}_prefix.pt\u0027\n        torch.save(prefix.detach().cpu(), path)\n        self._cache[task_name] = prefix.detach().cpu()\n        print(f\u0027Saved prefix for task \"{task_name}\": {prefix.shape} -\u003e {path}\u0027)\n\n    def load_prefix(self, task_name: str, device: str = \u0027cpu\u0027) -\u003e torch.Tensor:\n        if task_name in self._cache:\n            return self._cache[task_name].to(device)\n        path = self.save_dir / f\u0027{task_name}_prefix.pt\u0027\n        prefix = torch.load(path, map_location=device)\n        self._cache[task_name] = prefix\n        return prefix\n\n    def list_tasks(self):\n        return [p.stem.replace(\u0027_prefix\u0027, \u0027\u0027) for p in self.save_dir.glob(\u0027*_prefix.pt\u0027)]\n\n# Demo: save prefixes for two tasks\nstore = PrefixStore(\u0027/tmp/prefix_store\u0027)\nfor task in [\u0027summarization\u0027, \u0027qa\u0027, \u0027translation\u0027]:\n    prefix = torch.randn(12, 2, 20, 768)  # (n_layers, KV, P, d)\n    store.save_prefix(task, prefix)\n\nprint(f\u0027Stored tasks: {store.list_tasks()}\u0027)\nloaded = store.load_prefix(\u0027qa\u0027)\nprint(f\u0027Loaded QA prefix: {loaded.shape}\u0027)"},{"type":"heading","level":2,"content":"Parameter Count and Context Cost"},{"type":"text","content":"For a model with L layers, prefix length P, and hidden dimension d: trainable parameters = L × 2 × P × d (factor of 2 for K and V). For GPT-2 medium (L=24, d=1024, P=100): 24 × 2 × 100 × 1024 = 4.9M parameters — tiny compared to 354M total. Context cost: P positions are consumed per request, reducing usable sequence length from max_len to max_len - P. For long-context tasks with max_len=2048, P=100 reduces usable context by 5%."},{"type":"heading","level":2,"content":"Prefix Tuning vs Other PEFT Methods"},{"type":"table","headers":["Method","Where Adaptation Happens","Trainable Params","Context Consumed","Training Stability","Typical Performance Gap"],"rows":[["Full Fine-Tuning","All weights updated","100% of model","None","High","Baseline"],["Prefix Tuning","KV at every attention layer","L×2×P×d (~5M)","P tokens per layer","Needs MLP reparam","-2 to -4% vs FT"],["Prompt Tuning","Input embedding only","P×d (~0.1M)","P tokens (input only)","High (simpler)","-4 to -8% vs FT"],["Adapter","FFN after each attention","2×L×r×d (~7M)","None","High","-1 to -3% vs FT"],["LoRA r=16","Q and V weight matrices","4×L×r×d (~84M for 7B)","None","High","-1 to -2% vs FT"]]},{"type":"text","content":"Li \u0026 Liang (2021) evaluate prefix tuning on table-to-text generation (E2E, WebNLG, DART) and summarization (XSUM). With P=100 prefix tokens, prefix tuning matches or exceeds full fine-tuning on E2E and WebNLG despite only 0.1% of total parameters. On XSUM summarization, prefix tuning falls ~1 ROUGE point short. These results suggest prefix tuning is most effective on generation tasks with a clear format structure that the prefix can encode as a prior."},{"type":"callout","variant":"warning","title":"Prefix tokens reduce effective context window","content":"Prefix tuning consumes P positions from the effective context window at each layer — using P=100 prefix tokens reduces usable context by 100 tokens, which matters for long-context tasks and must be accounted for in max_length settings. For models already near their context limit (e.g., summarizing 1900-token documents with max_len=2048), reducing to 1948 usable positions may cause truncation."},{"type":"list","ordered":false,"items":["MLP reparameterization is needed only during training; materialize and discard the MLP before inference deployment.","Prefix length P is a hyperparameter: P=10 for simple tasks, P=50–100 for complex structured generation.","Causal LMs: prefix tokens should not be causally masked — use bidirectional attention for prefix positions.","Multi-task: one frozen base model + N small prefix files is more storage-efficient than N full fine-tuned models.","Prefix vs LoRA: prefix tuning is stronger for generation format control; LoRA is stronger for knowledge injection.","Combine with quantization: prefix vectors are small enough to store in FP32 even when the base model is in INT4."]},{"type":"divider"}]"
---
# Prefix Tuning — Virtual Token Prepending to Each Layer's KV Cache

Prompt tuning prepends learned tokens to the input embedding layer only — these soft tokens must propagate their influence through all attention layers via the residual stream. Prefix tuning (Li & Liang, 2021) is more direct: it prepends learned prefix vectors P_K^l and P_V^l directly to the key and value matrices at every transformer layer l. This gives every layer independent, direct control over attention patterns regardless of how information flows through intermediate layers. The prefix vectors are the only trainable parameters; all transformer weights remain frozen.

## Prefix vs Prompt Tuning

Prompt tuning adds P tokens to the input embedding. These tokens attend to actual content tokens but are themselves attended to only at later layers through the residual. Prefix tuning adds P_K and P_V vectors directly to the K and V matrices of every attention layer. The content tokens can attend to the prefix at every layer — much stronger and more direct conditioning. The cost is proportionally more parameters (one prefix pair per layer vs one embedding block) and P consumed context positions.

## Prefix Tuning Forward Pass

For an attention layer with head dimension d_head and P prefix tokens, the key matrix becomes K = concat([P_K, K_input]) ∈ ℝ^{(P+T)×d_head} and similarly V = concat([P_V, V_input]) ∈ ℝ^{(P+T)×d_head}, where T is the sequence length. The query Q ∈ ℝ^{T×d_head} attends over all P+T positions. Causal masking is applied only to the input token positions; prefix tokens are always visible to all input positions (like a prefix that predates the sequence).

```python
import torch
import torch.nn as nn
import torch.nn.functional as F
import math

class PrefixAttentionLayer(nn.Module):
    """Single multi-head attention layer with prefix tuning."""

    def __init__(self, d_model: int, n_heads: int, prefix_len: int):
        super().__init__()
        self.n_heads = n_heads
        self.d_head = d_model // n_heads
        self.prefix_len = prefix_len
        self.W_q = nn.Linear(d_model, d_model, bias=False)
        self.W_k = nn.Linear(d_model, d_model, bias=False)
        self.W_v = nn.Linear(d_model, d_model, bias=False)
        self.W_o = nn.Linear(d_model, d_model, bias=False)
        # Learnable prefix key and value vectors (one per head)
        self.prefix_k = nn.Parameter(torch.randn(1, prefix_len, d_model) * 0.02)
        self.prefix_v = nn.Parameter(torch.randn(1, prefix_len, d_model) * 0.02)
        # Freeze all non-prefix params
        for p in [self.W_q.weight, self.W_k.weight, self.W_v.weight, self.W_o.weight]:
            p.requires_grad_(False)

    def forward(self, x: torch.Tensor) -> torch.Tensor:
        B, T, D = x.shape
        Q = self.W_q(x).reshape(B, T, self.n_heads, self.d_head).transpose(1, 2)
        K_input = self.W_k(x).reshape(B, T, self.n_heads, self.d_head).transpose(1, 2)
        V_input = self.W_v(x).reshape(B, T, self.n_heads, self.d_head).transpose(1, 2)
        # Expand prefix K and V to match batch and reshape for heads
        P_K = self.W_k(self.prefix_k.expand(B, -1, -1)).reshape(B, self.prefix_len, self.n_heads, self.d_head).transpose(1, 2)
        P_V = self.W_v(self.prefix_v.expand(B, -1, -1)).reshape(B, self.prefix_len, self.n_heads, self.d_head).transpose(1, 2)
        K = torch.cat([P_K, K_input], dim=2)  # (B, H, P+T, d_head)
        V = torch.cat([P_V, V_input], dim=2)
        scale = math.sqrt(self.d_head)
        attn = torch.softmax(Q @ K.transpose(-2, -1) / scale, dim=-1)
        out = (attn @ V).transpose(1, 2).reshape(B, T, D)
        return self.W_o(out)

layer = PrefixAttentionLayer(d_model=64, n_heads=4, prefix_len=10)
x = torch.randn(2, 8, 64)
print(f'Output shape: {layer(x).shape}')
trainable = sum(p.numel() for p in layer.parameters() if p.requires_grad)
print(f'Trainable prefix params: {trainable}')
```

## MLP Reparameterization for Training Stability

Li & Liang found that directly optimizing the prefix vectors P_K and P_V is unstable — the prefix tends to collapse to a degenerate solution in early training. To stabilize, they propose reparameterization: the actual prefix vectors are produced by a small MLP that takes a compact set of free parameters as input. After training, the MLP is discarded and only the output prefix vectors (the fixed-point of the MLP) are stored. This reparameterization is used only during training; at inference, the prefix vectors are materialized and cached.

```python
import torch
import torch.nn as nn
import torch.optim as optim

class PrefixMLP(nn.Module):
    """MLP reparameterization for prefix tuning (used only during training)."""

    def __init__(self, prefix_len: int, d_model: int, n_layers: int,
                 bottleneck_dim: int = 512):
        super().__init__()
        self.prefix_len = prefix_len
        self.d_model = d_model
        self.n_layers = n_layers
        # Free parameters: compact embedding for each prefix position
        self.free_params = nn.Parameter(
            torch.randn(prefix_len, bottleneck_dim) * 0.01
        )
        # MLP that expands free params to full prefix K and V for each layer
        self.mlp = nn.Sequential(
            nn.Linear(bottleneck_dim, bottleneck_dim * 2),
            nn.Tanh(),
            nn.Linear(bottleneck_dim * 2, n_layers * 2 * d_model),  # K and V per layer
        )

    def forward(self) -> torch.Tensor:
        """Returns prefix tensor of shape (n_layers, 2, prefix_len, d_model)."""
        out = self.mlp(self.free_params)  # (prefix_len, n_layers*2*d_model)
        out = out.view(self.prefix_len, self.n_layers, 2, self.d_model)
        return out.permute(1, 2, 0, 3)  # (n_layers, 2, prefix_len, d_model)

    def materialize(self) -> torch.Tensor:
        """Call after training to extract fixed prefix (MLP no longer needed)."""
        with torch.no_grad():
            return self()

# Training setup
prefix_mlp = PrefixMLP(prefix_len=20, d_model=768, n_layers=12, bottleneck_dim=256)
optimizer = optim.AdamW(prefix_mlp.parameters(), lr=5e-3)
prefixes = prefix_mlp()
print(f'Prefix tensor shape: {prefixes.shape}')  # (12 layers, 2 for K/V, 20 tokens, 768 dim)
print(f'MLP trainable params: {sum(p.numel() for p in prefix_mlp.parameters()):,}')
materialized = prefix_mlp.materialize()
print(f'Materialized prefix: {materialized.shape}')
```

## Full Model with Prefix Injection

A complete prefix-tuned LLM wraps the base transformer to intercept each attention layer's key and value computation. The wrapper stores prefix vectors indexed by layer number and injects them during the forward pass. All base model parameters have requires_grad=False; only the prefix parameters are optimized.

```python
import torch
import torch.nn as nn
from typing import Optional

class PrefixTunedModel(nn.Module):
    """Wraps a transformer to inject per-layer prefix vectors."""

    def __init__(self, base_model: nn.Module, n_layers: int,
                 d_model: int, prefix_len: int = 20):
        super().__init__()
        self.base = base_model
        self.prefix_len = prefix_len
        # Freeze all base model parameters
        for param in self.base.parameters():
            param.requires_grad_(False)
        # Learnable prefix K and V for every layer (shape: [n_layers, 2, P, d_model])
        self.prefix = nn.Parameter(
            torch.zeros(n_layers, 2, prefix_len, d_model)
        )
        nn.init.normal_(self.prefix, std=0.02)

    def get_prefix_kv(self, layer_idx: int):
        """Return (prefix_K, prefix_V) for a given layer."""
        return self.prefix[layer_idx, 0], self.prefix[layer_idx, 1]

    def forward(self, input_ids: torch.Tensor,
                attention_mask: Optional[torch.Tensor] = None):
        # Prepend prefix attention mask (all ones — prefix is always visible)
        B = input_ids.shape[0]
        if attention_mask is not None:
            prefix_mask = torch.ones(B, self.prefix_len, device=input_ids.device)
            attention_mask = torch.cat([prefix_mask, attention_mask], dim=1)
        return self.base(input_ids, attention_mask=attention_mask,
                         past_key_values=None)

# Trainable parameter count
n_layers, d_model, prefix_len = 12, 768, 20
params = n_layers * 2 * prefix_len * d_model
print(f'Prefix trainable params: {params:,}')
print(f'Approx. for GPT2-medium (24 layers, d=1024, P=100): '
      f'{24*2*100*1024:,}')
```

## Multi-Task Prefix Storage and Routing

Since prefix tuning only adds a small tensor per task, multiple tasks can be served from a single frozen base model by storing one prefix per task and loading the appropriate prefix at inference time. This is a form of task-conditional computation: the same model weights produce different behaviors based purely on which prefix is prepended to the KV cache.

```python
import torch
import torch.nn as nn
from pathlib import Path

class PrefixStore:
    """Store and load task-specific prefixes for multi-task inference routing."""

    def __init__(self, save_dir: str):
        self.save_dir = Path(save_dir)
        self.save_dir.mkdir(parents=True, exist_ok=True)
        self._cache: dict = {}

    def save_prefix(self, task_name: str, prefix: torch.Tensor):
        path = self.save_dir / f'{task_name}_prefix.pt'
        torch.save(prefix.detach().cpu(), path)
        self._cache[task_name] = prefix.detach().cpu()
        print(f'Saved prefix for task "{task_name}": {prefix.shape} -> {path}')

    def load_prefix(self, task_name: str, device: str = 'cpu') -> torch.Tensor:
        if task_name in self._cache:
            return self._cache[task_name].to(device)
        path = self.save_dir / f'{task_name}_prefix.pt'
        prefix = torch.load(path, map_location=device)
        self._cache[task_name] = prefix
        return prefix

    def list_tasks(self):
        return [p.stem.replace('_prefix', '') for p in self.save_dir.glob('*_prefix.pt')]

# Demo: save prefixes for two tasks
store = PrefixStore('/tmp/prefix_store')
for task in ['summarization', 'qa', 'translation']:
    prefix = torch.randn(12, 2, 20, 768)  # (n_layers, KV, P, d)
    store.save_prefix(task, prefix)

print(f'Stored tasks: {store.list_tasks()}')
loaded = store.load_prefix('qa')
print(f'Loaded QA prefix: {loaded.shape}')
```

## Parameter Count and Context Cost

For a model with L layers, prefix length P, and hidden dimension d: trainable parameters = L × 2 × P × d (factor of 2 for K and V). For GPT-2 medium (L=24, d=1024, P=100): 24 × 2 × 100 × 1024 = 4.9M parameters — tiny compared to 354M total. Context cost: P positions are consumed per request, reducing usable sequence length from max_len to max_len - P. For long-context tasks with max_len=2048, P=100 reduces usable context by 5%.

## Prefix Tuning vs Other PEFT Methods

| Method | Where Adaptation Happens | Trainable Params | Context Consumed | Training Stability | Typical Performance Gap |
| --- | --- | --- | --- | --- | --- |
| Full Fine-Tuning | All weights updated | 100% of model | None | High | Baseline |
| Prefix Tuning | KV at every attention layer | L×2×P×d (~5M) | P tokens per layer | Needs MLP reparam | -2 to -4% vs FT |
| Prompt Tuning | Input embedding only | P×d (~0.1M) | P tokens (input only) | High (simpler) | -4 to -8% vs FT |
| Adapter | FFN after each attention | 2×L×r×d (~7M) | None | High | -1 to -3% vs FT |
| LoRA r=16 | Q and V weight matrices | 4×L×r×d (~84M for 7B) | None | High | -1 to -2% vs FT |

Li & Liang (2021) evaluate prefix tuning on table-to-text generation (E2E, WebNLG, DART) and summarization (XSUM). With P=100 prefix tokens, prefix tuning matches or exceeds full fine-tuning on E2E and WebNLG despite only 0.1% of total parameters. On XSUM summarization, prefix tuning falls ~1 ROUGE point short. These results suggest prefix tuning is most effective on generation tasks with a clear format structure that the prefix can encode as a prior.

> **Prefix tokens reduce effective context window**: Prefix tuning consumes P positions from the effective context window at each layer — using P=100 prefix tokens reduces usable context by 100 tokens, which matters for long-context tasks and must be accounted for in max_length settings. For models already near their context limit (e.g., summarizing 1900-token documents with max_len=2048), reducing to 1948 usable positions may cause truncation.

- MLP reparameterization is needed only during training; materialize and discard the MLP before inference deployment.
- Prefix length P is a hyperparameter: P=10 for simple tasks, P=50–100 for complex structured generation.
- Causal LMs: prefix tokens should not be causally masked — use bidirectional attention for prefix positions.
- Multi-task: one frozen base model + N small prefix files is more storage-efficient than N full fine-tuned models.
- Prefix vs LoRA: prefix tuning is stronger for generation format control; LoRA is stronger for knowledge injection.
- Combine with quantization: prefix vectors are small enough to store in FP32 even when the base model is in INT4.

---

