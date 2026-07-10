---
title: "Padding Mask — Variable-Length Sequences in Batches"
slug: "padding-mask-transformer"
description: "Handling variable-length sequences in batched Transformer training and inference by masking PAD tokens from attention, covering PyTorch and HuggingFace conventions plus sequence packing."
tags: ["deep-learning", "transformers"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"GPUs process examples in parallel batches, but natural language sequences vary wildly in length. A batch of sentences with lengths [3, 7, 12] must be padded to a common length of 12 before being stacked into a tensor. The padding tokens (PAD) are meaningless — they carry no information — but without explicit handling, the attention mechanism will happily attend to them, corrupting the computation and degrading model quality especially at the end of shorter sequences."},{"type":"heading","level":2,"content":"Variable-Length Sequences and the Padding Problem"},{"type":"text","content":"Two separate masking needs arise when padding is present. First, no query token should attend to PAD key positions — a real token at position 2 attending to a PAD token at position 9 would pull meaningless information into its representation. Second, PAD token queries themselves produce meaningless outputs, which must be zeroed out or ignored in the loss computation. The padding mask addresses the first concern by adding -∞ to attention scores at PAD key positions before softmax, producing zero attention weight on those positions."},{"type":"list","ordered":false,"items":["seq_lens = [3, 7, 12] → pad all sequences to max_len = 12","PAD token id (typically 0) added at positions beyond the real sequence length","Create key_padding_mask: True at PAD positions (PyTorch) or 0 at PAD positions (HuggingFace)","Mask maps to additive -∞ on PAD key columns before softmax","Loss: ignore PAD positions via label = -100 in CrossEntropyLoss"]},{"type":"callout","variant":"warning","title":"Convention Mismatch: PyTorch vs HuggingFace","content":"PyTorch nn.MultiheadAttention uses key_padding_mask where True means \u0027ignore this position\u0027 (ignore=True). HuggingFace transformers uses attention_mask where 1 means \u0027attend\u0027 and 0 means \u0027ignore\u0027 (attend=1). These are opposite conventions — converting between them is a common source of bugs when mixing PyTorch attention layers with HuggingFace tokenizers."},{"type":"heading","level":2,"content":"Constructing a Padding Mask from Sequence Lengths"},{"type":"text","content":"Given a list of actual sequence lengths, the padding mask is computed by broadcasting: create a (1, max_len) range tensor of position indices and compare it against a (B, 1) tensor of lengths. Positions where index \u003e= length are PAD. This vectorised comparison avoids looping over the batch and is fully GPU-compatible."},{"type":"heading","level":2,"content":"PyTorch vs HuggingFace Conventions"},{"type":"text","content":"The two major libraries use opposite sign conventions. PyTorch\u0027s nn.MultiheadAttention accepts key_padding_mask as a Boolean tensor where True flags positions to ignore, which it internally converts to -∞ additive values. HuggingFace models accept attention_mask as a float or int tensor where 1 flags real tokens and 0 flags PAD — the model converts 0s to -∞ additive values. Both achieve the same result but require different input preparation. When using a HuggingFace tokenizer with a custom PyTorch attention layer, always check and convert the convention."},{"type":"heading","level":2,"content":"Code 1 — Padding Mask from Sequence Lengths"},{"type":"text","content":"Vectorised construction of the additive padding mask from a list of real sequence lengths, returning shape (B, 1, 1, max_len) ready to broadcast over attention score tensors."},{"type":"code","language":"python","content":"import torch\n\ndef make_padding_mask(seq_lens: list, max_len: int,\n                      device: str = \u0027cpu\u0027) -\u003e torch.Tensor:\n    \"\"\"\n    Additive padding mask of shape (B, 1, 1, max_len).\n    Value: 0.0 at real token positions, -inf at PAD positions.\n    Broadcast-safe with attention scores of shape (B, H, L_q, L_k).\n    \"\"\"\n    B    = len(seq_lens)\n    ids  = torch.arange(max_len, device=device).unsqueeze(0)  # (1, max_len)\n    lens = torch.tensor(seq_lens, device=device).unsqueeze(1) # (B, 1)\n    is_pad = (ids \u003e= lens).float()                             # (B, max_len)\n    mask   = is_pad * float(\u0027-inf\u0027)                            # 0 or -inf\n    return mask.view(B, 1, 1, max_len)                         # (B,1,1,max_len)\n\n# Demo with three sequences of different lengths\nseq_lens = [6, 4, 2]\nmask = make_padding_mask(seq_lens, max_len=6)\nprint(\u0027Mask shape:\u0027, mask.shape)  # (3, 1, 1, 6)\nfor i, length in enumerate(seq_lens):\n    row = mask[i, 0, 0].tolist()\n    labels = [\u0027ok\u0027 if v == 0.0 else \u0027-inf\u0027 for v in row]\n    print(f\u0027  seq {i} (len={length}): {labels}\u0027)\n# Adding this mask to (B, H, L, L) scores blocks all PAD key columns"},{"type":"heading","level":2,"content":"Code 2 — nn.MultiheadAttention with key_padding_mask"},{"type":"text","content":"Using PyTorch\u0027s built-in MultiheadAttention with the key_padding_mask parameter, verifying that attention weights on PAD key positions are effectively zero."},{"type":"code","language":"python","content":"import torch\nimport torch.nn as nn\n\ntorch.manual_seed(0)\nB, L, d_model, n_heads = 3, 6, 64, 4\n\nmha = nn.MultiheadAttention(embed_dim=d_model, num_heads=n_heads, batch_first=True)\n\n# Input sequences; padding already applied (zeros at PAD positions)\nx = torch.randn(B, L, d_model)\nseq_lens = [6, 4, 2]\n\n# PyTorch key_padding_mask: True = ignore (PAD), False = attend (real token)\nids  = torch.arange(L).unsqueeze(0)              # (1, L)\nlens = torch.tensor(seq_lens).unsqueeze(1)        # (B, 1)\nkey_padding_mask = (ids \u003e= lens)                  # (B, L) bool, True at PAD\n\nout, attn_weights = mha(\n    query=x, key=x, value=x,\n    key_padding_mask=key_padding_mask,\n    need_weights=True,\n    average_attn_weights=False,\n)\nprint(\u0027Output shape:       \u0027, out.shape)           # (3, 6, 64)\nprint(\u0027Attn weights shape: \u0027, attn_weights.shape)  # (3, 4, 6, 6)\n\n# Verify: weights on PAD key columns should be near zero\nfor i, length in enumerate(seq_lens):\n    if length \u003c L:\n        pad_w = attn_weights[i, :, :length, length:].abs().max().item()\n        print(f\u0027  seq {i} (len={length}): max weight on PAD keys = {pad_w:.2e}\u0027)"},{"type":"heading","level":2,"content":"Code 3 — HuggingFace Attention Mask Convention"},{"type":"text","content":"Converting between the HuggingFace attention_mask (1=attend, 0=PAD) and the additive -∞ format expected by raw attention score tensors."},{"type":"code","language":"python","content":"import torch\n\ndef hf_to_additive_mask(attention_mask: torch.Tensor) -\u003e torch.Tensor:\n    \"\"\"\n    HuggingFace convention: attention_mask[b, pos] = 1 attend, 0 ignore.\n    Convert to additive mask: 0 at real positions, -inf at PAD positions.\n    Input: (B, L)  -\u003e  Output: (B, 1, 1, L) for broadcasting over (B, H, L, L).\n    \"\"\"\n    inverted = (1.0 - attention_mask.float()) * float(\u0027-inf\u0027)\n    return inverted.unsqueeze(1).unsqueeze(2)      # (B, 1, 1, L)\n\ndef additive_to_hf(mask: torch.Tensor) -\u003e torch.Tensor:\n    \"\"\"Reverse: additive (B,1,1,L) -\u003e HF attention_mask (B, L).\"\"\"\n    flat = mask.squeeze(1).squeeze(1)              # (B, L)\n    return (flat == 0.0).long()                    # 1 where real, 0 where -inf\n\n# Simulate HuggingFace tokenizer output (PAD id = 0)\ninput_ids = torch.tensor([\n    [101, 1234, 5678, 9012, 3456,  102],  # length 6\n    [101, 2468, 1357,  102,    0,    0],  # length 4, pads at 4,5\n    [101,  999,  102,    0,    0,    0],  # length 3, pads at 3,4,5\n])\nhf_mask   = (input_ids != 0).long()       # 1=real, 0=PAD  (HuggingFace)\nprint(\u0027HF attention_mask:\u0027)\nprint(hf_mask)\nadd_mask = hf_to_additive_mask(hf_mask)\nprint(\u0027Additive mask (seq 1):\u0027, add_mask[1, 0, 0].tolist())\n# [0.0, 0.0, 0.0, 0.0, -inf, -inf]"},{"type":"heading","level":2,"content":"Code 4 — Sequence Packing Without Padding"},{"type":"text","content":"For training efficiency, sequences can be packed end-to-end without PAD tokens, eliminating wasted compute. PyTorch\u0027s pack_padded_sequence / pad_packed_sequence implements this for RNN-style layers; for Transformers the same idea applies with custom position ids and segment attention masks."},{"type":"code","language":"python","content":"import torch\nfrom torch.nn.utils.rnn import pack_padded_sequence, pad_packed_sequence\n\ntorch.manual_seed(1)\nd_model  = 32\nseq_lens = [8, 5, 3]       # must be sorted descending for pack_padded_sequence\nmax_len  = max(seq_lens)\nB        = len(seq_lens)\n\n# Padded input: (B, max_len, d_model)\nx_padded = torch.randn(B, max_len, d_model)\nfor i, l in enumerate(seq_lens):\n    x_padded[i, l:] = 0.0  # zero-fill PAD positions for clarity\n\nprint(\u0027Padded tensor shape:\u0027, x_padded.shape)          # (3, 8, 32)\nprint(\u0027Total elements (with PAD):\u0027, B * max_len)\nprint(\u0027Real token count:         \u0027, sum(seq_lens))\nwaste = 100 * (1 - sum(seq_lens) / (B * max_len))\nprint(f\u0027Wasted compute (PAD fraction): {waste:.1f}%\u0027)\n\n# Pack: remove PAD tokens, concatenate only real tokens\nlengths_t = torch.tensor(seq_lens)\npacked = pack_padded_sequence(x_padded, lengths_t, batch_first=True,\n                               enforce_sorted=True)\nprint(\u0027\\nPacked data shape:\u0027, packed.data.shape)       # (16, 32) real tokens only\n\n# Unpack back to padded for loss computation\nunpacked, out_lens = pad_packed_sequence(packed, batch_first=True)\nprint(\u0027Unpacked shape:\u0027, unpacked.shape)\nprint(\u0027Recovered lengths:\u0027, out_lens.tolist())"},{"type":"heading","level":2,"content":"Padding Strategies Compared"},{"type":"table","headers":["Strategy","Model Type","Positions Masked","Implementation","HF Convention"],"rows":[["No mask","Any","None (attend to all)","Omit mask parameter","attention_mask: all 1s"],["Padding only","Encoder (BERT)","PAD key positions","key_padding_mask=True at PAD","attention_mask: 0 at PAD"],["Causal only","Decoder (GPT)","Future positions (j \u003e i)","attn_mask upper-tri -inf","Not a standard HF param"],["Causal + padding","Decoder (batched)","Future + PAD keys","Sum causal + pad additive masks","attention_mask + causal"],["Sequence packing","Any (training)","No PAD tokens at all","pack_padded_sequence or custom","Variable position_ids"]]},{"type":"text","content":"Padding masks are conceptually simple but operationally important: unmasked PAD tokens introduce spurious signal, especially in short sequences where PAD tokens form a large fraction of the batch. Sequence packing eliminates this overhead entirely during training. At inference, padding masks remain necessary when processing variable-length batches because most serving frameworks pad to a fixed bucket size for memory layout efficiency."}]"
---
# Padding Mask — Variable-Length Sequences in Batches

