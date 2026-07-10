---
title: "Special Tokens — BOS, EOS, PAD, Instruction Formats, and Chat Templates"
slug: "special-tokens-llm"
description: "Special tokens are structural vocabulary entries that control sequence boundaries, padding, and instruction formatting. Covers BOS/EOS/PAD roles, instruction format tokens across LLaMA-3/Mistral/ChatML/Alpaca/Gemma, apply_chat_template usage, stop token configuration, and left- vs right-padding strategies."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Special tokens are vocabulary entries with structural rather than semantic roles. Unlike regular subword tokens that represent text fragments, special tokens signal sequence boundaries, separate conversation turns, indicate padding positions, and trigger specific model behaviors. Every major language model family defines a distinct set of special tokens and an instruction format that the model has been trained to recognise. Mismatching these tokens at inference time — using the wrong chat template, wrong BOS token, or wrong stop condition — causes severe quality degradation even when the semantic content of the prompt is correct."},{"type":"heading","level":2,"content":"BOS, EOS, PAD — Core Structural Tokens"},{"type":"text","content":"BOS (beginning of sequence) is prepended to every input sequence and signals to the model where text begins. EOS (end of sequence) signals the model to stop generating; it is also the token the model is trained to predict at the end of its output. Without a properly recognised EOS token in the stopping criteria, decoder-only models continue generating past the intended output until they hit the context limit. PAD fills shorter sequences in a batch to match the maximum sequence length; PAD tokens are masked in the attention computation so they do not influence loss or logits. SEP separates segments in encoder models like BERT; CLS is prepended as the classification token whose final-layer representation is used for sequence-level tasks."},{"type":"heading","level":2,"content":"Instruction Format Tokens by Model Family"},{"type":"text","content":"LLaMA-3 uses \u003c|begin_of_text|\u003e as BOS, \u003c|eot_id|\u003e to mark end-of-turn, \u003c|start_header_id|\u003e and \u003c|end_header_id|\u003e to delimit role headers (system, user, assistant), and \u003c|end_of_text|\u003e as EOS. ChatML (used by GPT-4 and many open models) uses \u003c|im_start|\u003erole\\n...content...\u003c|im_end|\u003e for each turn. Mistral/Mixtral uses \u003cs\u003e as BOS, [INST] and [/INST] to delimit user turns, and \u003c/s\u003e as EOS with no explicit system token — system prompts are prepended to the first user message. Alpaca format uses human-readable delimiters: ### Instruction:\\n...\\n### Response:\\n with generation stopping on the next ### marker."},{"type":"heading","level":2,"content":"Inspecting Special Tokens Across Model Families"},{"type":"code","language":"python","content":"from transformers import AutoTokenizer\n\ndef inspect_special_tokens(model_name):\n    tok = AutoTokenizer.from_pretrained(model_name, trust_remote_code=True)\n    print(f\u0027\\n=== {model_name} ===\u0027)\n    print(f\u0027  bos_token:       {repr(tok.bos_token)} (id={tok.bos_token_id})\u0027)\n    print(f\u0027  eos_token:       {repr(tok.eos_token)} (id={tok.eos_token_id})\u0027)\n    print(f\u0027  pad_token:       {repr(tok.pad_token)} (id={tok.pad_token_id})\u0027)\n    print(f\u0027  unk_token:       {repr(tok.unk_token)} (id={tok.unk_token_id})\u0027)\n    print(f\u0027  sep_token:       {repr(tok.sep_token)}\u0027)\n    print(f\u0027  all_special_tokens ({len(tok.all_special_tokens)} total):\u0027)\n    for st in tok.all_special_tokens[:10]:\n        sid = tok.convert_tokens_to_ids(st)\n        print(f\u0027    {repr(st):\u003c40} id={sid}\u0027)\n    if hasattr(tok, \u0027chat_template\u0027) and tok.chat_template:\n        preview = tok.chat_template[:80].replace(\u0027\\n\u0027, \u0027 \u0027)\n        print(f\u0027  chat_template: {preview}...\u0027)\n\nmodels = [\n    \u0027meta-llama/Meta-Llama-3-8B-Instruct\u0027,\n    \u0027mistralai/Mistral-7B-Instruct-v0.2\u0027,\n    \u0027google/gemma-7b-it\u0027,\n]\nfor model in models:\n    try:\n        inspect_special_tokens(model)\n    except Exception as e:\n        print(f\u0027{model}: {e}\u0027)"},{"type":"heading","level":2,"content":"Chat Template Application"},{"type":"text","content":"HuggingFace tokenizers expose apply_chat_template(), which formats a list of role-content dictionaries into the model-specific instruction format. The template is stored in the tokenizer\u0027s tokenizer_config.json as a Jinja2 template string. Calling apply_chat_template() with add_generation_prompt=True appends the assistant header token, priming the model for response generation. Using this method guarantees correct formatting regardless of model family — the same Python code works for LLaMA-3, Mistral, and Gemma by switching only the model name."},{"type":"code","language":"python","content":"from transformers import AutoTokenizer\n\ndef format_conversation(model_name, system_msg, user_msg, assistant_msg=None):\n    tok = AutoTokenizer.from_pretrained(model_name)\n    messages = []\n    if system_msg:\n        messages.append({\u0027role\u0027: \u0027system\u0027, \u0027content\u0027: system_msg})\n    messages.append({\u0027role\u0027: \u0027user\u0027, \u0027content\u0027: user_msg})\n    if assistant_msg:\n        messages.append({\u0027role\u0027: \u0027assistant\u0027, \u0027content\u0027: assistant_msg})\n    formatted = tok.apply_chat_template(\n        messages,\n        tokenize=False,\n        add_generation_prompt=(assistant_msg is None),\n    )\n    token_ids = tok.apply_chat_template(\n        messages,\n        tokenize=True,\n        add_generation_prompt=(assistant_msg is None),\n        return_tensors=\u0027pt\u0027,\n    )\n    return formatted, token_ids\n\nsystem = \u0027You are a helpful assistant specialising in machine learning.\u0027\nuser = \u0027Explain the difference between BPE and WordPiece tokenization.\u0027\nmodels = [\u0027meta-llama/Meta-Llama-3-8B-Instruct\u0027, \u0027mistralai/Mistral-7B-Instruct-v0.2\u0027]\nfor model in models:\n    try:\n        text, ids = format_conversation(model, system, user)\n        print(f\u0027{model}:\u0027)\n        print(f\u0027  Token count: {ids.shape[-1]}\u0027)\n        print(f\u0027  First 200 chars: {text[:200]}\u0027)\n        print()\n    except Exception as e:\n        print(f\u0027{model}: {e}\u0027)"},{"type":"heading","level":2,"content":"Generation Stop Token Configuration"},{"type":"text","content":"Correct stop token configuration is essential for inference. The model\u0027s generate() method accepts eos_token_id as a single token id or a list of ids; generation halts when any of these ids is produced. For models with multiple stop tokens (LLaMA-3 has both \u003c|eot_id|\u003e and \u003c|end_of_text|\u003e), all valid stop ids must be included or the model will continue generating past the intended turn boundary. The stopping_criteria argument accepts custom StoppingCriteria subclasses for pattern-based stopping, useful when stop sequences span multiple tokens."},{"type":"code","language":"python","content":"import torch\nfrom transformers import AutoTokenizer, AutoModelForCausalLM, StoppingCriteria, StoppingCriteriaList\n\nclass MultiTokenStopCriteria(StoppingCriteria):\n    def __init__(self, stop_token_ids):\n        self.stop_ids = set(stop_token_ids)\n\n    def __call__(self, input_ids, scores, **kwargs):\n        last_token = input_ids[0, -1].item()\n        return last_token in self.stop_ids\n\ndef configure_generation(model_name, prompt):\n    tok = AutoTokenizer.from_pretrained(model_name)\n    # Collect all valid stop token ids for this model\n    stop_ids = []\n    for special in [tok.eos_token, \u0027\u003c|eot_id|\u003e\u0027, \u0027\u003c|end_of_text|\u003e\u0027, \u0027\u003c/s\u003e\u0027, \u0027\u003c|im_end|\u003e\u0027]:\n        if special and special in tok.get_vocab():\n            stop_ids.append(tok.convert_tokens_to_ids(special))\n    stop_criteria = StoppingCriteriaList([MultiTokenStopCriteria(stop_ids)])\n    print(f\u0027{model_name}:\u0027)\n    print(f\u0027  Stop token ids: {stop_ids}\u0027)\n    stop_tokens = [tok.convert_ids_to_tokens(sid) for sid in stop_ids]\n    print(f\u0027  Stop tokens:    {stop_tokens}\u0027)\n    return stop_criteria\n\nfor model in [\u0027meta-llama/Meta-Llama-3-8B\u0027, \u0027mistralai/Mistral-7B-v0.1\u0027]:\n    try:\n        configure_generation(model, \u0027test\u0027)\n    except Exception as e:\n        print(f\u0027{model}: {e}\u0027)"},{"type":"heading","level":2,"content":"Padding Strategy for Batched Inference"},{"type":"text","content":"Decoder-only models (GPT, LLaMA, Mistral) use left-padding for batched generation: PAD tokens are prepended so that all sequences in a batch end at the same position, allowing the model\u0027s autoregressive generation to begin at identical positions across batch elements. Right-padding is used for encoder training (BERT, RoBERTa) and for computing loss on variable-length sequences: padding is appended and masked via attention_mask. Using right-padding with a decoder-only model during generation causes incorrect output because the model sees PAD tokens between the prompt end and the first generated token."},{"type":"code","language":"python","content":"import torch\nfrom transformers import AutoTokenizer\n\ndef demonstrate_padding(model_name, prompts):\n    tok = AutoTokenizer.from_pretrained(model_name)\n    if tok.pad_token is None:\n        tok.pad_token = tok.eos_token\n\n    # Left-padding: correct for decoder-only generation\n    tok.padding_side = \u0027left\u0027\n    left_batch = tok(prompts, return_tensors=\u0027pt\u0027, padding=True, truncation=True)\n    print(f\u0027Left-padding (decoder generation):\u0027)\n    print(f\u0027  input_ids shape:      {left_batch.input_ids.shape}\u0027)\n    print(f\u0027  attention_mask shape: {left_batch.attention_mask.shape}\u0027)\n    print(f\u0027  First sequence ids:   {left_batch.input_ids[0].tolist()}\u0027)\n    print(f\u0027  First seq mask:       {left_batch.attention_mask[0].tolist()}\u0027)\n\n    # Right-padding: correct for encoder training\n    tok.padding_side = \u0027right\u0027\n    right_batch = tok(prompts, return_tensors=\u0027pt\u0027, padding=True, truncation=True)\n    print(f\u0027Right-padding (encoder training):\u0027)\n    print(f\u0027  First sequence ids:   {right_batch.input_ids[0].tolist()}\u0027)\n    print(f\u0027  First seq mask:       {right_batch.attention_mask[0].tolist()}\u0027)\n\nshort_prompts = [\u0027Hi\u0027, \u0027Explain BPE tokenization in detail please.\u0027]\ndemonstrate_padding(\u0027gpt2\u0027, short_prompts)"},{"type":"heading","level":2,"content":"Special Token Formats by Model Family"},{"type":"table","headers":["Model Family","BOS Token","Turn Delimiter","EOS Token","System Role Format"],"rows":[["LLaMA-3","\u003c|begin_of_text|\u003e","\u003c|eot_id|\u003e + \u003c|start_header_id|\u003erole\u003c|end_header_id|\u003e","\u003c|end_of_text|\u003e","\u003c|start_header_id|\u003esystem\u003c|end_header_id|\u003e\\n{content}\u003c|eot_id|\u003e"],["Mistral/Mixtral","\u003cs\u003e","[INST] / [/INST]","\u003c/s\u003e","No system tag — prepend to first user message inside [INST]"],["ChatML (GPT-4)","\u003c|im_start|\u003e","\u003c|im_end|\u003e\\n\u003c|im_start|\u003erole\\n","\u003c|endoftext|\u003e","\u003c|im_start|\u003esystem\\n{content}\u003c|im_end|\u003e"],["Alpaca","None","### Instruction:\\n / ### Response:\\n","Stop on next ### (pattern-based)","### System Prompt:\\n{content}\\n\\n"],["Gemma","\u003cbos\u003e","\u003cstart_of_turn\u003erole\\n / \u003cend_of_turn\u003e\\n","\u003ceos\u003e","\u003cstart_of_turn\u003euser\\n{system+user}\u003cend_of_turn\u003e"]]},{"type":"text","content":"System prompts encode the model\u0027s persona, constraints, and task context. In LLaMA-3 they are placed in a dedicated system header before the first user turn. In Mistral they are concatenated to the first user message inside [INST] brackets. In Gemma, there is no separate system role; system context is prepended to the user content in the first turn. These differences mean that a system prompt working correctly with one model family may produce different behavior on another even if the words are identical — the model has learned to respond to its specific structural delimiters."},{"type":"callout","variant":"warning","title":"Wrong Chat Template Causes Incoherent Outputs","content":"Using the wrong chat template for a model causes dramatic quality degradation — models are trained to recognise specific delimiter tokens around each turn, and mismatched templates produce incoherent outputs even with correct content. Always use apply_chat_template() from the model\u0027s own tokenizer rather than hand-constructing prompt strings. If the tokenizer lacks a chat_template field (older models), check the model card for the exact format used during instruction tuning."},{"type":"list","ordered":false,"items":["Always use apply_chat_template() — never hand-construct instruction prompts for instruction-tuned models.","Set eos_token_id to ALL valid stop token ids for the model family to prevent runaway generation.","Use left-padding for decoder-only generation batches; use right-padding for encoder training.","PAD token must be set for models that lack one (GPT-2): set pad_token = eos_token and mask it in attention_mask.","LLaMA-3 has two stop tokens: \u003c|eot_id|\u003e ends a turn, \u003c|end_of_text|\u003e ends the document — both must be in stop ids.","Tool call tokens in function-calling models (e.g., \u003ctool_call\u003e, \u003c|python_tag|\u003e) are additional special tokens to register."]},{"type":"divider"}]"
---
# Special Tokens — BOS, EOS, PAD, Instruction Formats, and Chat Templates

