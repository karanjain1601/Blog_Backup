---
title: "Chat Templates — System/User/Assistant Format and Tokenizer Integration"
slug: "chat-templates"
description: "Chat templates standardize multi-turn conversation encoding as Jinja2 templates in tokenizer_config.json — covering LLaMA-3, Mistral, ChatML, and Phi-3 formats, applying templates with HuggingFace tokenizers, implementing SFT loss masking, and encoding tool-calling sequences correctly."
tags: ["deep-learning", "llm"]
topic: "deep-learning"
status: "published"
updated: "2026-07-10"
blocks_json: "[{"type":"text","content":"Chat templates define how multi-turn conversations between system, user, and assistant roles are serialized into a flat token sequence for language model input. Each model family uses a distinct format with unique role delimiters, special tokens, and turn boundaries. HuggingFace stores these templates as Jinja2 strings in tokenizer_config.json and exposes them via tokenizer.apply_chat_template(). Using the correct template at both training and inference time is non-negotiable — even minor format differences cause the model to fail to follow instructions or produce repetitive text."},{"type":"heading","level":2,"content":"Why Chat Templates Matter"},{"type":"text","content":"Chat-tuned models are trained on millions of conversations formatted according to a specific template. The model learns to associate role delimiter tokens with behavioral patterns: after the assistant header token, the model generates a response; after the user header token, it switches to listening mode. If you apply the wrong template at inference time — wrong delimiters, missing newlines, wrong EOS token — the model sees a format it was not trained on, which degrades generation quality significantly. The failure mode is subtle: the model may still generate text, but it ignores the system prompt, fails to stop at the right turn boundary, or produces generic completions."},{"type":"heading","level":2,"content":"Applying Built-in Templates with HuggingFace"},{"type":"text","content":"tokenizer.apply_chat_template() is the standard API for converting a list of role-content dicts to a formatted string or token IDs. The key parameters: tokenize=True to get token IDs (for model input), tokenize=False to get the formatted string (for inspection); add_generation_prompt=True appends the start of the assistant turn to prompt the model to generate a response. The template is sourced from tokenizer.chat_template — a Jinja2 string in tokenizer_config.json. For models without a built-in template, a ValueError is raised, indicating the model was not trained with a standard chat format."},{"type":"code","language":"python","content":"from transformers import AutoTokenizer\n\ndef compare_chat_templates(user_prompt, system_msg=\u0027You are a helpful assistant.\u0027):\n    # Apply and compare chat templates for LLaMA-3 and Mistral\n    messages_with_system = [\n        {\u0027role\u0027: \u0027system\u0027, \u0027content\u0027: system_msg},\n        {\u0027role\u0027: \u0027user\u0027, \u0027content\u0027: user_prompt},\n    ]\n    messages_no_system = [{\u0027role\u0027: \u0027user\u0027, \u0027content\u0027: user_prompt}]\n    model_configs = [\n        (\u0027meta-llama/Meta-Llama-3-8B-Instruct\u0027, True),\n        (\u0027mistralai/Mistral-7B-Instruct-v0.3\u0027, False),\n    ]\n    for model_id, supports_system in model_configs:\n        try:\n            tokenizer = AutoTokenizer.from_pretrained(model_id)\n            msgs = messages_with_system if supports_system else messages_no_system\n            formatted = tokenizer.apply_chat_template(msgs, tokenize=False, add_generation_prompt=True)\n            tokens = tokenizer.apply_chat_template(msgs, tokenize=True, add_generation_prompt=True)\n            print(f\u0027--- {model_id} ---\u0027)\n            print(f\u0027Formatted ({len(tokens)} tokens):\u0027)\n            print(repr(formatted[:250]))\n            print()\n        except Exception as e:\n            print(f\u0027{model_id}: {e}\u0027)\n\ndef inspect_template(model_id):\n    tok = AutoTokenizer.from_pretrained(model_id)\n    tmpl = tok.chat_template or \u0027No chat_template found\u0027\n    print(f\u0027Template ({len(tmpl)} chars):\u0027, tmpl[:200], \u0027...\u0027)\n\ncompare_chat_templates(\u0027Explain transformer attention in 3 sentences.\u0027)\nprint(\u0027Template mismatch at inference -\u003e generic output or instruction-following failure\u0027)"},{"type":"heading","level":2,"content":"Custom Jinja2 Templates"},{"type":"text","content":"When a model lacks a built-in template or you need a custom format, you can write a Jinja2 template and assign it to tokenizer.chat_template. The template has access to the messages list and add_generation_prompt boolean. Role names are accessed via message[\u0027role\u0027] and content via message[\u0027content\u0027]. The template is saved to tokenizer_config.json when you call tokenizer.save_pretrained(), persisting it for future use. ChatML is the most widely adopted custom format — it was popularized by OpenAI and is used as the default for many open-source models fine-tuned without format specification."},{"type":"code","language":"python","content":"from transformers import AutoTokenizer\nfrom jinja2 import Environment\n\nCHATML_TEMPLATE = (\n    \u0027{%- for message in messages %}\u0027\n    \u0027{%- if message[\"role\"] == \"system\" %}\u003c|im_start|\u003esystem\\n{{ message[\"content\"] }}\u003c|im_end|\u003e\\n\u0027\n    \u0027{%- elif message[\"role\"] == \"user\" %}\u003c|im_start|\u003euser\\n{{ message[\"content\"] }}\u003c|im_end|\u003e\\n\u0027\n    \u0027{%- elif message[\"role\"] == \"assistant\" %}\u003c|im_start|\u003eassistant\\n{{ message[\"content\"] }}\u003c|im_end|\u003e\\n\u0027\n    \u0027{%- endif %}{%- endfor %}\u0027\n    \u0027{%- if add_generation_prompt %}\u003c|im_start|\u003eassistant\\n{%- endif %}\u0027\n)\n\ndef apply_template_manually(messages, template_str, add_generation_prompt=True):\n    # Apply Jinja2 template without a tokenizer (for inspection/testing)\n    env = Environment()\n    tmpl = env.from_string(template_str)\n    return tmpl.render(messages=messages, add_generation_prompt=add_generation_prompt)\n\ndef register_custom_template(base_model_id, custom_template):\n    # Assign custom chat template to tokenizer and save\n    tokenizer = AutoTokenizer.from_pretrained(base_model_id)\n    tokenizer.chat_template = custom_template\n    print(f\u0027Template registered: {len(custom_template)} chars\u0027)\n    print(\u0027Save with: tokenizer.save_pretrained(output_dir)\u0027)\n    return tokenizer\n\nsample_msgs = [\n    {\u0027role\u0027: \u0027system\u0027, \u0027content\u0027: \u0027You are a concise assistant.\u0027},\n    {\u0027role\u0027: \u0027user\u0027, \u0027content\u0027: \u0027What is 2+2?\u0027},\n    {\u0027role\u0027: \u0027assistant\u0027, \u0027content\u0027: \u00274.\u0027},\n    {\u0027role\u0027: \u0027user\u0027, \u0027content\u0027: \u0027Why?\u0027},\n]\nformatted = apply_template_manually(sample_msgs, CHATML_TEMPLATE)\nprint(\u0027ChatML formatted output:\u0027)\nprint(repr(formatted))\nprint(f\u0027Length: {len(formatted)} chars\u0027)"},{"type":"heading","level":2,"content":"Training with Template-Based Loss Masking"},{"type":"text","content":"For SFT training on multi-turn conversations, the loss should be computed only on assistant tokens — system and user tokens are inputs, not learning targets. The standard approach: (1) apply the chat template to get the full token sequence; (2) find the token positions of each assistant response; (3) set labels to -100 (ignored by cross-entropy loss) for all non-assistant positions. The assistant response boundaries are identified by encoding the response text separately and searching for the matching token subsequence in the full sequence. HuggingFace TRL\u0027s DataCollatorForCompletionOnlyLM automates this masking."},{"type":"code","language":"python","content":"import torch\nfrom transformers import AutoTokenizer\n\ndef create_sft_labels(messages, tokenizer, ignore_index=-100):\n    # Apply template, mask non-assistant tokens with ignore_index\n    full_text = tokenizer.apply_chat_template(messages, tokenize=False, add_generation_prompt=False)\n    encodings = tokenizer(full_text, return_tensors=\u0027pt\u0027)\n    input_ids = encodings[\u0027input_ids\u0027][0]\n    labels = input_ids.clone()\n    # Start by masking everything, then unmask assistant response tokens\n    labels[:] = ignore_index\n    for msg in messages:\n        if msg[\u0027role\u0027] != \u0027assistant\u0027:\n            continue\n        resp_ids = tokenizer.encode(msg[\u0027content\u0027], add_special_tokens=False)\n        resp_len = len(resp_ids)\n        for i in range(len(input_ids) - resp_len + 1):\n            if input_ids[i:i + resp_len].tolist() == resp_ids:\n                labels[i:i + resp_len] = input_ids[i:i + resp_len]\n                break\n    n_supervised = (labels != ignore_index).sum().item()\n    n_total = len(input_ids)\n    print(f\u0027Total tokens: {n_total}, supervised: {n_supervised}, masked: {n_total - n_supervised}\u0027)\n    print(f\u0027Supervision ratio: {n_supervised/n_total:.2%} (assistant tokens only)\u0027)\n    return {\u0027input_ids\u0027: input_ids, \u0027labels\u0027: labels,\n            \u0027attention_mask\u0027: encodings[\u0027attention_mask\u0027][0]}\n\nmsgs = [\n    {\u0027role\u0027: \u0027system\u0027, \u0027content\u0027: \u0027Be helpful.\u0027},\n    {\u0027role\u0027: \u0027user\u0027, \u0027content\u0027: \u0027What is Python?\u0027},\n    {\u0027role\u0027: \u0027assistant\u0027, \u0027content\u0027: \u0027Python is a high-level programming language known for readability.\u0027},\n]\nprint(\u0027SFT masking: only assistant tokens contribute to the training loss\u0027)"},{"type":"heading","level":2,"content":"Tool Calling Template Format"},{"type":"text","content":"Tool calling extends the chat template to encode function definitions, function call invocations, and tool results as part of the conversation. LLaMA-3.1+ uses a \u003c|python_tag|\u003e or special JSON format within the assistant turn. Mistral uses a [TOOL_CALLS] marker. Models trained on tool-use data expect the exact format used during training — passing tools to tokenizer.apply_chat_template() formats them correctly. The tool definition is typically injected into the system prompt as a JSON schema, and function call outputs are injected as tool-role messages."},{"type":"code","language":"python","content":"import json\nfrom transformers import AutoTokenizer\n\ndef format_tool_conversation(tokenizer):\n    # Format a tool-use conversation with function call and result\n    tools = [{\n        \u0027type\u0027: \u0027function\u0027,\n        \u0027function\u0027: {\n            \u0027name\u0027: \u0027get_weather\u0027,\n            \u0027description\u0027: \u0027Get current weather for a city\u0027,\n            \u0027parameters\u0027: {\n                \u0027type\u0027: \u0027object\u0027,\n                \u0027properties\u0027: {\u0027location\u0027: {\u0027type\u0027: \u0027string\u0027, \u0027description\u0027: \u0027City name\u0027}},\n                \u0027required\u0027: [\u0027location\u0027],\n            },\n        },\n    }]\n    messages = [\n        {\u0027role\u0027: \u0027system\u0027, \u0027content\u0027: \u0027You are a helpful assistant with tool access.\u0027},\n        {\u0027role\u0027: \u0027user\u0027, \u0027content\u0027: \u0027What is the weather in Tokyo?\u0027},\n        {\u0027role\u0027: \u0027assistant\u0027, \u0027content\u0027: None,\n         \u0027tool_calls\u0027: [{\u0027id\u0027: \u0027call_001\u0027, \u0027type\u0027: \u0027function\u0027,\n                         \u0027function\u0027: {\u0027name\u0027: \u0027get_weather\u0027, \u0027arguments\u0027: \u0027{\"location\": \"Tokyo\"}\u0027}}]},\n        {\u0027role\u0027: \u0027tool\u0027, \u0027tool_call_id\u0027: \u0027call_001\u0027,\n         \u0027content\u0027: \u0027{\"temperature\": 22, \"condition\": \"sunny\", \"humidity\": 60}\u0027},\n        {\u0027role\u0027: \u0027assistant\u0027, \u0027content\u0027: \u0027It is currently 22 degrees Celsius and sunny in Tokyo.\u0027},\n    ]\n    try:\n        formatted = tokenizer.apply_chat_template(messages, tools=tools, tokenize=False)\n        print(f\u0027Tool conversation formatted: {len(formatted)} chars\u0027)\n        print(repr(formatted[:400]))\n    except Exception as e:\n        print(f\u0027Tool formatting error: {e}\u0027)\n        print(\u0027Tool calling requires model-specific template with tool support\u0027)\n    return json.dumps(messages, indent=2)\n\nprint(\u0027Tool format: function defs in system, calls in assistant, results in tool role\u0027)\nprint(\u0027Training requires exact same format as inference for reliable tool invocation\u0027)"},{"type":"heading","level":2,"content":"Chat Templates Across Model Families"},{"type":"table","headers":["Model Family","System Role","Turn Delimiter","EOS Token","Tool Support","Format Name"],"rows":[["LLaMA-3","Yes (\u003c|start_header_id|\u003esystem\u003c|end_header_id|\u003e)","\u003c|eot_id|\u003e","\u003c|eot_id|\u003e","Yes (v3.1+)","LLaMA-3 format"],["Mistral / Mixtral","No (injected into first user turn)","[INST] / [/INST]","\u003c/s\u003e","Yes ([TOOL_CALLS])","Mistral Instruct"],["ChatML (Qwen, many fine-tunes)","Yes (\u003c|im_start|\u003esystem)","\u003c|im_end|\u003e","\u003c|im_end|\u003e","Varies by fine-tune","ChatML"],["Phi-3","Yes (\u003c|system|\u003e)","\u003c|end|\u003e","\u003c|end|\u003e","Phi-3.5+ only","Phi-3 format"],["Gemma","No system role (ignored)","\u003cend_of_turn\u003e","\u003ceos\u003e","Gemma 2+ with tool tag","Gemma format"]]},{"type":"heading","level":2,"content":"Common Pitfalls and Best Practices"},{"type":"text","content":"The most common pitfall is using the base model tokenizer template at inference for a fine-tuned model that was trained on a different template — or conversely, using the fine-tuned template for a base model that was not trained on it. Another frequent mistake is applying the template manually with string formatting instead of tokenizer.apply_chat_template(), which can produce subtle differences (missing newlines, wrong special token IDs) that degrade quality. Always verify the template produces the expected token IDs by comparing with the reference template output before training or deployment."},{"type":"list","ordered":false,"items":["Always use tokenizer.apply_chat_template() — never format conversations manually with string concatenation.","Check tokenizer.chat_template is not None before inference — a missing template is a silent failure mode.","Verify special tokens (im_start, eot_id, etc.) are in the tokenizer vocabulary — missing special tokens are mapped to UNK and break the format.","Use add_generation_prompt=True at inference and add_generation_prompt=False at training to avoid training on the generation prefix.","For multi-turn SFT datasets, verify the supervision ratio (assistant tokens / total tokens) — below 20% often indicates a masking bug."]},{"type":"callout","variant":"warning","title":"Template Mismatch Silently Degrades Quality","content":"Applying the wrong chat template at inference time causes the model to fail to follow instructions — even a minor difference (missing newline, wrong separator) breaks the expected format the model was trained on and produces generic or repeated text. Always match the inference template exactly to the training template, including whitespace details."},{"type":"divider"}]"
---
# Chat Templates — System/User/Assistant Format and Tokenizer Integration