GPUs process examples in parallel batches, but natural language sequences vary wildly in length. A batch of sentences with lengths [3, 7, 12] must be padded to a common length of 12 before being stacked into a tensor. The padding tokens (PAD) are meaningless — they carry no information — but without explicit handling, the attention mechanism will happily attend to them, corrupting the computation and degrading model quality especially at the end of shorter sequences.

## Variable-Length Sequences and the Padding Problem

Two separate masking needs arise when padding is present. First, no query token should attend to PAD key positions — a real token at position 2 attending to a PAD token at position 9 would pull meaningless information into its representation. Second, PAD token queries themselves produce meaningless outputs, which must be zeroed out or ignored in the loss computation. The padding mask addresses the first concern by adding -∞ to attention scores at PAD key positions before softmax, producing zero attention weight on those positions.

- seq_lens = [3, 7, 12] → pad all sequences to max_len = 12
- PAD token id (typically 0) added at positions beyond the real sequence length
- Create key_padding_mask: True at PAD positions (PyTorch) or 0 at PAD positions (HuggingFace)
- Mask maps to additive -∞ on PAD key columns before softmax
- Loss: ignore PAD positions via label = -100 in CrossEntropyLoss

> **Convention Mismatch: PyTorch vs HuggingFace**: PyTorch nn.MultiheadAttention uses key_padding_mask where True means 'ignore this position' (ignore=True). HuggingFace transformers uses attention_mask where 1 means 'attend' and 0 means 'ignore' (attend=1). These are opposite conventions — converting between them is a common source of bugs when mixing PyTorch attention layers with HuggingFace tokenizers.