Special tokens are vocabulary entries with structural rather than semantic roles. Unlike regular subword tokens that represent text fragments, special tokens signal sequence boundaries, separate conversation turns, indicate padding positions, and trigger specific model behaviors. Every major language model family defines a distinct set of special tokens and an instruction format that the model has been trained to recognise. Mismatching these tokens at inference time — using the wrong chat template, wrong BOS token, or wrong stop condition — causes severe quality degradation even when the semantic content of the prompt is correct.

## BOS, EOS, PAD — Core Structural Tokens

BOS (beginning of sequence) is prepended to every input sequence and signals to the model where text begins. EOS (end of sequence) signals the model to stop generating; it is also the token the model is trained to predict at the end of its output. Without a properly recognised EOS token in the stopping criteria, decoder-only models continue generating past the intended output until they hit the context limit. PAD fills shorter sequences in a batch to match the maximum sequence length; PAD tokens are masked in the attention computation so they do not influence loss or logits. SEP separates segments in encoder models like BERT; CLS is prepended as the classification token whose final-layer representation is used for sequence-level tasks.

## Instruction Format Tokens by Model Family

LLaMA-3 uses <|begin_of_text|> as BOS, <|eot_id|> to mark end-of-turn, <|start_header_id|> and <|end_header_id|> to delimit role headers (system, user, assistant), and <|end_of_text|> as EOS. ChatML (used by GPT-4 and many open models) uses <|im_start|>role\n...content...<|im_end|> for each turn. Mistral/Mixtral uses <s> as BOS, [INST] and [/INST] to delimit user turns, and </s> as EOS with no explicit system token — system prompts are prepended to the first user message. Alpaca format uses human-readable delimiters: ### Instruction:\n...\n### Response:\n with generation stopping on the next ### marker.