Chat templates define how multi-turn conversations between system, user, and assistant roles are serialized into a flat token sequence for language model input. Each model family uses a distinct format with unique role delimiters, special tokens, and turn boundaries. HuggingFace stores these templates as Jinja2 strings in tokenizer_config.json and exposes them via tokenizer.apply_chat_template(). Using the correct template at both training and inference time is non-negotiable — even minor format differences cause the model to fail to follow instructions or produce repetitive text.

## Why Chat Templates Matter

Chat-tuned models are trained on millions of conversations formatted according to a specific template. The model learns to associate role delimiter tokens with behavioral patterns: after the assistant header token, the model generates a response; after the user header token, it switches to listening mode. If you apply the wrong template at inference time — wrong delimiters, missing newlines, wrong EOS token — the model sees a format it was not trained on, which degrades generation quality significantly. The failure mode is subtle: the model may still generate text, but it ignores the system prompt, fails to stop at the right turn boundary, or produces generic completions.

## Applying Built-in Templates with HuggingFace

tokenizer.apply_chat_template() is the standard API for converting a list of role-content dicts to a formatted string or token IDs. The key parameters: tokenize=True to get token IDs (for model input), tokenize=False to get the formatted string (for inspection); add_generation_prompt=True appends the start of the assistant turn to prompt the model to generate a response. The template is sourced from tokenizer.chat_template — a Jinja2 string in tokenizer_config.json. For models without a built-in template, a ValueError is raised, indicating the model was not trained with a standard chat format.