## Constructing a Padding Mask from Sequence Lengths

Given a list of actual sequence lengths, the padding mask is computed by broadcasting: create a (1, max_len) range tensor of position indices and compare it against a (B, 1) tensor of lengths. Positions where index >= length are PAD. This vectorised comparison avoids looping over the batch and is fully GPU-compatible.

## PyTorch vs HuggingFace Conventions

The two major libraries use opposite sign conventions. PyTorch's nn.MultiheadAttention accepts key_padding_mask as a Boolean tensor where True flags positions to ignore, which it internally converts to -∞ additive values. HuggingFace models accept attention_mask as a float or int tensor where 1 flags real tokens and 0 flags PAD — the model converts 0s to -∞ additive values. Both achieve the same result but require different input preparation. When using a HuggingFace tokenizer with a custom PyTorch attention layer, always check and convert the convention.

## Code 1 — Padding Mask from Sequence Lengths

Vectorised construction of the additive padding mask from a list of real sequence lengths, returning shape (B, 1, 1, max_len) ready to broadcast over attention score tensors.

```python
import torch

def make_padding_mask(seq_lens: list, max_len: int,
                      device: str = 'cpu') -> torch.Tensor:
    """
    Additive padding mask of shape (B, 1, 1, max_len).
    Value: 0.0 at real token positions, -inf at PAD positions.
    Broadcast-safe with attention scores of shape (B, H, L_q, L_k).
    """
    B    = len(seq_lens)
    ids  = torch.arange(max_len, device=device).unsqueeze(0)  # (1, max_len)
    lens = torch.tensor(seq_lens, device=device).unsqueeze(1) # (B, 1)
    is_pad = (ids >= lens).float()                             # (B, max_len)
    mask   = is_pad * float('-inf')                            # 0 or -inf
    return mask.view(B, 1, 1, max_len)                         # (B,1,1,max_len)

# Demo with three sequences of different lengths
seq_lens = [6, 4, 2]
mask = make_padding_mask(seq_lens, max_len=6)
print('Mask shape:', mask.shape)  # (3, 1, 1, 6)
for i, length in enumerate(seq_lens):
    row = mask[i, 0, 0].tolist()
    labels = ['ok' if v == 0.0 else '-inf' for v in row]
    print(f'  seq {i} (len={length}): {labels}')
# Adding this mask to (B, H, L, L) scores blocks all PAD key columns
```