## Inspecting Special Tokens Across Model Families

```python
from transformers import AutoTokenizer

def inspect_special_tokens(model_name):
    tok = AutoTokenizer.from_pretrained(model_name, trust_remote_code=True)
    print(f'\n=== {model_name} ===')
    print(f'  bos_token:       {repr(tok.bos_token)} (id={tok.bos_token_id})')
    print(f'  eos_token:       {repr(tok.eos_token)} (id={tok.eos_token_id})')
    print(f'  pad_token:       {repr(tok.pad_token)} (id={tok.pad_token_id})')
    print(f'  unk_token:       {repr(tok.unk_token)} (id={tok.unk_token_id})')
    print(f'  sep_token:       {repr(tok.sep_token)}')
    print(f'  all_special_tokens ({len(tok.all_special_tokens)} total):')
    for st in tok.all_special_tokens[:10]:
        sid = tok.convert_tokens_to_ids(st)
        print(f'    {repr(st):<40} id={sid}')
    if hasattr(tok, 'chat_template') and tok.chat_template:
        preview = tok.chat_template[:80].replace('\n', ' ')
        print(f'  chat_template: {preview}...')

models = [
    'meta-llama/Meta-Llama-3-8B-Instruct',
    'mistralai/Mistral-7B-Instruct-v0.2',
    'google/gemma-7b-it',
]
for model in models:
    try:
        inspect_special_tokens(model)
    except Exception as e:
        print(f'{model}: {e}')
```