```python
from transformers import AutoTokenizer

def compare_chat_templates(user_prompt, system_msg='You are a helpful assistant.'):
    # Apply and compare chat templates for LLaMA-3 and Mistral
    messages_with_system = [
        {'role': 'system', 'content': system_msg},
        {'role': 'user', 'content': user_prompt},
    ]
    messages_no_system = [{'role': 'user', 'content': user_prompt}]
    model_configs = [
        ('meta-llama/Meta-Llama-3-8B-Instruct', True),
        ('mistralai/Mistral-7B-Instruct-v0.3', False),
    ]
    for model_id, supports_system in model_configs:
        try:
            tokenizer = AutoTokenizer.from_pretrained(model_id)
            msgs = messages_with_system if supports_system else messages_no_system
            formatted = tokenizer.apply_chat_template(msgs, tokenize=False, add_generation_prompt=True)
            tokens = tokenizer.apply_chat_template(msgs, tokenize=True, add_generation_prompt=True)
            print(f'--- {model_id} ---')
            print(f'Formatted ({len(tokens)} tokens):')
            print(repr(formatted[:250]))
            print()
        except Exception as e:
            print(f'{model_id}: {e}')

def inspect_template(model_id):
    tok = AutoTokenizer.from_pretrained(model_id)
    tmpl = tok.chat_template or 'No chat_template found'
    print(f'Template ({len(tmpl)} chars):', tmpl[:200], '...')

compare_chat_templates('Explain transformer attention in 3 sentences.')
print('Template mismatch at inference -> generic output or instruction-following failure')
```