## Code 2 — nn.MultiheadAttention with key_padding_mask

Using PyTorch's built-in MultiheadAttention with the key_padding_mask parameter, verifying that attention weights on PAD key positions are effectively zero.

```python
import torch
import torch.nn as nn

torch.manual_seed(0)
B, L, d_model, n_heads = 3, 6, 64, 4

mha = nn.MultiheadAttention(embed_dim=d_model, num_heads=n_heads, batch_first=True)

# Input sequences; padding already applied (zeros at PAD positions)
x = torch.randn(B, L, d_model)
seq_lens = [6, 4, 2]

# PyTorch key_padding_mask: True = ignore (PAD), False = attend (real token)
ids  = torch.arange(L).unsqueeze(0)              # (1, L)
lens = torch.tensor(seq_lens).unsqueeze(1)        # (B, 1)
key_padding_mask = (ids >= lens)                  # (B, L) bool, True at PAD

out, attn_weights = mha(
    query=x, key=x, value=x,
    key_padding_mask=key_padding_mask,
    need_weights=True,
    average_attn_weights=False,
)
print('Output shape:       ', out.shape)           # (3, 6, 64)
print('Attn weights shape: ', attn_weights.shape)  # (3, 4, 6, 6)

# Verify: weights on PAD key columns should be near zero
for i, length in enumerate(seq_lens):
    if length < L:
        pad_w = attn_weights[i, :, :length, length:].abs().max().item()
        print(f'  seq {i} (len={length}): max weight on PAD keys = {pad_w:.2e}')
```

## Code 3 — HuggingFace Attention Mask Convention