## Chat Template Application

HuggingFace tokenizers expose apply_chat_template(), which formats a list of role-content dictionaries into the model-specific instruction format. The template is stored in the tokenizer's tokenizer_config.json as a Jinja2 template string. Calling apply_chat_template() with add_generation_prompt=True appends the assistant header token, priming the model for response generation. Using this method guarantees correct formatting regardless of model family — the same Python code works for LLaMA-3, Mistral, and Gemma by switching only the model name.

```python
from transformers import AutoTokenizer

def format_conversation(model_name, system_msg, user_msg, assistant_msg=None):
    tok = AutoTokenizer.from_pretrained(model_name)
    messages = []
    if system_msg:
        messages.append({'role': 'system', 'content': system_msg})
    messages.append({'role': 'user', 'content': user_msg})
    if assistant_msg:
        messages.append({'role': 'assistant', 'content': assistant_msg})
    formatted = tok.apply_chat_template(
        messages,
        tokenize=False,
        add_generation_prompt=(assistant_msg is None),
    )
    token_ids = tok.apply_chat_template(
        messages,
        tokenize=True,
        add_generation_prompt=(assistant_msg is None),
        return_tensors='pt',
    )
    return formatted, token_ids

system = 'You are a helpful assistant specialising in machine learning.'
user = 'Explain the difference between BPE and WordPiece tokenization.'
models = ['meta-llama/Meta-Llama-3-8B-Instruct', 'mistralai/Mistral-7B-Instruct-v0.2']
for model in models:
    try:
        text, ids = format_conversation(model, system, user)
        print(f'{model}:')
        print(f'  Token count: {ids.shape[-1]}')
        print(f'  First 200 chars: {text[:200]}')
        print()
    except Exception as e:
        print(f'{model}: {e}')
```