## Custom Jinja2 Templates

When a model lacks a built-in template or you need a custom format, you can write a Jinja2 template and assign it to tokenizer.chat_template. The template has access to the messages list and add_generation_prompt boolean. Role names are accessed via message['role'] and content via message['content']. The template is saved to tokenizer_config.json when you call tokenizer.save_pretrained(), persisting it for future use. ChatML is the most widely adopted custom format — it was popularized by OpenAI and is used as the default for many open-source models fine-tuned without format specification.

```python
from transformers import AutoTokenizer
from jinja2 import Environment

CHATML_TEMPLATE = (
    '{%- for message in messages %}'
    '{%- if message["role"] == "system" %}<|im_start|>system\n{{ message["content"] }}<|im_end|>\n'
    '{%- elif message["role"] == "user" %}<|im_start|>user\n{{ message["content"] }}<|im_end|>\n'
    '{%- elif message["role"] == "assistant" %}<|im_start|>assistant\n{{ message["content"] }}<|im_end|>\n'
    '{%- endif %}{%- endfor %}'
    '{%- if add_generation_prompt %}<|im_start|>assistant\n{%- endif %}'
)

def apply_template_manually(messages, template_str, add_generation_prompt=True):
    # Apply Jinja2 template without a tokenizer (for inspection/testing)
    env = Environment()
    tmpl = env.from_string(template_str)
    return tmpl.render(messages=messages, add_generation_prompt=add_generation_prompt)

def register_custom_template(base_model_id, custom_template):
    # Assign custom chat template to tokenizer and save
    tokenizer = AutoTokenizer.from_pretrained(base_model_id)
    tokenizer.chat_template = custom_template
    print(f'Template registered: {len(custom_template)} chars')
    print('Save with: tokenizer.save_pretrained(output_dir)')
    return tokenizer

sample_msgs = [
    {'role': 'system', 'content': 'You are a concise assistant.'},
    {'role': 'user', 'content': 'What is 2+2?'},
    {'role': 'assistant', 'content': '4.'},
    {'role': 'user', 'content': 'Why?'},
]
formatted = apply_template_manually(sample_msgs, CHATML_TEMPLATE)
print('ChatML formatted output:')
print(repr(formatted))
print(f'Length: {len(formatted)} chars')
```