Converting between the HuggingFace attention_mask (1=attend, 0=PAD) and the additive -∞ format expected by raw attention score tensors.

```python
import torch

def hf_to_additive_mask(attention_mask: torch.Tensor) -> torch.Tensor:
    """
    HuggingFace convention: attention_mask[b, pos] = 1 attend, 0 ignore.
    Convert to additive mask: 0 at real positions, -inf at PAD positions.
    Input: (B, L)  ->  Output: (B, 1, 1, L) for broadcasting over (B, H, L, L).
    """
    inverted = (1.0 - attention_mask.float()) * float('-inf')
    return inverted.unsqueeze(1).unsqueeze(2)      # (B, 1, 1, L)

def additive_to_hf(mask: torch.Tensor) -> torch.Tensor:
    """Reverse: additive (B,1,1,L) -> HF attention_mask (B, L)."""
    flat = mask.squeeze(1).squeeze(1)              # (B, L)
    return (flat == 0.0).long()                    # 1 where real, 0 where -inf

# Simulate HuggingFace tokenizer output (PAD id = 0)
input_ids = torch.tensor([
    [101, 1234, 5678, 9012, 3456,  102],  # length 6
    [101, 2468, 1357,  102,    0,    0],  # length 4, pads at 4,5
    [101,  999,  102,    0,    0,    0],  # length 3, pads at 3,4,5
])
hf_mask   = (input_ids != 0).long()       # 1=real, 0=PAD  (HuggingFace)
print('HF attention_mask:')
print(hf_mask)
add_mask = hf_to_additive_mask(hf_mask)
print('Additive mask (seq 1):', add_mask[1, 0, 0].tolist())
# [0.0, 0.0, 0.0, 0.0, -inf, -inf]
```

## Code 4 — Sequence Packing Without Padding

For training efficiency, sequences can be packed end-to-end without PAD tokens, eliminating wasted compute. PyTorch's pack_padded_sequence / pad_packed_sequence implements this for RNN-style layers; for Transformers the same idea applies with custom position ids and segment attention masks.

```python
import torch
from torch.nn.utils.rnn import pack_padded_sequence, pad_packed_sequence

torch.manual_seed(1)
d_model  = 32
seq_lens = [8, 5, 3]       # must be sorted descending for pack_padded_sequence
max_len  = max(seq_lens)
B        = len(seq_lens)

# Padded input: (B, max_len, d_model)
x_padded = torch.randn(B, max_len, d_model)
for i, l in enumerate(seq_lens):
    x_padded[i, l:] = 0.0  # zero-fill PAD positions for clarity

print('Padded tensor shape:', x_padded.shape)          # (3, 8, 32)
print('Total elements (with PAD):', B * max_len)
print('Real token count:         ', sum(seq_lens))
waste = 100 * (1 - sum(seq_lens) / (B * max_len))
print(f'Wasted compute (PAD fraction): {waste:.1f}%')

# Pack: remove PAD tokens, concatenate only real tokens
lengths_t = torch.tensor(seq_lens)
packed = pack_padded_sequence(x_padded, lengths_t, batch_first=True,
                               enforce_sorted=True)
print('\nPacked data shape:', packed.data.shape)       # (16, 32) real tokens only

# Unpack back to padded for loss computation
unpacked, out_lens = pad_packed_sequence(packed, batch_first=True)
print('Unpacked shape:', unpacked.shape)
print('Recovered lengths:', out_lens.tolist())
```

## Padding Strategies Compared

| Strategy | Model Type | Positions Masked | Implementation | HF Convention |
| --- | --- | --- | --- | --- |
| No mask | Any | None (attend to all) | Omit mask parameter | attention_mask: all 1s |
| Padding only | Encoder (BERT) | PAD key positions | key_padding_mask=True at PAD | attention_mask: 0 at PAD |
| Causal only | Decoder (GPT) | Future positions (j > i) | attn_mask upper-tri -inf | Not a standard HF param |
| Causal + padding | Decoder (batched) | Future + PAD keys | Sum causal + pad additive masks | attention_mask + causal |
| Sequence packing | Any (training) | No PAD tokens at all | pack_padded_sequence or custom | Variable position_ids |

Padding masks are conceptually simple but operationally important: unmasked PAD tokens introduce spurious signal, especially in short sequences where PAD tokens form a large fraction of the batch. Sequence packing eliminates this overhead entirely during training. At inference, padding masks remain necessary when processing variable-length batches because most serving frameworks pad to a fixed bucket size for memory layout efficiency.