## Generation Stop Token Configuration

Correct stop token configuration is essential for inference. The model's generate() method accepts eos_token_id as a single token id or a list of ids; generation halts when any of these ids is produced. For models with multiple stop tokens (LLaMA-3 has both <|eot_id|> and <|end_of_text|>), all valid stop ids must be included or the model will continue generating past the intended turn boundary. The stopping_criteria argument accepts custom StoppingCriteria subclasses for pattern-based stopping, useful when stop sequences span multiple tokens.

```python
import torch
from transformers import AutoTokenizer, AutoModelForCausalLM, StoppingCriteria, StoppingCriteriaList

class MultiTokenStopCriteria(StoppingCriteria):
    def __init__(self, stop_token_ids):
        self.stop_ids = set(stop_token_ids)

    def __call__(self, input_ids, scores, **kwargs):
        last_token = input_ids[0, -1].item()
        return last_token in self.stop_ids

def configure_generation(model_name, prompt):
    tok = AutoTokenizer.from_pretrained(model_name)
    # Collect all valid stop token ids for this model
    stop_ids = []
    for special in [tok.eos_token, '<|eot_id|>', '<|end_of_text|>', '</s>', '<|im_end|>']:
        if special and special in tok.get_vocab():
            stop_ids.append(tok.convert_tokens_to_ids(special))
    stop_criteria = StoppingCriteriaList([MultiTokenStopCriteria(stop_ids)])
    print(f'{model_name}:')
    print(f'  Stop token ids: {stop_ids}')
    stop_tokens = [tok.convert_ids_to_tokens(sid) for sid in stop_ids]
    print(f'  Stop tokens:    {stop_tokens}')
    return stop_criteria

for model in ['meta-llama/Meta-Llama-3-8B', 'mistralai/Mistral-7B-v0.1']:
    try:
        configure_generation(model, 'test')
    except Exception as e:
        print(f'{model}: {e}')
```