## Training with Template-Based Loss Masking

For SFT training on multi-turn conversations, the loss should be computed only on assistant tokens — system and user tokens are inputs, not learning targets. The standard approach: (1) apply the chat template to get the full token sequence; (2) find the token positions of each assistant response; (3) set labels to -100 (ignored by cross-entropy loss) for all non-assistant positions. The assistant response boundaries are identified by encoding the response text separately and searching for the matching token subsequence in the full sequence. HuggingFace TRL's DataCollatorForCompletionOnlyLM automates this masking.

```python
import torch
from transformers import AutoTokenizer

def create_sft_labels(messages, tokenizer, ignore_index=-100):
    # Apply template, mask non-assistant tokens with ignore_index
    full_text = tokenizer.apply_chat_template(messages, tokenize=False, add_generation_prompt=False)
    encodings = tokenizer(full_text, return_tensors='pt')
    input_ids = encodings['input_ids'][0]
    labels = input_ids.clone()
    # Start by masking everything, then unmask assistant response tokens
    labels[:] = ignore_index
    for msg in messages:
        if msg['role'] != 'assistant':
            continue
        resp_ids = tokenizer.encode(msg['content'], add_special_tokens=False)
        resp_len = len(resp_ids)
        for i in range(len(input_ids) - resp_len + 1):
            if input_ids[i:i + resp_len].tolist() == resp_ids:
                labels[i:i + resp_len] = input_ids[i:i + resp_len]
                break
    n_supervised = (labels != ignore_index).sum().item()
    n_total = len(input_ids)
    print(f'Total tokens: {n_total}, supervised: {n_supervised}, masked: {n_total - n_supervised}')
    print(f'Supervision ratio: {n_supervised/n_total:.2%} (assistant tokens only)')
    return {'input_ids': input_ids, 'labels': labels,
            'attention_mask': encodings['attention_mask'][0]}

msgs = [
    {'role': 'system', 'content': 'Be helpful.'},
    {'role': 'user', 'content': 'What is Python?'},
    {'role': 'assistant', 'content': 'Python is a high-level programming language known for readability.'},
]
print('SFT masking: only assistant tokens contribute to the training loss')
```

## Tool Calling Template Format

Tool calling extends the chat template to encode function definitions, function call invocations, and tool results as part of the conversation. LLaMA-3.1+ uses a <|python_tag|> or special JSON format within the assistant turn. Mistral uses a [TOOL_CALLS] marker. Models trained on tool-use data expect the exact format used during training — passing tools to tokenizer.apply_chat_template() formats them correctly. The tool definition is typically injected into the system prompt as a JSON schema, and function call outputs are injected as tool-role messages.

```python
import json
from transformers import AutoTokenizer

def format_tool_conversation(tokenizer):
    # Format a tool-use conversation with function call and result
    tools = [{
        'type': 'function',
        'function': {
            'name': 'get_weather',
            'description': 'Get current weather for a city',
            'parameters': {
                'type': 'object',
                'properties': {'location': {'type': 'string', 'description': 'City name'}},
                'required': ['location'],
            },
        },
    }]
    messages = [
        {'role': 'system', 'content': 'You are a helpful assistant with tool access.'},
        {'role': 'user', 'content': 'What is the weather in Tokyo?'},
        {'role': 'assistant', 'content': None,
         'tool_calls': [{'id': 'call_001', 'type': 'function',
                         'function': {'name': 'get_weather', 'arguments': '{"location": "Tokyo"}'}}]},
        {'role': 'tool', 'tool_call_id': 'call_001',
         'content': '{"temperature": 22, "condition": "sunny", "humidity": 60}'},
        {'role': 'assistant', 'content': 'It is currently 22 degrees Celsius and sunny in Tokyo.'},
    ]
    try:
        formatted = tokenizer.apply_chat_template(messages, tools=tools, tokenize=False)
        print(f'Tool conversation formatted: {len(formatted)} chars')
        print(repr(formatted[:400]))
    except Exception as e:
        print(f'Tool formatting error: {e}')
        print('Tool calling requires model-specific template with tool support')
    return json.dumps(messages, indent=2)

print('Tool format: function defs in system, calls in assistant, results in tool role')
print('Training requires exact same format as inference for reliable tool invocation')
```