## Padding Strategy for Batched Inference

Decoder-only models (GPT, LLaMA, Mistral) use left-padding for batched generation: PAD tokens are prepended so that all sequences in a batch end at the same position, allowing the model's autoregressive generation to begin at identical positions across batch elements. Right-padding is used for encoder training (BERT, RoBERTa) and for computing loss on variable-length sequences: padding is appended and masked via attention_mask. Using right-padding with a decoder-only model during generation causes incorrect output because the model sees PAD tokens between the prompt end and the first generated token.

```python
import torch
from transformers import AutoTokenizer

def demonstrate_padding(model_name, prompts):
    tok = AutoTokenizer.from_pretrained(model_name)
    if tok.pad_token is None:
        tok.pad_token = tok.eos_token

    # Left-padding: correct for decoder-only generation
    tok.padding_side = 'left'
    left_batch = tok(prompts, return_tensors='pt', padding=True, truncation=True)
    print(f'Left-padding (decoder generation):')
    print(f'  input_ids shape:      {left_batch.input_ids.shape}')
    print(f'  attention_mask shape: {left_batch.attention_mask.shape}')
    print(f'  First sequence ids:   {left_batch.input_ids[0].tolist()}')
    print(f'  First seq mask:       {left_batch.attention_mask[0].tolist()}')

    # Right-padding: correct for encoder training
    tok.padding_side = 'right'
    right_batch = tok(prompts, return_tensors='pt', padding=True, truncation=True)
    print(f'Right-padding (encoder training):')
    print(f'  First sequence ids:   {right_batch.input_ids[0].tolist()}')
    print(f'  First seq mask:       {right_batch.attention_mask[0].tolist()}')

short_prompts = ['Hi', 'Explain BPE tokenization in detail please.']
demonstrate_padding('gpt2', short_prompts)
```

## Special Token Formats by Model Family

| Model Family | BOS Token | Turn Delimiter | EOS Token | System Role Format |
| --- | --- | --- | --- | --- |
| LLaMA-3 | <|begin_of_text|> | <|eot_id|> + <|start_header_id|>role<|end_header_id|> | <|end_of_text|> | <|start_header_id|>system<|end_header_id|>\n{content}<|eot_id|> |
| Mistral/Mixtral | <s> | [INST] / [/INST] | </s> | No system tag — prepend to first user message inside [INST] |
| ChatML (GPT-4) | <|im_start|> | <|im_end|>\n<|im_start|>role\n | <|endoftext|> | <|im_start|>system\n{content}<|im_end|> |
| Alpaca | None | ### Instruction:\n / ### Response:\n | Stop on next ### (pattern-based) | ### System Prompt:\n{content}\n\n |
| Gemma | <bos> | <start_of_turn>role\n / <end_of_turn>\n | <eos> | <start_of_turn>user\n{system+user}<end_of_turn> |

System prompts encode the model's persona, constraints, and task context. In LLaMA-3 they are placed in a dedicated system header before the first user turn. In Mistral they are concatenated to the first user message inside [INST] brackets. In Gemma, there is no separate system role; system context is prepended to the user content in the first turn. These differences mean that a system prompt working correctly with one model family may produce different behavior on another even if the words are identical — the model has learned to respond to its specific structural delimiters.

> **Wrong Chat Template Causes Incoherent Outputs**: Using the wrong chat template for a model causes dramatic quality degradation — models are trained to recognise specific delimiter tokens around each turn, and mismatched templates produce incoherent outputs even with correct content. Always use apply_chat_template() from the model's own tokenizer rather than hand-constructing prompt strings. If the tokenizer lacks a chat_template field (older models), check the model card for the exact format used during instruction tuning.

- Always use apply_chat_template() — never hand-construct instruction prompts for instruction-tuned models.
- Set eos_token_id to ALL valid stop token ids for the model family to prevent runaway generation.
- Use left-padding for decoder-only generation batches; use right-padding for encoder training.
- PAD token must be set for models that lack one (GPT-2): set pad_token = eos_token and mask it in attention_mask.
- LLaMA-3 has two stop tokens: <|eot_id|> ends a turn, <|end_of_text|> ends the document — both must be in stop ids.
- Tool call tokens in function-calling models (e.g., <tool_call>, <|python_tag|>) are additional special tokens to register.

---