## Chat Templates Across Model Families

| Model Family | System Role | Turn Delimiter | EOS Token | Tool Support | Format Name |
| --- | --- | --- | --- | --- | --- |
| LLaMA-3 | Yes (<|start_header_id|>system<|end_header_id|>) | <|eot_id|> | <|eot_id|> | Yes (v3.1+) | LLaMA-3 format |
| Mistral / Mixtral | No (injected into first user turn) | [INST] / [/INST] | </s> | Yes ([TOOL_CALLS]) | Mistral Instruct |
| ChatML (Qwen, many fine-tunes) | Yes (<|im_start|>system) | <|im_end|> | <|im_end|> | Varies by fine-tune | ChatML |
| Phi-3 | Yes (<|system|>) | <|end|> | <|end|> | Phi-3.5+ only | Phi-3 format |
| Gemma | No system role (ignored) | <end_of_turn> | <eos> | Gemma 2+ with tool tag | Gemma format |

## Common Pitfalls and Best Practices

The most common pitfall is using the base model tokenizer template at inference for a fine-tuned model that was trained on a different template — or conversely, using the fine-tuned template for a base model that was not trained on it. Another frequent mistake is applying the template manually with string formatting instead of tokenizer.apply_chat_template(), which can produce subtle differences (missing newlines, wrong special token IDs) that degrade quality. Always verify the template produces the expected token IDs by comparing with the reference template output before training or deployment.

- Always use tokenizer.apply_chat_template() — never format conversations manually with string concatenation.
- Check tokenizer.chat_template is not None before inference — a missing template is a silent failure mode.
- Verify special tokens (im_start, eot_id, etc.) are in the tokenizer vocabulary — missing special tokens are mapped to UNK and break the format.
- Use add_generation_prompt=True at inference and add_generation_prompt=False at training to avoid training on the generation prefix.
- For multi-turn SFT datasets, verify the supervision ratio (assistant tokens / total tokens) — below 20% often indicates a masking bug.

> **Template Mismatch Silently Degrades Quality**: Applying the wrong chat template at inference time causes the model to fail to follow instructions — even a minor difference (missing newline, wrong separator) breaks the expected format the model was trained on and produces generic or repeated text. Always match the inference template exactly to the training template, including whitespace details.

---

