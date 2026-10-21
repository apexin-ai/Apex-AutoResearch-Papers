# code rsft train config

**Evidence at What Cost? Decoupling and Scaling in LLM-Based Document Relation Extraction** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 94
- **Recorded user turns:** 0
- **Tool calls:** 34
- **Original source:** `logs/workers/worker_code_rsft-train-config_20260515T022446.log`
- **Structured JSON:** [`bcf0705ddd7baa707374.json`](../../sessions/bc/bcf0705ddd7baa707374.json)

## Before a recorded user message

94 recorded events

### Log line

_source line 1_

Warning: no stdin data received in 3s, proceeding without it. If piping from a slow command, redirect stdin explicitly: < /dev/null to skip, or wait longer.

---

### System

_source line 2_

```json
{
  "type": "system",
  "subtype": "init",
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "tools": [
    "Task",
    "AskUserQuestion",
    "Bash",
    "CronCreate",
    "CronDelete",
    "CronList",
    "Edit",
    "EnterPlanMode",
    "EnterWorktree",
    "ExitPlanMode",
    "ExitWorktree",
    "Glob",
    "Grep",
    "ListMcpResourcesTool",
    "Monitor",
    "NotebookEdit",
    "PushNotification",
    "Read",
    "ReadMcpResourceTool",
    "RemoteTrigger",
    "ScheduleWakeup",
    "Skill",
    "TaskOutput",
    "TaskStop",
    "TodoWrite",
    "ToolSearch",
    "WebFetch",
    "WebSearch",
    "Write",
    "mcp__agent-ml-research__detect_image",
    "mcp__agent-ml-research__kill_job",
    "mcp__agent-ml-research__ssh_execute",
    "mcp__agent-ml-research__ssh_read_only"
  ],
  "mcp_servers": [
    {
      "name": "agent-ml-research",
      "status": "connected"
    }
  ],
  "model": "claude-opus-4-6",
  "permissionMode": "bypassPermissions",
  "slash_commands": [
    "update-config",
    "debug",
    "simplify",
    "batch",
    "fewer-permission-prompts",
    "loop",
    "schedule",
    "claude-api",
    "clear",
    "compact",
    "context",
    "heapdump",
    "init",
    "review",
    "security-review",
    "extra-usage",
    "usage",
    "insights",
    "team-onboarding"
  ],
  "apiKeySource": "none",
  "claude_code_version": "2.1.126",
  "output_style": "default",
  "agents": [
    "claude",
    "Explore",
    "general-purpose",
    "Plan",
    "statusline-setup"
  ],
  "skills": [
    "update-config",
    "debug",
    "simplify",
    "batch",
    "fewer-permission-prompts",
    "loop",
    "schedule",
    "claude-api"
  ],
  "plugins": [],
  "analytics_disabled": false,
  "uuid": "21eda756-1096-4cb3-9e4f-8b5f99b86491",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/memory/"
  },
  "fast_mode_state": "off"
}
```

---

### Assistant

_source line 3_

<details><summary>Logged reasoning block</summary>

```text
Let me start by reading the relevant files on the server to understand the current state of rsft_trainer.py and sft_trainer.py.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "4a5b9676-41af-4c13-a2cc-a9ab6590030f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01R6kgqiE2wsWZiGZCJUfvXC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12220,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12220
      },
      "output_tokens": 39,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Runtime record

_source line 4_

```json
{
  "type": "rate_limit_event",
  "rate_limit_info": {
    "status": "allowed",
    "resetsAt": 1778824200,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "62da9bcb-ddfb-4614-9fc9-d469e5fb0b79",
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73"
}
```

---

### Assistant

_source line 5_

先读取服务器上的训练代码和 SFT 配置。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "f167cb75-3a76-4084-bfea-864cb838a04a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01R6kgqiE2wsWZiGZCJUfvXC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12220,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12220
      },
      "output_tokens": 39,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 6_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01LM3QXncqDpnEEqqrVMzmnY`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__detect_image",
  "max_results": 3
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "0770a33d-8f02-4cad-9b98-7025151636c5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01R6kgqiE2wsWZiGZCJUfvXC",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12220,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12220
      },
      "output_tokens": 39,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 7 · 2026-05-15T02:24:58.485Z_

<details><summary>↩ Tool result · `toolu_01LM3QXncqDpnEEqqrVMzmnY`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__ssh_read_only"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__ssh_execute"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__detect_image"
}
```
````

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "38a16b38-4f33-4a8a-b087-5a79be0be554",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__ssh_read_only",
      "mcp__agent-ml-research__ssh_execute",
      "mcp__agent-ml-research__detect_image"
    ],
    "query": "select:mcp__agent-ml-research__ssh_read_only,mcp__agent-ml-research__ssh_execute,mcp__agent-ml-research__detect_image",
    "total_deferred_tools": 23
  }
}
```

</details>

---

### Tool call

_source line 8_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01PxMi8xkjSGU6gg3kgHTb2k`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "cat /root/autodl-tmp/freige/training/rsft_trainer.py",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "6ec28445-8b5b-4251-aba5-5f9c9148b383",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DnZW8nNWSp7EJFj5bVX2z9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 939,
      "cache_read_input_tokens": 24061,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 939
      },
      "output_tokens": 73,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 9_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01CsNpr2pyWFHyTdTyXcFnKK`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "cat /root/autodl-tmp/freige/training/sft_trainer.py",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "e5d0e761-b4af-4989-8759-ce6da94a3ec9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DnZW8nNWSp7EJFj5bVX2z9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 939,
      "cache_read_input_tokens": 24061,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 939
      },
      "output_tokens": 73,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 10 · 2026-05-15T02:25:02.804Z_

<details><summary>↩ Tool result · `toolu_01PxMi8xkjSGU6gg3kgHTb2k`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\\n\\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\\n\\n输入: JSONL，每行 {\\\"doc_id\\\": ..., \\\"input\\\": ..., \\\"output\\\": ..., \\\"ced_score\\\": ..., ...}\\n输出: QLoRA adapter checkpoint\\n依赖: transformers, trl, peft, bitsandbytes, datasets\\n\\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\\\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport os\\n\\nimport torch\\nfrom datasets import Dataset\\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\\nfrom torch.utils.data import WeightedRandomSampler\\nfrom transformers import (\\n    AutoModelForCausalLM,\\n    AutoTokenizer,\\n    BitsAndBytesConfig,\\n)\\nfrom trl import SFTConfig, SFTTrainer\\n\\nfrom freige.training.sft_trainer import SYSTEM_PROMPT\\n\\nlogging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s %(levelname)s %(message)s\\\")\\nlogger = logging.getLogger(__name__)\\n\\nDEFAULT_BASE_MODEL = \\\"/root/autodl-tmp/models/Qwen3-4B\\\"\\nDEFAULT_SFT_ADAPTER = \\\"/root/autodl-tmp/sft_output\\\"\\n\\n\\ndef load_rsft_data(data_path: str, tokenizer, max_length: int = 2048):\\n    \\\"\\\"\\\"加载 CED 筛选后的 RSFT 数据，格式化为 chat template 文本。\\n\\n    每行 JSONL 的 input 字段作为 user message，output 字段作为 assistant response，\\n    经 apply_chat_template 拼接后用于 SFT 训练。超过 max_length 的样本被跳过\\n    而非截断，避免训练在不完整 JSON 输出上。\\n\\n    Returns:\\n        (Dataset, list[float]): 训练数据集和对应的 CED scores\\n    \\\"\\\"\\\"\\n    samples = []\\n    with open(data_path) as f:\\n        for line in f:\\n            if line.strip():\\n                samples.append(json.loads(line))\\n\\n    logger.info(\\\"Loaded %d RSFT samples from %s\\\", len(samples), data_path)\\n\\n    formatted = []\\n    ced_scores = []\\n    skipped = 0\\n    for s in samples:\\n        messages = [\\n            {\\\"role\\\": \\\"system\\\", \\\"content\\\": SYSTEM_PROMPT},\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": s[\\\"input\\\"]},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": s[\\\"output\\\"]},\\n        ]\\n        text = tokenizer.apply_chat_template(\\n            messages,\\n            tokenize=False,\\n            add_generation_prompt=False,\\n            enable_thinking=False,\\n        )\\n        token_len = len(tokenizer.encode(text, add_special_tokens=False))\\n        if token_len > max_length:\\n            skipped += 1\\n            continue\\n        formatted.append({\\\"text\\\": text})\\n        ced_scores.append(s.get(\\\"ced_score\\\", 1.0))\\n\\n    if skipped:\\n        logger.warning(\\\"Skipped %d samples exceeding max_length=%d\\\", skipped, max_length)\\n\\n    if ced_scores:\\n        logger.info(\\n            \\\"Prepared %d RSFT samples (CED scores: min=%.3f, max=%.3f, mean=%.3f)\\\",\\n            len(formatted), min(ced_scores), max(ced_scores),\\n            sum(ced_scores) / len(ced_scores),\\n        )\\n    return Dataset.from_list(formatted), ced_scores\\n\\n\\nclass WeightedSFTTrainer(SFTTrainer):\\n    \\\"\\\"\\\"SFTTrainer with CED score-weighted sampling.\\n\\n    高 CED score 的样本被更频繁采样。使用 WeightedRandomSampler 实现，\\n    适用于单机训练。多机 DDP 场景下 Accelerate 会替换 sampler，\\n    此时 weighted_sampling 不生效，需改用数据集层面的过采样。\\n    \\\"\\\"\\\"\\n\\n    def __init__(self, *args, sample_weights=None, **kwargs):\\n        super().__init__(*args, **kwargs)\\n        self.sample_weights = sample_weights\\n\\n    def _get_train_sampler(self, dataset=None):\\n        if self.sample_weights is not None:\\n            ds = dataset if dataset is not None else self.train_dataset\\n            return WeightedRandomSampler(\\n                weights=self.sample_weights,\\n                num_samples=len(ds),\\n                replacement=True,\\n            )\\n        return super()._get_train_sampler(dataset)\\n\\n\\ndef main():\\n    parser = argparse.ArgumentParser(description=\\\"FREIGE RSFT Training\\\")\\n    parser.add_argument(\\\"--base_model\\\", type=str, default=DEFAULT_BASE_MODEL)\\n    parser.add_argument(\\\"--sft_adapter\\\", type=str, default=DEFAULT_SFT_ADAPTER,\\n                        help=\\\"SFT warmup a\\n\\n... [截断: 输出过长，省略 1274 字符] ...\\n\\ngument(\\\"--lora_alpha\\\", type=int, default=128)\\n    parser.add_argument(\\\"--lora_dropout\\\", type=float, default=0.05)\\n    parser.add_argument(\\\"--bf16\\\", action=\\\"store_true\\\", default=True)\\n    parser.add_argument(\\\"--deepspeed\\\", type=str, default=None,\\n                        help=\\\"DeepSpeed 配置文件路径\\\")\\n    args = parser.parse_args()\\n\\n    # W&B\\n    if args.wandb_project and \\\"WANDB_API_KEY\\\" in os.environ:\\n        os.environ[\\\"WANDB_PROJECT\\\"] = args.wandb_project\\n        if args.wandb_run_name:\\n            os.environ[\\\"WANDB_NAME\\\"] = args.wandb_run_name\\n\\n    # Tokenizer\\n    logger.info(\\\"Loading tokenizer: %s\\\", args.base_model)\\n    tokenizer = AutoTokenizer.from_pretrained(\\n        args.base_model, trust_remote_code=True, padding_side=\\\"right\\\",\\n    )\\n    if tokenizer.pad_token is None:\\n        tokenizer.pad_token = tokenizer.eos_token\\n\\n    # Data\\n    logger.info(\\\"Loading RSFT data: %s\\\", args.rsft_data_path)\\n    train_dataset, ced_scores = load_rsft_data(\\n        args.rsft_data_path, tokenizer, args.max_length,\\n    )\\n\\n    # Model: base → merge SFT adapter → new LoRA\\n    logger.info(\\\"Loading base model: %s\\\", args.base_model)\\n    local_rank = int(os.environ.get(\\\"LOCAL_RANK\\\", 0))\\n    model_kwargs = dict(\\n        trust_remote_code=True,\\n        attn_implementation=\\\"sdpa\\\",\\n        device_map={\\\"\\\": local_rank},\\n    )\\n    if args.quantize:\\n        logger.info(\\\"Using 4-bit QLoRA quantization\\\")\\n        model_kwargs[\\\"quantization_config\\\"] = BitsAndBytesConfig(\\n            load_in_4bit=True,\\n            bnb_4bit_compute_dtype=torch.bfloat16,\\n            bnb_4bit_quant_type=\\\"nf4\\\",\\n            bnb_4bit_use_double_quant=True,\\n        )\\n    else:\\n        model_kwargs[\\\"torch_dtype\\\"] = torch.bfloat16 if args.bf16 else torch.float16\\n\\n    model = AutoModelForCausalLM.from_pretrained(args.base_model, **model_kwargs)\\n\\n    if args.sft_adapter:\\n        logger.info(\\\"Merging SFT adapter: %s\\\", args.sft_adapter)\\n        model = PeftModel.from_pretrained(model, args.sft_adapter)\\n        model = model.merge_and_unload()\\n\\n    model.config.use_cache = False\\n    model.gradient_checkpointing_enable()\\n\\n    # Fresh LoRA for RSFT (与 SFT warmup 相同结构)\\n    lora_config = LoraConfig(\\n        task_type=TaskType.CAUSAL_LM,\\n        r=args.lora_rank,\\n        lora_alpha=args.lora_alpha,\\n        lora_dropout=args.lora_dropout,\\n        target_modules=[\\\"q_proj\\\", \\\"k_proj\\\", \\\"v_proj\\\", \\\"o_proj\\\",\\n                         \\\"gate_proj\\\", \\\"up_proj\\\", \\\"down_proj\\\"],\\n    )\\n    model = get_peft_model(model, lora_config)\\n    model.print_trainable_parameters()\\n\\n    # Training config\\n    training_args = SFTConfig(\\n        output_dir=args.output_dir,\\n        num_train_epochs=args.num_epochs,\\n        per_device_train_batch_size=args.per_device_batch_size,\\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\\n        learning_rate=args.learning_rate,\\n        warmup_steps=args.warmup_steps,\\n        bf16=args.bf16,\\n        logging_steps=10,\\n        save_strategy=\\\"steps\\\",\\n        save_steps=args.save_steps,\\n        save_total_limit=args.save_total_limit,\\n        seed=args.seed,\\n        max_length=args.max_length,\\n        dataset_text_field=\\\"text\\\",\\n        report_to=\\\"wandb\\\" if \\\"WANDB_API_KEY\\\" in os.environ else \\\"none\\\",\\n        gradient_checkpointing=True,\\n        gradient_checkpointing_kwargs={\\\"use_reentrant\\\": False},\\n        deepspeed=args.deepspeed,\\n    )\\n\\n    sample_weights = ced_scores if args.weighted_sampling else None\\n\\n    trainer = WeightedSFTTrainer(\\n        model=model,\\n        args=training_args,\\n        train_dataset=train_dataset,\\n        processing_class=tokenizer,\\n        sample_weights=sample_weights,\\n    )\\n\\n    logger.info(\\n        \\\"Starting RSFT training (%d samples, weighted=%s)...\\\",\\n        len(train_dataset), args.weighted_sampling,\\n    )\\n    trainer.train()\\n\\n    logger.info(\\\"Saving model to %s\\\", args.output_dir)\\n    trainer.save_model(args.output_dir)\\n    tokenizer.save_pretrained(args.output_dir)\\n    logger.info(\\\"RSFT training complete.\\\")\\n\\n\\nif __name__ == \\\"__main__\\\":\\n    main()\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.85}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "74e4a6b1-62c2-47b2-b2f0-f203b6452cf7",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\"\\\\\\\"\\\\\\\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\\\\n\\\\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\\\\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\\\\n\\\\n输入: JSONL，每行 {\\\\\\\"doc_id\\\\\\\": ..., \\\\\\\"input\\\\\\\": ..., \\\\\\\"output\\\\\\\": ..., \\\\\\\"ced_score\\\\\\\": ..., ...}\\\\n输出: QLoRA adapter checkpoint\\\\n依赖: transformers, trl, peft, bitsandbytes, datasets\\\\n\\\\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\\\\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\\\\\\\\\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\\\\n\\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\nimport argparse\\\\nimport json\\\\nimport logging\\\\nimport os\\\\n\\\\nimport torch\\\\nfrom datasets import Dataset\\\\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\\\\nfrom torch.utils.data import WeightedRandomSampler\\\\nfrom transformers import (\\\\n    AutoModelForCausalLM,\\\\n    AutoTokenizer,\\\\n    BitsAndBytesConfig,\\\\n)\\\\nfrom trl import SFTConfig, SFTTrainer\\\\n\\\\nfrom freige.training.sft_trainer import SYSTEM_PROMPT\\\\n\\\\nlogging.basicConfig(level=logging.INFO, format=\\\\\\\"%(asctime)s %(levelname)s %(message)s\\\\\\\")\\\\nlogger = logging.getLogger(__name__)\\\\n\\\\nDEFAULT_BASE_MODEL = \\\\\\\"/root/autodl-tmp/models/Qwen3-4B\\\\\\\"\\\\nDEFAULT_SFT_ADAPTER = \\\\\\\"/root/autodl-tmp/sft_output\\\\\\\"\\\\n\\\\n\\\\ndef load_rsft_data(data_path: str, tokenizer, max_length: int = 2048):\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"加载 CED 筛选后的 RSFT 数据，格式化为 chat template 文本。\\\\n\\\\n    每行 JSONL 的 input 字段作为 user message，output 字段作为 assistant response，\\\\n    经 apply_chat_template 拼接后用于 SFT 训练。超过 max_length 的样本被跳过\\\\n    而非截断，避免训练在不完整 JSON 输出上。\\\\n\\\\n    Returns:\\\\n        (Dataset, list[float]): 训练数据集和对应的 CED scores\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"\\\\n    samples = []\\\\n    with open(data_path) as f:\\\\n        for line in f:\\\\n            if line.strip():\\\\n                samples.append(json.loads(line))\\\\n\\\\n    logger.info(\\\\\\\"Loaded %d RSFT samples from %s\\\\\\\", len(samples), data_path)\\\\n\\\\n    formatted = []\\\\n    ced_scores = []\\\\n    skipped = 0\\\\n    for s in samples:\\\\n        messages = [\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"system\\\\\\\", \\\\\\\"content\\\\\\\": SYSTEM_PROMPT},\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"user\\\\\\\", \\\\\\\"content\\\\\\\": s[\\\\\\\"input\\\\\\\"]},\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"assistant\\\\\\\", \\\\\\\"content\\\\\\\": s[\\\\\\\"output\\\\\\\"]},\\\\n        ]\\\\n        text = tokenizer.apply_chat_template(\\\\n            messages,\\\\n            tokenize=False,\\\\n            add_generation_prompt=False,\\\\n            enable_thinking=False,\\\\n        )\\\\n        token_len = len(tokenizer.encode(text, add_special_tokens=False))\\\\n        if token_len > max_length:\\\\n            skipped += 1\\\\n            continue\\\\n        formatted.append({\\\\\\\"text\\\\\\\": text})\\\\n        ced_scores.append(s.get(\\\\\\\"ced_score\\\\\\\", 1.0))\\\\n\\\\n    if skipped:\\\\n        logger.warning(\\\\\\\"Skipped %d samples exceeding max_length=%d\\\\\\\", skipped, max_length)\\\\n\\\\n    if ced_scores:\\\\n        logger.info(\\\\n            \\\\\\\"Prepared %d RSFT samples (CED scores: min=%.3f, max=%.3f, mean=%.3f)\\\\\\\",\\\\n            len(formatted), min(ced_scores), max(ced_scores),\\\\n            sum(ced_scores) / len(ced_scores),\\\\n        )\\\\n    return Dataset.from_list(formatted), ced_scores\\\\n\\\\n\\\\nclass WeightedSFTTrainer(SFTTrainer):\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"SFTTrainer with CED score-weighted sampling.\\\\n\\\\n    高 CED score 的样本被更频繁采样。使用 WeightedRandomSampler 实现，\\\\n    适用于单机训练。多机 DDP 场景下 Accelerate 会替换 sampler，\\\\n    此时 weighted_sampling 不生效，需改用数据集层面的过采样。\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\n    def __init__(self, *args, sample_weights=None, **kwargs):\\\\n        super().__init__(*args, **kwargs)\\\\n        self.sample_weights = sample_weights\\\\n\\\\n    def _get_train_sampler(self, dataset=None):\\\\n        if self.sample_weights is not None:\\\\n            ds = dataset if dataset is not None else self.train_dataset\\\\n            return WeightedRandomSampler(\\\\n                weights=self.sample_weights,\\\\n                num_samples=len(ds),\\\\n                replacement=True,\\\\n            )\\\\n        return super()._get_train_sampler(dataset)\\\\n\\\\n\\\\ndef main():\\\\n    parser = argparse.ArgumentParser(description=\\\\\\\"FREIGE RSFT Training\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--base_model\\\\\\\", type=str, default=DEFAULT_BASE_MODEL)\\\\n    parser.add_argument(\\\\\\\"--sft_adapter\\\\\\\", type=str, default=DEFAULT_SFT_ADAPTER,\\\\n                        help=\\\\\\\"SFT warmup a\\\\n\\\\n... [截断: 输出过长，省略 1274 字符] ...\\\\n\\\\ngument(\\\\\\\"--lora_alpha\\\\\\\", type=int, default=128)\\\\n    parser.add_argument(\\\\\\\"--lora_dropout\\\\\\\", type=float, default=0.05)\\\\n    parser.add_argument(\\\\\\\"--bf16\\\\\\\", action=\\\\\\\"store_true\\\\\\\", default=True)\\\\n    parser.add_argument(\\\\\\\"--deepspeed\\\\\\\", type=str, default=None,\\\\n                        help=\\\\\\\"DeepSpeed 配置文件路径\\\\\\\")\\\\n    args = parser.parse_args()\\\\n\\\\n    # W&B\\\\n    if args.wandb_project and \\\\\\\"WANDB_API_KEY\\\\\\\" in os.environ:\\\\n        os.environ[\\\\\\\"WANDB_PROJECT\\\\\\\"] = args.wandb_project\\\\n        if args.wandb_run_name:\\\\n            os.environ[\\\\\\\"WANDB_NAME\\\\\\\"] = args.wandb_run_name\\\\n\\\\n    # Tokenizer\\\\n    logger.info(\\\\\\\"Loading tokenizer: %s\\\\\\\", args.base_model)\\\\n    tokenizer = AutoTokenizer.from_pretrained(\\\\n        args.base_model, trust_remote_code=True, padding_side=\\\\\\\"right\\\\\\\",\\\\n    )\\\\n    if tokenizer.pad_token is None:\\\\n        tokenizer.pad_token = tokenizer.eos_token\\\\n\\\\n    # Data\\\\n    logger.info(\\\\\\\"Loading RSFT data: %s\\\\\\\", args.rsft_data_path)\\\\n    train_dataset, ced_scores = load_rsft_data(\\\\n        args.rsft_data_path, tokenizer, args.max_length,\\\\n    )\\\\n\\\\n    # Model: base → merge SFT adapter → new LoRA\\\\n    logger.info(\\\\\\\"Loading base model: %s\\\\\\\", args.base_model)\\\\n    local_rank = int(os.environ.get(\\\\\\\"LOCAL_RANK\\\\\\\", 0))\\\\n    model_kwargs = dict(\\\\n        trust_remote_code=True,\\\\n        attn_implementation=\\\\\\\"sdpa\\\\\\\",\\\\n        device_map={\\\\\\\"\\\\\\\": local_rank},\\\\n    )\\\\n    if args.quantize:\\\\n        logger.info(\\\\\\\"Using 4-bit QLoRA quantization\\\\\\\")\\\\n        model_kwargs[\\\\\\\"quantization_config\\\\\\\"] = BitsAndBytesConfig(\\\\n            load_in_4bit=True,\\\\n            bnb_4bit_compute_dtype=torch.bfloat16,\\\\n            bnb_4bit_quant_type=\\\\\\\"nf4\\\\\\\",\\\\n            bnb_4bit_use_double_quant=True,\\\\n        )\\\\n    else:\\\\n        model_kwargs[\\\\\\\"torch_dtype\\\\\\\"] = torch.bfloat16 if args.bf16 else torch.float16\\\\n\\\\n    model = AutoModelForCausalLM.from_pretrained(args.base_model, **model_kwargs)\\\\n\\\\n    if args.sft_adapter:\\\\n        logger.info(\\\\\\\"Merging SFT adapter: %s\\\\\\\", args.sft_adapter)\\\\n        model = PeftModel.from_pretrained(model, args.sft_adapter)\\\\n        model = model.merge_and_unload()\\\\n\\\\n    model.config.use_cache = False\\\\n    model.gradient_checkpointing_enable()\\\\n\\\\n    # Fresh LoRA for RSFT (与 SFT warmup 相同结构)\\\\n    lora_config = LoraConfig(\\\\n        task_type=TaskType.CAUSAL_LM,\\\\n        r=args.lora_rank,\\\\n        lora_alpha=args.lora_alpha,\\\\n        lora_dropout=args.lora_dropout,\\\\n        target_modules=[\\\\\\\"q_proj\\\\\\\", \\\\\\\"k_proj\\\\\\\", \\\\\\\"v_proj\\\\\\\", \\\\\\\"o_proj\\\\\\\",\\\\n                         \\\\\\\"gate_proj\\\\\\\", \\\\\\\"up_proj\\\\\\\", \\\\\\\"down_proj\\\\\\\"],\\\\n    )\\\\n    model = get_peft_model(model, lora_config)\\\\n    model.print_trainable_parameters()\\\\n\\\\n    # Training config\\\\n    training_args = SFTConfig(\\\\n        output_dir=args.output_dir,\\\\n        num_train_epochs=args.num_epochs,\\\\n        per_device_train_batch_size=args.per_device_batch_size,\\\\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\\\\n        learning_rate=args.learning_rate,\\\\n        warmup_steps=args.warmup_steps,\\\\n        bf16=args.bf16,\\\\n        logging_steps=10,\\\\n        save_strategy=\\\\\\\"steps\\\\\\\",\\\\n        save_steps=args.save_steps,\\\\n        save_total_limit=args.save_total_limit,\\\\n        seed=args.seed,\\\\n        max_length=args.max_length,\\\\n        dataset_text_field=\\\\\\\"text\\\\\\\",\\\\n        report_to=\\\\\\\"wandb\\\\\\\" if \\\\\\\"WANDB_API_KEY\\\\\\\" in os.environ else \\\\\\\"none\\\\\\\",\\\\n        gradient_checkpointing=True,\\\\n        gradient_checkpointing_kwargs={\\\\\\\"use_reentrant\\\\\\\": False},\\\\n        deepspeed=args.deepspeed,\\\\n    )\\\\n\\\\n    sample_weights = ced_scores if args.weighted_sampling else None\\\\n\\\\n    trainer = WeightedSFTTrainer(\\\\n        model=model,\\\\n        args=training_args,\\\\n        train_dataset=train_dataset,\\\\n        processing_class=tokenizer,\\\\n        sample_weights=sample_weights,\\\\n    )\\\\n\\\\n    logger.info(\\\\n        \\\\\\\"Starting RSFT training (%d samples, weighted=%s)...\\\\\\\",\\\\n        len(train_dataset), args.weighted_sampling,\\\\n    )\\\\n    trainer.train()\\\\n\\\\n    logger.info(\\\\\\\"Saving model to %s\\\\\\\", args.output_dir)\\\\n    trainer.save_model(args.output_dir)\\\\n    tokenizer.save_pretrained(args.output_dir)\\\\n    logger.info(\\\\\\\"RSFT training complete.\\\\\\\")\\\\n\\\\n\\\\nif __name__ == \\\\\\\"__main__\\\\\\\":\\\\n    main()\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.85}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\\n\\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\\n\\n输入: JSONL，每行 {\\\"doc_id\\\": ..., \\\"input\\\": ..., \\\"output\\\": ..., \\\"ced_score\\\": ..., ...}\\n输出: QLoRA adapter checkpoint\\n依赖: transformers, trl, peft, bitsandbytes, datasets\\n\\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\\\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport os\\n\\nimport torch\\nfrom datasets import Dataset\\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\\nfrom torch.utils.data import WeightedRandomSampler\\nfrom transformers import (\\n    AutoModelForCausalLM,\\n    AutoTokenizer,\\n    BitsAndBytesConfig,\\n)\\nfrom trl import SFTConfig, SFTTrainer\\n\\nfrom freige.training.sft_trainer import SYSTEM_PROMPT\\n\\nlogging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s %(levelname)s %(message)s\\\")\\nlogger = logging.getLogger(__name__)\\n\\nDEFAULT_BASE_MODEL = \\\"/root/autodl-tmp/models/Qwen3-4B\\\"\\nDEFAULT_SFT_ADAPTER = \\\"/root/autodl-tmp/sft_output\\\"\\n\\n\\ndef load_rsft_data(data_path: str, tokenizer, max_length: int = 2048):\\n    \\\"\\\"\\\"加载 CED 筛选后的 RSFT 数据，格式化为 chat template 文本。\\n\\n    每行 JSONL 的 input 字段作为 user message，output 字段作为 assistant response，\\n    经 apply_chat_template 拼接后用于 SFT 训练。超过 max_length 的样本被跳过\\n    而非截断，避免训练在不完整 JSON 输出上。\\n\\n    Returns:\\n        (Dataset, list[float]): 训练数据集和对应的 CED scores\\n    \\\"\\\"\\\"\\n    samples = []\\n    with open(data_path) as f:\\n        for line in f:\\n            if line.strip():\\n                samples.append(json.loads(line))\\n\\n    logger.info(\\\"Loaded %d RSFT samples from %s\\\", len(samples), data_path)\\n\\n    formatted = []\\n    ced_scores = []\\n    skipped = 0\\n    for s in samples:\\n        messages = [\\n            {\\\"role\\\": \\\"system\\\", \\\"content\\\": SYSTEM_PROMPT},\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": s[\\\"input\\\"]},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": s[\\\"output\\\"]},\\n        ]\\n        text = tokenizer.apply_chat_template(\\n            messages,\\n            tokenize=False,\\n            add_generation_prompt=False,\\n            enable_thinking=False,\\n        )\\n        token_len = len(tokenizer.encode(text, add_special_tokens=False))\\n        if token_len > max_length:\\n            skipped += 1\\n            continue\\n        formatted.append({\\\"text\\\": text})\\n        ced_scores.append(s.get(\\\"ced_score\\\", 1.0))\\n\\n    if skipped:\\n        logger.warning(\\\"Skipped %d samples exceeding max_length=%d\\\", skipped, max_length)\\n\\n    if ced_scores:\\n        logger.info(\\n            \\\"Prepared %d RSFT samples (CED scores: min=%.3f, max=%.3f, mean=%.3f)\\\",\\n            len(formatted), min(ced_scores), max(ced_scores),\\n            sum(ced_scores) / len(ced_scores),\\n        )\\n    return Dataset.from_list(formatted), ced_scores\\n\\n\\nclass WeightedSFTTrainer(SFTTrainer):\\n    \\\"\\\"\\\"SFTTrainer with CED score-weighted sampling.\\n\\n    高 CED score 的样本被更频繁采样。使用 WeightedRandomSampler 实现，\\n    适用于单机训练。多机 DDP 场景下 Accelerate 会替换 sampler，\\n    此时 weighted_sampling 不生效，需改用数据集层面的过采样。\\n    \\\"\\\"\\\"\\n\\n    def __init__(self, *args, sample_weights=None, **kwargs):\\n        super().__init__(*args, **kwargs)\\n        self.sample_weights = sample_weights\\n\\n    def _get_train_sampler(self, dataset=None):\\n        if self.sample_weights is not None:\\n            ds = dataset if dataset is not None else self.train_dataset\\n            return WeightedRandomSampler(\\n                weights=self.sample_weights,\\n                num_samples=len(ds),\\n                replacement=True,\\n            )\\n        return super()._get_train_sampler(dataset)\\n\\n\\ndef main():\\n    parser = argparse.ArgumentParser(description=\\\"FREIGE RSFT Training\\\")\\n    parser.add_argument(\\\"--base_model\\\", type=str, default=DEFAULT_BASE_MODEL)\\n    parser.add_argument(\\\"--sft_adapter\\\", type=str, default=DEFAULT_SFT_ADAPTER,\\n                        help=\\\"SFT warmup a\\n\\n... [截断: 输出过长，省略 1274 字符] ...\\n\\ngument(\\\"--lora_alpha\\\", type=int, default=128)\\n    parser.add_argument(\\\"--lora_dropout\\\", type=float, default=0.05)\\n    parser.add_argument(\\\"--bf16\\\", action=\\\"store_true\\\", default=True)\\n    parser.add_argument(\\\"--deepspeed\\\", type=str, default=None,\\n                        help=\\\"DeepSpeed 配置文件路径\\\")\\n    args = parser.parse_args()\\n\\n    # W&B\\n    if args.wandb_project and \\\"WANDB_API_KEY\\\" in os.environ:\\n        os.environ[\\\"WANDB_PROJECT\\\"] = args.wandb_project\\n        if args.wandb_run_name:\\n            os.environ[\\\"WANDB_NAME\\\"] = args.wandb_run_name\\n\\n    # Tokenizer\\n    logger.info(\\\"Loading tokenizer: %s\\\", args.base_model)\\n    tokenizer = AutoTokenizer.from_pretrained(\\n        args.base_model, trust_remote_code=True, padding_side=\\\"right\\\",\\n    )\\n    if tokenizer.pad_token is None:\\n        tokenizer.pad_token = tokenizer.eos_token\\n\\n    # Data\\n    logger.info(\\\"Loading RSFT data: %s\\\", args.rsft_data_path)\\n    train_dataset, ced_scores = load_rsft_data(\\n        args.rsft_data_path, tokenizer, args.max_length,\\n    )\\n\\n    # Model: base → merge SFT adapter → new LoRA\\n    logger.info(\\\"Loading base model: %s\\\", args.base_model)\\n    local_rank = int(os.environ.get(\\\"LOCAL_RANK\\\", 0))\\n    model_kwargs = dict(\\n        trust_remote_code=True,\\n        attn_implementation=\\\"sdpa\\\",\\n        device_map={\\\"\\\": local_rank},\\n    )\\n    if args.quantize:\\n        logger.info(\\\"Using 4-bit QLoRA quantization\\\")\\n        model_kwargs[\\\"quantization_config\\\"] = BitsAndBytesConfig(\\n            load_in_4bit=True,\\n            bnb_4bit_compute_dtype=torch.bfloat16,\\n            bnb_4bit_quant_type=\\\"nf4\\\",\\n            bnb_4bit_use_double_quant=True,\\n        )\\n    else:\\n        model_kwargs[\\\"torch_dtype\\\"] = torch.bfloat16 if args.bf16 else torch.float16\\n\\n    model = AutoModelForCausalLM.from_pretrained(args.base_model, **model_kwargs)\\n\\n    if args.sft_adapter:\\n        logger.info(\\\"Merging SFT adapter: %s\\\", args.sft_adapter)\\n        model = PeftModel.from_pretrained(model, args.sft_adapter)\\n        model = model.merge_and_unload()\\n\\n    model.config.use_cache = False\\n    model.gradient_checkpointing_enable()\\n\\n    # Fresh LoRA for RSFT (与 SFT warmup 相同结构)\\n    lora_config = LoraConfig(\\n        task_type=TaskType.CAUSAL_LM,\\n        r=args.lora_rank,\\n        lora_alpha=args.lora_alpha,\\n        lora_dropout=args.lora_dropout,\\n        target_modules=[\\\"q_proj\\\", \\\"k_proj\\\", \\\"v_proj\\\", \\\"o_proj\\\",\\n                         \\\"gate_proj\\\", \\\"up_proj\\\", \\\"down_proj\\\"],\\n    )\\n    model = get_peft_model(model, lora_config)\\n    model.print_trainable_parameters()\\n\\n    # Training config\\n    training_args = SFTConfig(\\n        output_dir=args.output_dir,\\n        num_train_epochs=args.num_epochs,\\n        per_device_train_batch_size=args.per_device_batch_size,\\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\\n        learning_rate=args.learning_rate,\\n        warmup_steps=args.warmup_steps,\\n        bf16=args.bf16,\\n        logging_steps=10,\\n        save_strategy=\\\"steps\\\",\\n        save_steps=args.save_steps,\\n        save_total_limit=args.save_total_limit,\\n        seed=args.seed,\\n        max_length=args.max_length,\\n        dataset_text_field=\\\"text\\\",\\n        report_to=\\\"wandb\\\" if \\\"WANDB_API_KEY\\\" in os.environ else \\\"none\\\",\\n        gradient_checkpointing=True,\\n        gradient_checkpointing_kwargs={\\\"use_reentrant\\\": False},\\n        deepspeed=args.deepspeed,\\n    )\\n\\n    sample_weights = ced_scores if args.weighted_sampling else None\\n\\n    trainer = WeightedSFTTrainer(\\n        model=model,\\n        args=training_args,\\n        train_dataset=train_dataset,\\n        processing_class=tokenizer,\\n        sample_weights=sample_weights,\\n    )\\n\\n    logger.info(\\n        \\\"Starting RSFT training (%d samples, weighted=%s)...\\\",\\n        len(train_dataset), args.weighted_sampling,\\n    )\\n    trainer.train()\\n\\n    logger.info(\\\"Saving model to %s\\\", args.output_dir)\\n    trainer.save_model(args.output_dir)\\n    tokenizer.save_pretrained(args.output_dir)\\n    logger.info(\\\"RSFT training complete.\\\")\\n\\n\\nif __name__ == \\\"__main__\\\":\\n    main()\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.85}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 11_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_013JJ1ysj6VQzPnig2sLDZxB`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "ls -la /root/autodl-tmp/sft_output/",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "a965f080-2ba7-47b8-aeb6-7dae3209d2da",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01DnZW8nNWSp7EJFj5bVX2z9",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 939,
      "cache_read_input_tokens": 24061,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 939
      },
      "output_tokens": 73,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 12 · 2026-05-15T02:25:03.179Z_

<details><summary>↩ Tool result · `toolu_01CsNpr2pyWFHyTdTyXcFnKK`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"SFT 训练脚本: Qwen3-4B + QLoRA 在 DocRED 上微调。\\n\\n支持单卡和多卡（DeepSpeed ZeRO-2/3）训练。\\n默认启用 4-bit QLoRA 量化，适配 RTX 5090 32GB x4。\\n\\n单卡:   python -m freige.training.sft_trainer --output_dir ./sft_output\\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\\\\n            -m freige.training.sft_trainer --deepspeed configs/deepspeed_zero2.json\\n不量化: 加 --no_quantize\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport os\\nfrom dataclasses import dataclass, field\\nfrom pathlib import Path\\nfrom typing import Optional\\n\\nimport torch\\nfrom datasets import Dataset\\nfrom peft import LoraConfig, TaskType, get_peft_model\\nfrom transformers import (\\n    AutoModelForCausalLM,\\n    AutoTokenizer,\\n    BitsAndBytesConfig,\\n    TrainingArguments,\\n)\\nfrom trl import SFTTrainer, SFTConfig\\n\\nlogging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s %(levelname)s %(message)s\\\")\\nlogger = logging.getLogger(__name__)\\n\\nSYSTEM_PROMPT = (\\n    \\\"You are an information extraction model. Given a document with numbered sentences \\\"\\n    \\\"and a list of entities, extract all relation triples. For each triple, provide the \\\"\\n    \\\"head entity, relation type, tail entity, and the sentence IDs that serve as evidence. \\\"\\n    \\\"Output as a JSON list.\\\"\\n)\\n\\nDEFAULT_MODEL = \\\"/root/autodl-tmp/models/Qwen3-4B\\\"\\n\\n\\ndef build_chat_messages(instruction: str, input_text: str, output_text: str = None):\\n    \\\"\\\"\\\"构建 Qwen3 chat 格式的消息列表。\\\"\\\"\\\"\\n    messages = [\\n        {\\\"role\\\": \\\"system\\\", \\\"content\\\": SYSTEM_PROMPT},\\n        {\\\"role\\\": \\\"user\\\", \\\"content\\\": f\\\"{instruction}\\\\n\\\\n{input_text}\\\"},\\n    ]\\n    if output_text is not None:\\n        messages.append({\\\"role\\\": \\\"assistant\\\", \\\"content\\\": output_text})\\n    return messages\\n\\n\\ndef prepare_dataset(\\n    data_dir: str = None,\\n    split: str = \\\"train\\\",\\n    tokenizer=None,\\n    max_length: int = 4096,\\n) -> Dataset:\\n    \\\"\\\"\\\"加载并格式化 DocRED 数据为 SFT 训练格式。\\\"\\\"\\\"\\n    from freige.data.docred_processor import DocREDProcessor\\n\\n    processor = DocREDProcessor(data_dir=data_dir)\\n    samples = processor.process(split)\\n    groups = processor.group_by_document(samples)\\n\\n    formatted = []\\n    for doc_id, doc_samples in groups.items():\\n        sft_sample = processor.format_sft_sample(doc_samples)\\n        messages = build_chat_messages(\\n            sft_sample[\\\"instruction\\\"],\\n            sft_sample[\\\"input\\\"],\\n            sft_sample[\\\"output\\\"],\\n        )\\n        text = tokenizer.apply_chat_template(\\n            messages,\\n            tokenize=False,\\n            add_generation_prompt=False,\\n            enable_thinking=False,\\n        )\\n        formatted.append({\\\"text\\\": text})\\n\\n    logger.info(\\\"Prepared %d SFT samples from %d documents\\\", len(formatted), len(groups))\\n    return Dataset.from_list(formatted)\\n\\n\\ndef main():\\n    parser = argparse.ArgumentParser(description=\\\"FREIGE SFT Training\\\")\\n    parser.add_argument(\\\"--model_name\\\", type=str, default=DEFAULT_MODEL)\\n    parser.add_argument(\\\"--data_dir\\\", type=str, default=None,\\n                        help=\\\"DocRED JSON 目录\\\")\\n    parser.add_argument(\\\"--output_dir\\\", type=str, default=\\\"./sft_output\\\")\\n    parser.add_argument(\\\"--lora_rank\\\", type=int, default=64)\\n    parser.add_argument(\\\"--lora_alpha\\\", type=int, default=128)\\n    parser.add_argument(\\\"--lora_dropout\\\", type=float, default=0.05)\\n    parser.add_argument(\\\"--max_length\\\", type=int, default=4096)\\n    parser.add_argument(\\\"--quantize\\\", action=argparse.BooleanOptionalAction, default=True,\\n                        help=\\\"启用 4-bit QLoRA 量化（默认启用，--no_quantize 禁用）\\\")\\n    parser.add_argument(\\\"--deepspeed\\\", type=str, default=None,\\n                        help=\\\"DeepSpeed 配置文件路径\\\")\\n    parser.add_argument(\\\"--per_device_batch_size\\\", type=int, default=1)\\n    parser.add_argument(\\\"--gradient_accumulation_steps\\\", type=int, default=16)\\n    parser.add_argument(\\\"--num_epochs\\\", type=int, default=3)\\n    parser.add_argument(\\\"--learning_rate\\\", type=float, default=2e-4)\\n    parser.add_argument(\\\"--warmup_ratio\\\", type=float, default=0.05)\\n    parser.add_argument(\\\"--bf16\\\", action=\\\"store_true\\\", default=True)\\n    parser.add_argument(\\\"--seed\\\", type=int, default=42)\\n    parser.add_argument(\\\"--wandb_project\\\", type=str, default=\\\"freige-sft\\\")\\n    parser.add_argument(\\\"--wandb_run_name\\\", type=str, default=None)\\n    args = parser.parse_args()\\n\\n    if args.wandb_project and \\\"WANDB_API_KEY\\\" in os.environ:\\n        os.environ[\\\"WANDB_PROJECT\\\"] = args.wandb_project\\n        if args.wandb_run_name:\\n            os.environ[\\\"WANDB_NAME\\\"] = args.wandb_run_name\\n\\n    logger.info(\\\"Loading tokenizer: %s\\\", args.model_name)\\n    tokenizer = AutoTokenizer.from_pretrained(\\n        args.model_name,\\n        trust_remote_code=True,\\n        padding_side=\\\"right\\\",\\n    )\\n    if tokenizer.pad_token is None:\\n        tokenizer.pad_token = tokenizer.eos_token\\n\\n    logger.info(\\\"Preparing dataset...\\\")\\n    train_dataset = prepare_dataset(\\n        data_dir=args.data_dir,\\n        split=\\\"train\\\",\\n        tokenizer=tokenizer,\\n        max_length=args.max_length,\\n    )\\n    eval_dataset = prepare_dataset(\\n        data_dir=args.data_dir,\\n        split=\\\"dev\\\",\\n        tokenizer=tokenizer,\\n        max_length=args.max_length,\\n    )\\n\\n    logger.info(\\\"Loading model: %s\\\", args.model_name)\\n    local_rank = int(os.environ.get(\\\"LOCAL_RANK\\\", 0))\\n    model_kwargs = dict(\\n        trust_remote_code=True,\\n        attn_implementation=\\\"sdpa\\\",\\n        device_map={\\\"\\\": local_rank},\\n    )\\n    if args.quantize:\\n        logger.info(\\\"Using 4-bit QLoRA quantization\\\")\\n        model_kwargs[\\\"quantization_config\\\"] = BitsAndBytesConfig(\\n            load_in_4bit=True,\\n            bnb_4bit_compute_dtype=torch.bfloat16,\\n            bnb_4bit_quant_type=\\\"nf4\\\",\\n            bnb_4bit_use_double_quant=True,\\n        )\\n    else:\\n        model_kwargs[\\\"torch_dtype\\\"] = torch.bfloat16 if args.bf16 else torch.float16\\n    model = AutoModelForCausalLM.from_pretrained(args.model_name, **model_kwargs)\\n    model.config.use_cache = False\\n    model.gradient_checkpointing_enable()\\n\\n    lora_config = LoraConfig(\\n        task_type=TaskType.CAUSAL_LM,\\n        r=args.lora_rank,\\n        lora_alpha=args.lora_alpha,\\n        lora_dropout=args.lora_dropout,\\n        target_modules=[\\\"q_proj\\\", \\\"k_proj\\\", \\\"v_proj\\\", \\\"o_proj\\\",\\n                         \\\"gate_proj\\\", \\\"up_proj\\\", \\\"down_proj\\\"],\\n    )\\n    model = get_peft_model(model, lora_config)\\n    model.print_trainable_parameters()\\n\\n    training_args = SFTConfig(\\n        output_dir=args.output_dir,\\n        num_train_epochs=args.num_epochs,\\n        per_device_train_batch_size=args.per_device_batch_size,\\n        per_device_eval_batch_size=args.per_device_batch_size,\\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\\n        learning_rate=args.learning_rate,\\n        warmup_ratio=args.warmup_ratio,\\n        bf16=args.bf16,\\n        logging_steps=10,\\n        eval_strategy=\\\"epoch\\\",\\n        save_strategy=\\\"epoch\\\",\\n        save_total_limit=2,\\n        load_best_model_at_end=True,\\n        metric_for_best_model=\\\"eval_loss\\\",\\n        greater_is_better=False,\\n        seed=args.seed,\\n        max_length=args.max_length,\\n        dataset_text_field=\\\"text\\\",\\n        report_to=\\\"wandb\\\" if \\\"WANDB_API_KEY\\\" in os.environ else \\\"none\\\",\\n        gradient_checkpointing=True,\\n        gradient_checkpointing_kwargs={\\\"use_reentrant\\\": False},\\n        deepspeed=args.deepspeed,\\n    )\\n\\n    trainer = SFTTrainer(\\n        model=model,\\n        args=training_args,\\n        train_dataset=train_dataset,\\n        eval_dataset=eval_dataset,\\n        processing_class=tokenizer,\\n    )\\n\\n    logger.info(\\\"Starting SFT training...\\\")\\n    trainer.train()\\n\\n    logger.info(\\\"Saving model to %s\\\", args.output_dir)\\n    trainer.save_model(args.output_dir)\\n    tokenizer.save_pretrained(args.output_dir)\\n    logger.info(\\\"SFT training complete.\\\")\\n\\n\\nif __name__ == \\\"__main__\\\":\\n    main()\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "c8ef03f4-f47e-4d4d-b749-392d50468c3b",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\"\\\\\\\"\\\\\\\"SFT 训练脚本: Qwen3-4B + QLoRA 在 DocRED 上微调。\\\\n\\\\n支持单卡和多卡（DeepSpeed ZeRO-2/3）训练。\\\\n默认启用 4-bit QLoRA 量化，适配 RTX 5090 32GB x4。\\\\n\\\\n单卡:   python -m freige.training.sft_trainer --output_dir ./sft_output\\\\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\\\\\\\\\\n            -m freige.training.sft_trainer --deepspeed configs/deepspeed_zero2.json\\\\n不量化: 加 --no_quantize\\\\n\\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\nimport argparse\\\\nimport json\\\\nimport logging\\\\nimport os\\\\nfrom dataclasses import dataclass, field\\\\nfrom pathlib import Path\\\\nfrom typing import Optional\\\\n\\\\nimport torch\\\\nfrom datasets import Dataset\\\\nfrom peft import LoraConfig, TaskType, get_peft_model\\\\nfrom transformers import (\\\\n    AutoModelForCausalLM,\\\\n    AutoTokenizer,\\\\n    BitsAndBytesConfig,\\\\n    TrainingArguments,\\\\n)\\\\nfrom trl import SFTTrainer, SFTConfig\\\\n\\\\nlogging.basicConfig(level=logging.INFO, format=\\\\\\\"%(asctime)s %(levelname)s %(message)s\\\\\\\")\\\\nlogger = logging.getLogger(__name__)\\\\n\\\\nSYSTEM_PROMPT = (\\\\n    \\\\\\\"You are an information extraction model. Given a document with numbered sentences \\\\\\\"\\\\n    \\\\\\\"and a list of entities, extract all relation triples. For each triple, provide the \\\\\\\"\\\\n    \\\\\\\"head entity, relation type, tail entity, and the sentence IDs that serve as evidence. \\\\\\\"\\\\n    \\\\\\\"Output as a JSON list.\\\\\\\"\\\\n)\\\\n\\\\nDEFAULT_MODEL = \\\\\\\"/root/autodl-tmp/models/Qwen3-4B\\\\\\\"\\\\n\\\\n\\\\ndef build_chat_messages(instruction: str, input_text: str, output_text: str = None):\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"构建 Qwen3 chat 格式的消息列表。\\\\\\\"\\\\\\\"\\\\\\\"\\\\n    messages = [\\\\n        {\\\\\\\"role\\\\\\\": \\\\\\\"system\\\\\\\", \\\\\\\"content\\\\\\\": SYSTEM_PROMPT},\\\\n        {\\\\\\\"role\\\\\\\": \\\\\\\"user\\\\\\\", \\\\\\\"content\\\\\\\": f\\\\\\\"{instruction}\\\\\\\\n\\\\\\\\n{input_text}\\\\\\\"},\\\\n    ]\\\\n    if output_text is not None:\\\\n        messages.append({\\\\\\\"role\\\\\\\": \\\\\\\"assistant\\\\\\\", \\\\\\\"content\\\\\\\": output_text})\\\\n    return messages\\\\n\\\\n\\\\ndef prepare_dataset(\\\\n    data_dir: str = None,\\\\n    split: str = \\\\\\\"train\\\\\\\",\\\\n    tokenizer=None,\\\\n    max_length: int = 4096,\\\\n) -> Dataset:\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"加载并格式化 DocRED 数据为 SFT 训练格式。\\\\\\\"\\\\\\\"\\\\\\\"\\\\n    from freige.data.docred_processor import DocREDProcessor\\\\n\\\\n    processor = DocREDProcessor(data_dir=data_dir)\\\\n    samples = processor.process(split)\\\\n    groups = processor.group_by_document(samples)\\\\n\\\\n    formatted = []\\\\n    for doc_id, doc_samples in groups.items():\\\\n        sft_sample = processor.format_sft_sample(doc_samples)\\\\n        messages = build_chat_messages(\\\\n            sft_sample[\\\\\\\"instruction\\\\\\\"],\\\\n            sft_sample[\\\\\\\"input\\\\\\\"],\\\\n            sft_sample[\\\\\\\"output\\\\\\\"],\\\\n        )\\\\n        text = tokenizer.apply_chat_template(\\\\n            messages,\\\\n            tokenize=False,\\\\n            add_generation_prompt=False,\\\\n            enable_thinking=False,\\\\n        )\\\\n        formatted.append({\\\\\\\"text\\\\\\\": text})\\\\n\\\\n    logger.info(\\\\\\\"Prepared %d SFT samples from %d documents\\\\\\\", len(formatted), len(groups))\\\\n    return Dataset.from_list(formatted)\\\\n\\\\n\\\\ndef main():\\\\n    parser = argparse.ArgumentParser(description=\\\\\\\"FREIGE SFT Training\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--model_name\\\\\\\", type=str, default=DEFAULT_MODEL)\\\\n    parser.add_argument(\\\\\\\"--data_dir\\\\\\\", type=str, default=None,\\\\n                        help=\\\\\\\"DocRED JSON 目录\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--output_dir\\\\\\\", type=str, default=\\\\\\\"./sft_output\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--lora_rank\\\\\\\", type=int, default=64)\\\\n    parser.add_argument(\\\\\\\"--lora_alpha\\\\\\\", type=int, default=128)\\\\n    parser.add_argument(\\\\\\\"--lora_dropout\\\\\\\", type=float, default=0.05)\\\\n    parser.add_argument(\\\\\\\"--max_length\\\\\\\", type=int, default=4096)\\\\n    parser.add_argument(\\\\\\\"--quantize\\\\\\\", action=argparse.BooleanOptionalAction, default=True,\\\\n                        help=\\\\\\\"启用 4-bit QLoRA 量化（默认启用，--no_quantize 禁用）\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--deepspeed\\\\\\\", type=str, default=None,\\\\n                        help=\\\\\\\"DeepSpeed 配置文件路径\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--per_device_batch_size\\\\\\\", type=int, default=1)\\\\n    parser.add_argument(\\\\\\\"--gradient_accumulation_steps\\\\\\\", type=int, default=16)\\\\n    parser.add_argument(\\\\\\\"--num_epochs\\\\\\\", type=int, default=3)\\\\n    parser.add_argument(\\\\\\\"--learning_rate\\\\\\\", type=float, default=2e-4)\\\\n    parser.add_argument(\\\\\\\"--warmup_ratio\\\\\\\", type=float, default=0.05)\\\\n    parser.add_argument(\\\\\\\"--bf16\\\\\\\", action=\\\\\\\"store_true\\\\\\\", default=True)\\\\n    parser.add_argument(\\\\\\\"--seed\\\\\\\", type=int, default=42)\\\\n    parser.add_argument(\\\\\\\"--wandb_project\\\\\\\", type=str, default=\\\\\\\"freige-sft\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--wandb_run_name\\\\\\\", type=str, default=None)\\\\n    args = parser.parse_args()\\\\n\\\\n    if args.wandb_project and \\\\\\\"WANDB_API_KEY\\\\\\\" in os.environ:\\\\n        os.environ[\\\\\\\"WANDB_PROJECT\\\\\\\"] = args.wandb_project\\\\n        if args.wandb_run_name:\\\\n            os.environ[\\\\\\\"WANDB_NAME\\\\\\\"] = args.wandb_run_name\\\\n\\\\n    logger.info(\\\\\\\"Loading tokenizer: %s\\\\\\\", args.model_name)\\\\n    tokenizer = AutoTokenizer.from_pretrained(\\\\n        args.model_name,\\\\n        trust_remote_code=True,\\\\n        padding_side=\\\\\\\"right\\\\\\\",\\\\n    )\\\\n    if tokenizer.pad_token is None:\\\\n        tokenizer.pad_token = tokenizer.eos_token\\\\n\\\\n    logger.info(\\\\\\\"Preparing dataset...\\\\\\\")\\\\n    train_dataset = prepare_dataset(\\\\n        data_dir=args.data_dir,\\\\n        split=\\\\\\\"train\\\\\\\",\\\\n        tokenizer=tokenizer,\\\\n        max_length=args.max_length,\\\\n    )\\\\n    eval_dataset = prepare_dataset(\\\\n        data_dir=args.data_dir,\\\\n        split=\\\\\\\"dev\\\\\\\",\\\\n        tokenizer=tokenizer,\\\\n        max_length=args.max_length,\\\\n    )\\\\n\\\\n    logger.info(\\\\\\\"Loading model: %s\\\\\\\", args.model_name)\\\\n    local_rank = int(os.environ.get(\\\\\\\"LOCAL_RANK\\\\\\\", 0))\\\\n    model_kwargs = dict(\\\\n        trust_remote_code=True,\\\\n        attn_implementation=\\\\\\\"sdpa\\\\\\\",\\\\n        device_map={\\\\\\\"\\\\\\\": local_rank},\\\\n    )\\\\n    if args.quantize:\\\\n        logger.info(\\\\\\\"Using 4-bit QLoRA quantization\\\\\\\")\\\\n        model_kwargs[\\\\\\\"quantization_config\\\\\\\"] = BitsAndBytesConfig(\\\\n            load_in_4bit=True,\\\\n            bnb_4bit_compute_dtype=torch.bfloat16,\\\\n            bnb_4bit_quant_type=\\\\\\\"nf4\\\\\\\",\\\\n            bnb_4bit_use_double_quant=True,\\\\n        )\\\\n    else:\\\\n        model_kwargs[\\\\\\\"torch_dtype\\\\\\\"] = torch.bfloat16 if args.bf16 else torch.float16\\\\n    model = AutoModelForCausalLM.from_pretrained(args.model_name, **model_kwargs)\\\\n    model.config.use_cache = False\\\\n    model.gradient_checkpointing_enable()\\\\n\\\\n    lora_config = LoraConfig(\\\\n        task_type=TaskType.CAUSAL_LM,\\\\n        r=args.lora_rank,\\\\n        lora_alpha=args.lora_alpha,\\\\n        lora_dropout=args.lora_dropout,\\\\n        target_modules=[\\\\\\\"q_proj\\\\\\\", \\\\\\\"k_proj\\\\\\\", \\\\\\\"v_proj\\\\\\\", \\\\\\\"o_proj\\\\\\\",\\\\n                         \\\\\\\"gate_proj\\\\\\\", \\\\\\\"up_proj\\\\\\\", \\\\\\\"down_proj\\\\\\\"],\\\\n    )\\\\n    model = get_peft_model(model, lora_config)\\\\n    model.print_trainable_parameters()\\\\n\\\\n    training_args = SFTConfig(\\\\n        output_dir=args.output_dir,\\\\n        num_train_epochs=args.num_epochs,\\\\n        per_device_train_batch_size=args.per_device_batch_size,\\\\n        per_device_eval_batch_size=args.per_device_batch_size,\\\\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\\\\n        learning_rate=args.learning_rate,\\\\n        warmup_ratio=args.warmup_ratio,\\\\n        bf16=args.bf16,\\\\n        logging_steps=10,\\\\n        eval_strategy=\\\\\\\"epoch\\\\\\\",\\\\n        save_strategy=\\\\\\\"epoch\\\\\\\",\\\\n        save_total_limit=2,\\\\n        load_best_model_at_end=True,\\\\n        metric_for_best_model=\\\\\\\"eval_loss\\\\\\\",\\\\n        greater_is_better=False,\\\\n        seed=args.seed,\\\\n        max_length=args.max_length,\\\\n        dataset_text_field=\\\\\\\"text\\\\\\\",\\\\n        report_to=\\\\\\\"wandb\\\\\\\" if \\\\\\\"WANDB_API_KEY\\\\\\\" in os.environ else \\\\\\\"none\\\\\\\",\\\\n        gradient_checkpointing=True,\\\\n        gradient_checkpointing_kwargs={\\\\\\\"use_reentrant\\\\\\\": False},\\\\n        deepspeed=args.deepspeed,\\\\n    )\\\\n\\\\n    trainer = SFTTrainer(\\\\n        model=model,\\\\n        args=training_args,\\\\n        train_dataset=train_dataset,\\\\n        eval_dataset=eval_dataset,\\\\n        processing_class=tokenizer,\\\\n    )\\\\n\\\\n    logger.info(\\\\\\\"Starting SFT training...\\\\\\\")\\\\n    trainer.train()\\\\n\\\\n    logger.info(\\\\\\\"Saving model to %s\\\\\\\", args.output_dir)\\\\n    trainer.save_model(args.output_dir)\\\\n    tokenizer.save_pretrained(args.output_dir)\\\\n    logger.info(\\\\\\\"SFT training complete.\\\\\\\")\\\\n\\\\n\\\\nif __name__ == \\\\\\\"__main__\\\\\\\":\\\\n    main()\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.36}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"SFT 训练脚本: Qwen3-4B + QLoRA 在 DocRED 上微调。\\n\\n支持单卡和多卡（DeepSpeed ZeRO-2/3）训练。\\n默认启用 4-bit QLoRA 量化，适配 RTX 5090 32GB x4。\\n\\n单卡:   python -m freige.training.sft_trainer --output_dir ./sft_output\\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\\\\n            -m freige.training.sft_trainer --deepspeed configs/deepspeed_zero2.json\\n不量化: 加 --no_quantize\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport os\\nfrom dataclasses import dataclass, field\\nfrom pathlib import Path\\nfrom typing import Optional\\n\\nimport torch\\nfrom datasets import Dataset\\nfrom peft import LoraConfig, TaskType, get_peft_model\\nfrom transformers import (\\n    AutoModelForCausalLM,\\n    AutoTokenizer,\\n    BitsAndBytesConfig,\\n    TrainingArguments,\\n)\\nfrom trl import SFTTrainer, SFTConfig\\n\\nlogging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s %(levelname)s %(message)s\\\")\\nlogger = logging.getLogger(__name__)\\n\\nSYSTEM_PROMPT = (\\n    \\\"You are an information extraction model. Given a document with numbered sentences \\\"\\n    \\\"and a list of entities, extract all relation triples. For each triple, provide the \\\"\\n    \\\"head entity, relation type, tail entity, and the sentence IDs that serve as evidence. \\\"\\n    \\\"Output as a JSON list.\\\"\\n)\\n\\nDEFAULT_MODEL = \\\"/root/autodl-tmp/models/Qwen3-4B\\\"\\n\\n\\ndef build_chat_messages(instruction: str, input_text: str, output_text: str = None):\\n    \\\"\\\"\\\"构建 Qwen3 chat 格式的消息列表。\\\"\\\"\\\"\\n    messages = [\\n        {\\\"role\\\": \\\"system\\\", \\\"content\\\": SYSTEM_PROMPT},\\n        {\\\"role\\\": \\\"user\\\", \\\"content\\\": f\\\"{instruction}\\\\n\\\\n{input_text}\\\"},\\n    ]\\n    if output_text is not None:\\n        messages.append({\\\"role\\\": \\\"assistant\\\", \\\"content\\\": output_text})\\n    return messages\\n\\n\\ndef prepare_dataset(\\n    data_dir: str = None,\\n    split: str = \\\"train\\\",\\n    tokenizer=None,\\n    max_length: int = 4096,\\n) -> Dataset:\\n    \\\"\\\"\\\"加载并格式化 DocRED 数据为 SFT 训练格式。\\\"\\\"\\\"\\n    from freige.data.docred_processor import DocREDProcessor\\n\\n    processor = DocREDProcessor(data_dir=data_dir)\\n    samples = processor.process(split)\\n    groups = processor.group_by_document(samples)\\n\\n    formatted = []\\n    for doc_id, doc_samples in groups.items():\\n        sft_sample = processor.format_sft_sample(doc_samples)\\n        messages = build_chat_messages(\\n            sft_sample[\\\"instruction\\\"],\\n            sft_sample[\\\"input\\\"],\\n            sft_sample[\\\"output\\\"],\\n        )\\n        text = tokenizer.apply_chat_template(\\n            messages,\\n            tokenize=False,\\n            add_generation_prompt=False,\\n            enable_thinking=False,\\n        )\\n        formatted.append({\\\"text\\\": text})\\n\\n    logger.info(\\\"Prepared %d SFT samples from %d documents\\\", len(formatted), len(groups))\\n    return Dataset.from_list(formatted)\\n\\n\\ndef main():\\n    parser = argparse.ArgumentParser(description=\\\"FREIGE SFT Training\\\")\\n    parser.add_argument(\\\"--model_name\\\", type=str, default=DEFAULT_MODEL)\\n    parser.add_argument(\\\"--data_dir\\\", type=str, default=None,\\n                        help=\\\"DocRED JSON 目录\\\")\\n    parser.add_argument(\\\"--output_dir\\\", type=str, default=\\\"./sft_output\\\")\\n    parser.add_argument(\\\"--lora_rank\\\", type=int, default=64)\\n    parser.add_argument(\\\"--lora_alpha\\\", type=int, default=128)\\n    parser.add_argument(\\\"--lora_dropout\\\", type=float, default=0.05)\\n    parser.add_argument(\\\"--max_length\\\", type=int, default=4096)\\n    parser.add_argument(\\\"--quantize\\\", action=argparse.BooleanOptionalAction, default=True,\\n                        help=\\\"启用 4-bit QLoRA 量化（默认启用，--no_quantize 禁用）\\\")\\n    parser.add_argument(\\\"--deepspeed\\\", type=str, default=None,\\n                        help=\\\"DeepSpeed 配置文件路径\\\")\\n    parser.add_argument(\\\"--per_device_batch_size\\\", type=int, default=1)\\n    parser.add_argument(\\\"--gradient_accumulation_steps\\\", type=int, default=16)\\n    parser.add_argument(\\\"--num_epochs\\\", type=int, default=3)\\n    parser.add_argument(\\\"--learning_rate\\\", type=float, default=2e-4)\\n    parser.add_argument(\\\"--warmup_ratio\\\", type=float, default=0.05)\\n    parser.add_argument(\\\"--bf16\\\", action=\\\"store_true\\\", default=True)\\n    parser.add_argument(\\\"--seed\\\", type=int, default=42)\\n    parser.add_argument(\\\"--wandb_project\\\", type=str, default=\\\"freige-sft\\\")\\n    parser.add_argument(\\\"--wandb_run_name\\\", type=str, default=None)\\n    args = parser.parse_args()\\n\\n    if args.wandb_project and \\\"WANDB_API_KEY\\\" in os.environ:\\n        os.environ[\\\"WANDB_PROJECT\\\"] = args.wandb_project\\n        if args.wandb_run_name:\\n            os.environ[\\\"WANDB_NAME\\\"] = args.wandb_run_name\\n\\n    logger.info(\\\"Loading tokenizer: %s\\\", args.model_name)\\n    tokenizer = AutoTokenizer.from_pretrained(\\n        args.model_name,\\n        trust_remote_code=True,\\n        padding_side=\\\"right\\\",\\n    )\\n    if tokenizer.pad_token is None:\\n        tokenizer.pad_token = tokenizer.eos_token\\n\\n    logger.info(\\\"Preparing dataset...\\\")\\n    train_dataset = prepare_dataset(\\n        data_dir=args.data_dir,\\n        split=\\\"train\\\",\\n        tokenizer=tokenizer,\\n        max_length=args.max_length,\\n    )\\n    eval_dataset = prepare_dataset(\\n        data_dir=args.data_dir,\\n        split=\\\"dev\\\",\\n        tokenizer=tokenizer,\\n        max_length=args.max_length,\\n    )\\n\\n    logger.info(\\\"Loading model: %s\\\", args.model_name)\\n    local_rank = int(os.environ.get(\\\"LOCAL_RANK\\\", 0))\\n    model_kwargs = dict(\\n        trust_remote_code=True,\\n        attn_implementation=\\\"sdpa\\\",\\n        device_map={\\\"\\\": local_rank},\\n    )\\n    if args.quantize:\\n        logger.info(\\\"Using 4-bit QLoRA quantization\\\")\\n        model_kwargs[\\\"quantization_config\\\"] = BitsAndBytesConfig(\\n            load_in_4bit=True,\\n            bnb_4bit_compute_dtype=torch.bfloat16,\\n            bnb_4bit_quant_type=\\\"nf4\\\",\\n            bnb_4bit_use_double_quant=True,\\n        )\\n    else:\\n        model_kwargs[\\\"torch_dtype\\\"] = torch.bfloat16 if args.bf16 else torch.float16\\n    model = AutoModelForCausalLM.from_pretrained(args.model_name, **model_kwargs)\\n    model.config.use_cache = False\\n    model.gradient_checkpointing_enable()\\n\\n    lora_config = LoraConfig(\\n        task_type=TaskType.CAUSAL_LM,\\n        r=args.lora_rank,\\n        lora_alpha=args.lora_alpha,\\n        lora_dropout=args.lora_dropout,\\n        target_modules=[\\\"q_proj\\\", \\\"k_proj\\\", \\\"v_proj\\\", \\\"o_proj\\\",\\n                         \\\"gate_proj\\\", \\\"up_proj\\\", \\\"down_proj\\\"],\\n    )\\n    model = get_peft_model(model, lora_config)\\n    model.print_trainable_parameters()\\n\\n    training_args = SFTConfig(\\n        output_dir=args.output_dir,\\n        num_train_epochs=args.num_epochs,\\n        per_device_train_batch_size=args.per_device_batch_size,\\n        per_device_eval_batch_size=args.per_device_batch_size,\\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\\n        learning_rate=args.learning_rate,\\n        warmup_ratio=args.warmup_ratio,\\n        bf16=args.bf16,\\n        logging_steps=10,\\n        eval_strategy=\\\"epoch\\\",\\n        save_strategy=\\\"epoch\\\",\\n        save_total_limit=2,\\n        load_best_model_at_end=True,\\n        metric_for_best_model=\\\"eval_loss\\\",\\n        greater_is_better=False,\\n        seed=args.seed,\\n        max_length=args.max_length,\\n        dataset_text_field=\\\"text\\\",\\n        report_to=\\\"wandb\\\" if \\\"WANDB_API_KEY\\\" in os.environ else \\\"none\\\",\\n        gradient_checkpointing=True,\\n        gradient_checkpointing_kwargs={\\\"use_reentrant\\\": False},\\n        deepspeed=args.deepspeed,\\n    )\\n\\n    trainer = SFTTrainer(\\n        model=model,\\n        args=training_args,\\n        train_dataset=train_dataset,\\n        eval_dataset=eval_dataset,\\n        processing_class=tokenizer,\\n    )\\n\\n    logger.info(\\\"Starting SFT training...\\\")\\n    trainer.train()\\n\\n    logger.info(\\\"Saving model to %s\\\", args.output_dir)\\n    trainer.save_model(args.output_dir)\\n    tokenizer.save_pretrained(args.output_dir)\\n    logger.info(\\\"SFT training complete.\\\")\\n\\n\\nif __name__ == \\\"__main__\\\":\\n    main()\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.36}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 13 · 2026-05-15T02:25:03.552Z_

<details><summary>↩ Tool result · `toolu_013JJ1ysj6VQzPnig2sLDZxB`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"total 273676\\ndrwxr-xr-x  4 root root      4096 May 14 14:43 .\\ndrwxr-xr-x 40 root root      4096 May 15 09:38 ..\\n-rw-r--r--  1 root root      1450 May 14 14:43 README.md\\n-rw-r--r--  1 root root      1112 May 14 14:43 adapter_config.json\\n-rw-r--r--  1 root root 264309400 May 14 14:43 adapter_model.safetensors\\n-rw-r--r--  1 root root       707 May 14 14:43 added_tokens.json\\n-rw-r--r--  1 root root      4168 May 14 14:43 chat_template.jinja\\ndrwxr-xr-x  3 root root      4096 May 14 14:43 checkpoint-144\\ndrwxr-xr-x  3 root root      4096 May 14 14:36 checkpoint-96\\n-rw-r--r--  1 root root   1671853 May 14 14:43 merges.txt\\n-rw-r--r--  1 root root       499 May 14 14:43 special_tokens_map.json\\n-rw-r--r--  1 root root  11422654 May 14 14:43 tokenizer.json\\n-rw-r--r--  1 root root      5431 May 14 14:43 tokenizer_config.json\\n-rw-r--r--  1 root root      8017 May 14 14:43 training_args.bin\\n-rw-r--r--  1 root root   2776833 May 14 14:43 vocab.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "27700cfe-ad6c-4f5d-9fba-2ac63ff0ed97",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"total 273676\\\\ndrwxr-xr-x  4 root root      4096 May 14 14:43 .\\\\ndrwxr-xr-x 40 root root      4096 May 15 09:38 ..\\\\n-rw-r--r--  1 root root      1450 May 14 14:43 README.md\\\\n-rw-r--r--  1 root root      1112 May 14 14:43 adapter_config.json\\\\n-rw-r--r--  1 root root 264309400 May 14 14:43 adapter_model.safetensors\\\\n-rw-r--r--  1 root root       707 May 14 14:43 added_tokens.json\\\\n-rw-r--r--  1 root root      4168 May 14 14:43 chat_template.jinja\\\\ndrwxr-xr-x  3 root root      4096 May 14 14:43 checkpoint-144\\\\ndrwxr-xr-x  3 root root      4096 May 14 14:36 checkpoint-96\\\\n-rw-r--r--  1 root root   1671853 May 14 14:43 merges.txt\\\\n-rw-r--r--  1 root root       499 May 14 14:43 special_tokens_map.json\\\\n-rw-r--r--  1 root root  11422654 May 14 14:43 tokenizer.json\\\\n-rw-r--r--  1 root root      5431 May 14 14:43 tokenizer_config.json\\\\n-rw-r--r--  1 root root      8017 May 14 14:43 training_args.bin\\\\n-rw-r--r--  1 root root   2776833 May 14 14:43 vocab.json\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.35}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"total 273676\\ndrwxr-xr-x  4 root root      4096 May 14 14:43 .\\ndrwxr-xr-x 40 root root      4096 May 15 09:38 ..\\n-rw-r--r--  1 root root      1450 May 14 14:43 README.md\\n-rw-r--r--  1 root root      1112 May 14 14:43 adapter_config.json\\n-rw-r--r--  1 root root 264309400 May 14 14:43 adapter_model.safetensors\\n-rw-r--r--  1 root root       707 May 14 14:43 added_tokens.json\\n-rw-r--r--  1 root root      4168 May 14 14:43 chat_template.jinja\\ndrwxr-xr-x  3 root root      4096 May 14 14:43 checkpoint-144\\ndrwxr-xr-x  3 root root      4096 May 14 14:36 checkpoint-96\\n-rw-r--r--  1 root root   1671853 May 14 14:43 merges.txt\\n-rw-r--r--  1 root root       499 May 14 14:43 special_tokens_map.json\\n-rw-r--r--  1 root root  11422654 May 14 14:43 tokenizer.json\\n-rw-r--r--  1 root root      5431 May 14 14:43 tokenizer_config.json\\n-rw-r--r--  1 root root      8017 May 14 14:43 training_args.bin\\n-rw-r--r--  1 root root   2776833 May 14 14:43 vocab.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 14_

<details><summary>Logged reasoning block</summary>

```text
Good, I have both files. Let me now get the SFT adapter config and check for eval-related code. The rsft_trainer.py output was truncated - I need to see the full argparse section. Let me also check for the evaluator module.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "e9a5e8f3-9ae7-4b49-a7d2-6342ae00b967",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QmnapXnLhQ8nXNRRNZHUAK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7656,
      "cache_read_input_tokens": 25000,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7656
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 15_

rsft_trainer.py 输出被截断了，需要补读中间部分。同时获取 SFT 配置和 evaluator 模块。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "06c48ca3-b217-40f3-b4a0-826899345317",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QmnapXnLhQ8nXNRRNZHUAK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7656,
      "cache_read_input_tokens": 25000,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7656
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 16_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01FNoktRAq2mLfpmq3emPLbH`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "cat /root/autodl-tmp/sft_output/adapter_config.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "d652d58b-6c05-4091-a4c8-d867033ff7ff",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QmnapXnLhQ8nXNRRNZHUAK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7656,
      "cache_read_input_tokens": 25000,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7656
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 17 · 2026-05-15T02:25:09.967Z_

<details><summary>↩ Tool result · `toolu_01FNoktRAq2mLfpmq3emPLbH`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"alora_invocation_tokens\\\": null,\\n  \\\"alpha_pattern\\\": {},\\n  \\\"arrow_config\\\": null,\\n  \\\"auto_mapping\\\": null,\\n  \\\"base_model_name_or_path\\\": \\\"/root/autodl-tmp/models/Qwen3-4B\\\",\\n  \\\"bias\\\": \\\"none\\\",\\n  \\\"corda_config\\\": null,\\n  \\\"ensure_weight_tying\\\": false,\\n  \\\"eva_config\\\": null,\\n  \\\"exclude_modules\\\": null,\\n  \\\"fan_in_fan_out\\\": false,\\n  \\\"inference_mode\\\": true,\\n  \\\"init_lora_weights\\\": true,\\n  \\\"layer_replication\\\": null,\\n  \\\"layers_pattern\\\": null,\\n  \\\"layers_to_transform\\\": null,\\n  \\\"loftq_config\\\": {},\\n  \\\"lora_alpha\\\": 128,\\n  \\\"lora_bias\\\": false,\\n  \\\"lora_dropout\\\": 0.05,\\n  \\\"lora_ga_config\\\": null,\\n  \\\"megatron_config\\\": null,\\n  \\\"megatron_core\\\": \\\"megatron.core\\\",\\n  \\\"modules_to_save\\\": null,\\n  \\\"peft_type\\\": \\\"LORA\\\",\\n  \\\"peft_version\\\": \\\"0.19.0\\\",\\n  \\\"qalora_group_size\\\": 16,\\n  \\\"r\\\": 64,\\n  \\\"rank_pattern\\\": {},\\n  \\\"revision\\\": null,\\n  \\\"target_modules\\\": [\\n    \\\"v_proj\\\",\\n    \\\"gate_proj\\\",\\n    \\\"q_proj\\\",\\n    \\\"o_proj\\\",\\n    \\\"down_proj\\\",\\n    \\\"up_proj\\\",\\n    \\\"k_proj\\\"\\n  ],\\n  \\\"target_parameters\\\": null,\\n  \\\"task_type\\\": \\\"CAUSAL_LM\\\",\\n  \\\"trainable_token_indices\\\": null,\\n  \\\"use_bdlora\\\": null,\\n  \\\"use_dora\\\": false,\\n  \\\"use_qalora\\\": false,\\n  \\\"use_rslora\\\": false\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.3}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "74bcf2e5-6f8d-4d26-bd3c-2e31e53201f6",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"{\\\\n  \\\\\\\"alora_invocation_tokens\\\\\\\": null,\\\\n  \\\\\\\"alpha_pattern\\\\\\\": {},\\\\n  \\\\\\\"arrow_config\\\\\\\": null,\\\\n  \\\\\\\"auto_mapping\\\\\\\": null,\\\\n  \\\\\\\"base_model_name_or_path\\\\\\\": \\\\\\\"/root/autodl-tmp/models/Qwen3-4B\\\\\\\",\\\\n  \\\\\\\"bias\\\\\\\": \\\\\\\"none\\\\\\\",\\\\n  \\\\\\\"corda_config\\\\\\\": null,\\\\n  \\\\\\\"ensure_weight_tying\\\\\\\": false,\\\\n  \\\\\\\"eva_config\\\\\\\": null,\\\\n  \\\\\\\"exclude_modules\\\\\\\": null,\\\\n  \\\\\\\"fan_in_fan_out\\\\\\\": false,\\\\n  \\\\\\\"inference_mode\\\\\\\": true,\\\\n  \\\\\\\"init_lora_weights\\\\\\\": true,\\\\n  \\\\\\\"layer_replication\\\\\\\": null,\\\\n  \\\\\\\"layers_pattern\\\\\\\": null,\\\\n  \\\\\\\"layers_to_transform\\\\\\\": null,\\\\n  \\\\\\\"loftq_config\\\\\\\": {},\\\\n  \\\\\\\"lora_alpha\\\\\\\": 128,\\\\n  \\\\\\\"lora_bias\\\\\\\": false,\\\\n  \\\\\\\"lora_dropout\\\\\\\": 0.05,\\\\n  \\\\\\\"lora_ga_config\\\\\\\": null,\\\\n  \\\\\\\"megatron_config\\\\\\\": null,\\\\n  \\\\\\\"megatron_core\\\\\\\": \\\\\\\"megatron.core\\\\\\\",\\\\n  \\\\\\\"modules_to_save\\\\\\\": null,\\\\n  \\\\\\\"peft_type\\\\\\\": \\\\\\\"LORA\\\\\\\",\\\\n  \\\\\\\"peft_version\\\\\\\": \\\\\\\"0.19.0\\\\\\\",\\\\n  \\\\\\\"qalora_group_size\\\\\\\": 16,\\\\n  \\\\\\\"r\\\\\\\": 64,\\\\n  \\\\\\\"rank_pattern\\\\\\\": {},\\\\n  \\\\\\\"revision\\\\\\\": null,\\\\n  \\\\\\\"target_modules\\\\\\\": [\\\\n    \\\\\\\"v_proj\\\\\\\",\\\\n    \\\\\\\"gate_proj\\\\\\\",\\\\n    \\\\\\\"q_proj\\\\\\\",\\\\n    \\\\\\\"o_proj\\\\\\\",\\\\n    \\\\\\\"down_proj\\\\\\\",\\\\n    \\\\\\\"up_proj\\\\\\\",\\\\n    \\\\\\\"k_proj\\\\\\\"\\\\n  ],\\\\n  \\\\\\\"target_parameters\\\\\\\": null,\\\\n  \\\\\\\"task_type\\\\\\\": \\\\\\\"CAUSAL_LM\\\\\\\",\\\\n  \\\\\\\"trainable_token_indices\\\\\\\": null,\\\\n  \\\\\\\"use_bdlora\\\\\\\": null,\\\\n  \\\\\\\"use_dora\\\\\\\": false,\\\\n  \\\\\\\"use_qalora\\\\\\\": false,\\\\n  \\\\\\\"use_rslora\\\\\\\": false\\\\n}\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.3}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"alora_invocation_tokens\\\": null,\\n  \\\"alpha_pattern\\\": {},\\n  \\\"arrow_config\\\": null,\\n  \\\"auto_mapping\\\": null,\\n  \\\"base_model_name_or_path\\\": \\\"/root/autodl-tmp/models/Qwen3-4B\\\",\\n  \\\"bias\\\": \\\"none\\\",\\n  \\\"corda_config\\\": null,\\n  \\\"ensure_weight_tying\\\": false,\\n  \\\"eva_config\\\": null,\\n  \\\"exclude_modules\\\": null,\\n  \\\"fan_in_fan_out\\\": false,\\n  \\\"inference_mode\\\": true,\\n  \\\"init_lora_weights\\\": true,\\n  \\\"layer_replication\\\": null,\\n  \\\"layers_pattern\\\": null,\\n  \\\"layers_to_transform\\\": null,\\n  \\\"loftq_config\\\": {},\\n  \\\"lora_alpha\\\": 128,\\n  \\\"lora_bias\\\": false,\\n  \\\"lora_dropout\\\": 0.05,\\n  \\\"lora_ga_config\\\": null,\\n  \\\"megatron_config\\\": null,\\n  \\\"megatron_core\\\": \\\"megatron.core\\\",\\n  \\\"modules_to_save\\\": null,\\n  \\\"peft_type\\\": \\\"LORA\\\",\\n  \\\"peft_version\\\": \\\"0.19.0\\\",\\n  \\\"qalora_group_size\\\": 16,\\n  \\\"r\\\": 64,\\n  \\\"rank_pattern\\\": {},\\n  \\\"revision\\\": null,\\n  \\\"target_modules\\\": [\\n    \\\"v_proj\\\",\\n    \\\"gate_proj\\\",\\n    \\\"q_proj\\\",\\n    \\\"o_proj\\\",\\n    \\\"down_proj\\\",\\n    \\\"up_proj\\\",\\n    \\\"k_proj\\\"\\n  ],\\n  \\\"target_parameters\\\": null,\\n  \\\"task_type\\\": \\\"CAUSAL_LM\\\",\\n  \\\"trainable_token_indices\\\": null,\\n  \\\"use_bdlora\\\": null,\\n  \\\"use_dora\\\": false,\\n  \\\"use_qalora\\\": false,\\n  \\\"use_rslora\\\": false\\n}\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.3}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 18_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01V25T86vXFowEmcZWiAbmo7`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "head -200 /root/autodl-tmp/freige/training/rsft_trainer.py",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "0685f084-1b1e-4923-8789-731fec9e7444",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QmnapXnLhQ8nXNRRNZHUAK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7656,
      "cache_read_input_tokens": 25000,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7656
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 19 · 2026-05-15T02:25:10.913Z_

<details><summary>↩ Tool result · `toolu_01V25T86vXFowEmcZWiAbmo7`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\\n\\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\\n\\n输入: JSONL，每行 {\\\"doc_id\\\": ..., \\\"input\\\": ..., \\\"output\\\": ..., \\\"ced_score\\\": ..., ...}\\n输出: QLoRA adapter checkpoint\\n依赖: transformers, trl, peft, bitsandbytes, datasets\\n\\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\\\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport os\\n\\nimport torch\\nfrom datasets import Dataset\\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\\nfrom torch.utils.data import WeightedRandomSampler\\nfrom transformers import (\\n    AutoModelForCausalLM,\\n    AutoTokenizer,\\n    BitsAndBytesConfig,\\n)\\nfrom trl import SFTConfig, SFTTrainer\\n\\nfrom freige.training.sft_trainer import SYSTEM_PROMPT\\n\\nlogging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s %(levelname)s %(message)s\\\")\\nlogger = logging.getLogger(__name__)\\n\\nDEFAULT_BASE_MODEL = \\\"/root/autodl-tmp/models/Qwen3-4B\\\"\\nDEFAULT_SFT_ADAPTER = \\\"/root/autodl-tmp/sft_output\\\"\\n\\n\\ndef load_rsft_data(data_path: str, tokenizer, max_length: int = 2048):\\n    \\\"\\\"\\\"加载 CED 筛选后的 RSFT 数据，格式化为 chat template 文本。\\n\\n    每行 JSONL 的 input 字段作为 user message，output 字段作为 assistant response，\\n    经 apply_chat_template 拼接后用于 SFT 训练。超过 max_length 的样本被跳过\\n    而非截断，避免训练在不完整 JSON 输出上。\\n\\n    Returns:\\n        (Dataset, list[float]): 训练数据集和对应的 CED scores\\n    \\\"\\\"\\\"\\n    samples = []\\n    with open(data_path) as f:\\n        for line in f:\\n            if line.strip():\\n                samples.append(json.loads(line))\\n\\n    logger.info(\\\"Loaded %d RSFT samples from %s\\\", len(samples), data_path)\\n\\n    formatted = []\\n    ced_scores = []\\n    skipped = 0\\n    for s in samples:\\n        messages = [\\n            {\\\"role\\\": \\\"system\\\", \\\"content\\\": SYSTEM_PROMPT},\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": s[\\\"input\\\"]},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": s[\\\"output\\\"]},\\n        ]\\n        text = tokenizer.apply_chat_template(\\n            messages,\\n            tokenize=False,\\n            add_generation_prompt=False,\\n            enable_thinking=False,\\n        )\\n        token_len = len(tokenizer.encode(text, add_special_tokens=False))\\n        if token_len > max_length:\\n            skipped += 1\\n            continue\\n        formatted.append({\\\"text\\\": text})\\n        ced_scores.append(s.get(\\\"ced_score\\\", 1.0))\\n\\n    if skipped:\\n        logger.warning(\\\"Skipped %d samples exceeding max_length=%d\\\", skipped, max_length)\\n\\n    if ced_scores:\\n        logger.info(\\n            \\\"Prepared %d RSFT samples (CED scores: min=%.3f, max=%.3f, mean=%.3f)\\\",\\n            len(formatted), min(ced_scores), max(ced_scores),\\n            sum(ced_scores) / len(ced_scores),\\n        )\\n    return Dataset.from_list(formatted), ced_scores\\n\\n\\nclass WeightedSFTTrainer(SFTTrainer):\\n    \\\"\\\"\\\"SFTTrainer with CED score-weighted sampling.\\n\\n    高 CED score 的样本被更频繁采样。使用 WeightedRandomSampler 实现，\\n    适用于单机训练。多机 DDP 场景下 Accelerate 会替换 sampler，\\n    此时 weighted_sampling 不生效，需改用数据集层面的过采样。\\n    \\\"\\\"\\\"\\n\\n    def __init__(self, *args, sample_weights=None, **kwargs):\\n        super().__init__(*args, **kwargs)\\n        self.sample_weights = sample_weights\\n\\n    def _get_train_sampler(self, dataset=None):\\n        if self.sample_weights is not None:\\n            ds = dataset if dataset is not None else self.train_dataset\\n            return WeightedRandomSampler(\\n                weights=self.sample_weights,\\n                num_samples=len(ds),\\n                replacement=True,\\n            )\\n        return super()._get_train_sampler(dataset)\\n\\n\\ndef main():\\n    parser = argparse.ArgumentParser(description=\\\"FREIGE RSFT Training\\\")\\n    parser.add_argument(\\\"--base_model\\\", type=str, default=DEFAULT_BASE_MODEL)\\n    parser.add_argument(\\\"--sft_adapter\\\", type=str, default=DEFAULT_SFT_ADAPTER,\\n                        help=\\\"SFT warmup adapter 路径 (merge 后训练新 LoRA)\\\")\\n    parser.add_argument(\\\"--rsft_data_path\\\", type=str, required=True,\\n                        help=\\\"CED 筛选后的 RSFT 训练数据 (JSONL)\\\")\\n    parser.add_argument(\\\"--output_dir\\\", type=str, required=True)\\n    parser.add_argument(\\\"--learning_rate\\\", type=float, default=2e-5)\\n    parser.add_argument(\\\"--num_epochs\\\", type=int, default=3)\\n    parser.add_argument(\\\"--per_device_batch_size\\\", type=int, default=4)\\n    parser.add_argument(\\\"--gradient_accumulation_steps\\\", type=int, default=4)\\n    parser.add_argument(\\\"--warmup_steps\\\", type=int, default=100)\\n    parser.add_argument(\\\"--save_steps\\\", type=int, default=50)\\n    parser.add_argument(\\\"--save_total_limit\\\", type=int, default=5)\\n    parser.add_argument(\\\"--max_length\\\", type=int, default=2048)\\n    parser.add_argument(\\\"--seed\\\", type=int, default=42)\\n    parser.add_argument(\\\"--wandb_project\\\", type=str, default=\\\"freige-rsft\\\")\\n    parser.add_argument(\\\"--wandb_run_name\\\", type=str, default=None)\\n    parser.add_argument(\\\"--weighted_sampling\\\", action=\\\"store_true\\\",\\n                        help=\\\"按 CED score 加权采样（高分样本更频繁）\\\")\\n    parser.add_argument(\\\"--quantize\\\", action=\\\"store_true\\\",\\n                        help=\\\"启用 4-bit QLoRA 量化\\\")\\n    parser.add_argument(\\\"--lora_rank\\\", type=int, default=64)\\n    parser.add_argument(\\\"--lora_alpha\\\", type=int, default=128)\\n    parser.add_argument(\\\"--lora_dropout\\\", type=float, default=0.05)\\n    parser.add_argument(\\\"--bf16\\\", action=\\\"store_true\\\", default=True)\\n    parser.add_argument(\\\"--deepspeed\\\", type=str, default=None,\\n                        help=\\\"DeepSpeed 配置文件路径\\\")\\n    args = parser.parse_args()\\n\\n    # W&B\\n    if args.wandb_project and \\\"WANDB_API_KEY\\\" in os.environ:\\n        os.environ[\\\"WANDB_PROJECT\\\"] = args.wandb_project\\n        if args.wandb_run_name:\\n            os.environ[\\\"WANDB_NAME\\\"] = args.wandb_run_name\\n\\n    # Tokenizer\\n    logger.info(\\\"Loading tokenizer: %s\\\", args.base_model)\\n    tokenizer = AutoTokenizer.from_pretrained(\\n        args.base_model, trust_remote_code=True, padding_side=\\\"right\\\",\\n    )\\n    if tokenizer.pad_token is None:\\n        tokenizer.pad_token = tokenizer.eos_token\\n\\n    # Data\\n    logger.info(\\\"Loading RSFT data: %s\\\", args.rsft_data_path)\\n    train_dataset, ced_scores = load_rsft_data(\\n        args.rsft_data_path, tokenizer, args.max_length,\\n    )\\n\\n    # Model: base → merge SFT adapter → new LoRA\\n    logger.info(\\\"Loading base model: %s\\\", args.base_model)\\n    local_rank = int(os.environ.get(\\\"LOCAL_RANK\\\", 0))\\n    model_kwargs = dict(\\n        trust_remote_code=True,\\n        attn_implementation=\\\"sdpa\\\",\\n        device_map={\\\"\\\": local_rank},\\n    )\\n    if args.quantize:\\n        logger.info(\\\"Using 4-bit QLoRA quantization\\\")\\n        model_kwargs[\\\"quantization_config\\\"] = BitsAndBytesConfig(\\n            load_in_4bit=True,\\n            bnb_4bit_compute_dtype=torch.bfloat16,\\n            bnb_4bit_quant_type=\\\"nf4\\\",\\n            bnb_4bit_use_double_quant=True,\\n        )\\n    else:\\n        model_kwargs[\\\"torch_dtype\\\"] = torch.bfloat16 if args.bf16 else torch.float16\\n\\n    model = AutoModelForCausalLM.from_pretrained(args.base_model, **model_kwargs)\\n\\n    if args.sft_adapter:\\n        logger.info(\\\"Merging SFT adapter: %s\\\", args.sft_adapter)\\n        model = PeftModel.from_pretrained(model, args.sft_adapter)\\n        model = model.merge_and_unload()\\n\\n    model.config.use_cache = False\\n    model.gradient_checkpointing_enable()\\n\\n    # Fresh LoRA for RSFT (与 SFT warmup 相同结构)\\n    lora_config = LoraConfig(\\n        task_type=TaskType.CAUSAL_LM,\\n        r=args.lora_rank,\\n        lora_alpha=args.lora_alpha,\\n        lora_dropout=args.lora_dropout,\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.3}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "86c29f4e-c199-4cbe-a7d3-7f486fb8ae03",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\"\\\\\\\"\\\\\\\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\\\\n\\\\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\\\\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\\\\n\\\\n输入: JSONL，每行 {\\\\\\\"doc_id\\\\\\\": ..., \\\\\\\"input\\\\\\\": ..., \\\\\\\"output\\\\\\\": ..., \\\\\\\"ced_score\\\\\\\": ..., ...}\\\\n输出: QLoRA adapter checkpoint\\\\n依赖: transformers, trl, peft, bitsandbytes, datasets\\\\n\\\\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\\\\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\\\\\\\\\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\\\\n\\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\nimport argparse\\\\nimport json\\\\nimport logging\\\\nimport os\\\\n\\\\nimport torch\\\\nfrom datasets import Dataset\\\\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\\\\nfrom torch.utils.data import WeightedRandomSampler\\\\nfrom transformers import (\\\\n    AutoModelForCausalLM,\\\\n    AutoTokenizer,\\\\n    BitsAndBytesConfig,\\\\n)\\\\nfrom trl import SFTConfig, SFTTrainer\\\\n\\\\nfrom freige.training.sft_trainer import SYSTEM_PROMPT\\\\n\\\\nlogging.basicConfig(level=logging.INFO, format=\\\\\\\"%(asctime)s %(levelname)s %(message)s\\\\\\\")\\\\nlogger = logging.getLogger(__name__)\\\\n\\\\nDEFAULT_BASE_MODEL = \\\\\\\"/root/autodl-tmp/models/Qwen3-4B\\\\\\\"\\\\nDEFAULT_SFT_ADAPTER = \\\\\\\"/root/autodl-tmp/sft_output\\\\\\\"\\\\n\\\\n\\\\ndef load_rsft_data(data_path: str, tokenizer, max_length: int = 2048):\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"加载 CED 筛选后的 RSFT 数据，格式化为 chat template 文本。\\\\n\\\\n    每行 JSONL 的 input 字段作为 user message，output 字段作为 assistant response，\\\\n    经 apply_chat_template 拼接后用于 SFT 训练。超过 max_length 的样本被跳过\\\\n    而非截断，避免训练在不完整 JSON 输出上。\\\\n\\\\n    Returns:\\\\n        (Dataset, list[float]): 训练数据集和对应的 CED scores\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"\\\\n    samples = []\\\\n    with open(data_path) as f:\\\\n        for line in f:\\\\n            if line.strip():\\\\n                samples.append(json.loads(line))\\\\n\\\\n    logger.info(\\\\\\\"Loaded %d RSFT samples from %s\\\\\\\", len(samples), data_path)\\\\n\\\\n    formatted = []\\\\n    ced_scores = []\\\\n    skipped = 0\\\\n    for s in samples:\\\\n        messages = [\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"system\\\\\\\", \\\\\\\"content\\\\\\\": SYSTEM_PROMPT},\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"user\\\\\\\", \\\\\\\"content\\\\\\\": s[\\\\\\\"input\\\\\\\"]},\\\\n            {\\\\\\\"role\\\\\\\": \\\\\\\"assistant\\\\\\\", \\\\\\\"content\\\\\\\": s[\\\\\\\"output\\\\\\\"]},\\\\n        ]\\\\n        text = tokenizer.apply_chat_template(\\\\n            messages,\\\\n            tokenize=False,\\\\n            add_generation_prompt=False,\\\\n            enable_thinking=False,\\\\n        )\\\\n        token_len = len(tokenizer.encode(text, add_special_tokens=False))\\\\n        if token_len > max_length:\\\\n            skipped += 1\\\\n            continue\\\\n        formatted.append({\\\\\\\"text\\\\\\\": text})\\\\n        ced_scores.append(s.get(\\\\\\\"ced_score\\\\\\\", 1.0))\\\\n\\\\n    if skipped:\\\\n        logger.warning(\\\\\\\"Skipped %d samples exceeding max_length=%d\\\\\\\", skipped, max_length)\\\\n\\\\n    if ced_scores:\\\\n        logger.info(\\\\n            \\\\\\\"Prepared %d RSFT samples (CED scores: min=%.3f, max=%.3f, mean=%.3f)\\\\\\\",\\\\n            len(formatted), min(ced_scores), max(ced_scores),\\\\n            sum(ced_scores) / len(ced_scores),\\\\n        )\\\\n    return Dataset.from_list(formatted), ced_scores\\\\n\\\\n\\\\nclass WeightedSFTTrainer(SFTTrainer):\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"SFTTrainer with CED score-weighted sampling.\\\\n\\\\n    高 CED score 的样本被更频繁采样。使用 WeightedRandomSampler 实现，\\\\n    适用于单机训练。多机 DDP 场景下 Accelerate 会替换 sampler，\\\\n    此时 weighted_sampling 不生效，需改用数据集层面的过采样。\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\n    def __init__(self, *args, sample_weights=None, **kwargs):\\\\n        super().__init__(*args, **kwargs)\\\\n        self.sample_weights = sample_weights\\\\n\\\\n    def _get_train_sampler(self, dataset=None):\\\\n        if self.sample_weights is not None:\\\\n            ds = dataset if dataset is not None else self.train_dataset\\\\n            return WeightedRandomSampler(\\\\n                weights=self.sample_weights,\\\\n                num_samples=len(ds),\\\\n                replacement=True,\\\\n            )\\\\n        return super()._get_train_sampler(dataset)\\\\n\\\\n\\\\ndef main():\\\\n    parser = argparse.ArgumentParser(description=\\\\\\\"FREIGE RSFT Training\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--base_model\\\\\\\", type=str, default=DEFAULT_BASE_MODEL)\\\\n    parser.add_argument(\\\\\\\"--sft_adapter\\\\\\\", type=str, default=DEFAULT_SFT_ADAPTER,\\\\n                        help=\\\\\\\"SFT warmup adapter 路径 (merge 后训练新 LoRA)\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--rsft_data_path\\\\\\\", type=str, required=True,\\\\n                        help=\\\\\\\"CED 筛选后的 RSFT 训练数据 (JSONL)\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--output_dir\\\\\\\", type=str, required=True)\\\\n    parser.add_argument(\\\\\\\"--learning_rate\\\\\\\", type=float, default=2e-5)\\\\n    parser.add_argument(\\\\\\\"--num_epochs\\\\\\\", type=int, default=3)\\\\n    parser.add_argument(\\\\\\\"--per_device_batch_size\\\\\\\", type=int, default=4)\\\\n    parser.add_argument(\\\\\\\"--gradient_accumulation_steps\\\\\\\", type=int, default=4)\\\\n    parser.add_argument(\\\\\\\"--warmup_steps\\\\\\\", type=int, default=100)\\\\n    parser.add_argument(\\\\\\\"--save_steps\\\\\\\", type=int, default=50)\\\\n    parser.add_argument(\\\\\\\"--save_total_limit\\\\\\\", type=int, default=5)\\\\n    parser.add_argument(\\\\\\\"--max_length\\\\\\\", type=int, default=2048)\\\\n    parser.add_argument(\\\\\\\"--seed\\\\\\\", type=int, default=42)\\\\n    parser.add_argument(\\\\\\\"--wandb_project\\\\\\\", type=str, default=\\\\\\\"freige-rsft\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--wandb_run_name\\\\\\\", type=str, default=None)\\\\n    parser.add_argument(\\\\\\\"--weighted_sampling\\\\\\\", action=\\\\\\\"store_true\\\\\\\",\\\\n                        help=\\\\\\\"按 CED score 加权采样（高分样本更频繁）\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--quantize\\\\\\\", action=\\\\\\\"store_true\\\\\\\",\\\\n                        help=\\\\\\\"启用 4-bit QLoRA 量化\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--lora_rank\\\\\\\", type=int, default=64)\\\\n    parser.add_argument(\\\\\\\"--lora_alpha\\\\\\\", type=int, default=128)\\\\n    parser.add_argument(\\\\\\\"--lora_dropout\\\\\\\", type=float, default=0.05)\\\\n    parser.add_argument(\\\\\\\"--bf16\\\\\\\", action=\\\\\\\"store_true\\\\\\\", default=True)\\\\n    parser.add_argument(\\\\\\\"--deepspeed\\\\\\\", type=str, default=None,\\\\n                        help=\\\\\\\"DeepSpeed 配置文件路径\\\\\\\")\\\\n    args = parser.parse_args()\\\\n\\\\n    # W&B\\\\n    if args.wandb_project and \\\\\\\"WANDB_API_KEY\\\\\\\" in os.environ:\\\\n        os.environ[\\\\\\\"WANDB_PROJECT\\\\\\\"] = args.wandb_project\\\\n        if args.wandb_run_name:\\\\n            os.environ[\\\\\\\"WANDB_NAME\\\\\\\"] = args.wandb_run_name\\\\n\\\\n    # Tokenizer\\\\n    logger.info(\\\\\\\"Loading tokenizer: %s\\\\\\\", args.base_model)\\\\n    tokenizer = AutoTokenizer.from_pretrained(\\\\n        args.base_model, trust_remote_code=True, padding_side=\\\\\\\"right\\\\\\\",\\\\n    )\\\\n    if tokenizer.pad_token is None:\\\\n        tokenizer.pad_token = tokenizer.eos_token\\\\n\\\\n    # Data\\\\n    logger.info(\\\\\\\"Loading RSFT data: %s\\\\\\\", args.rsft_data_path)\\\\n    train_dataset, ced_scores = load_rsft_data(\\\\n        args.rsft_data_path, tokenizer, args.max_length,\\\\n    )\\\\n\\\\n    # Model: base → merge SFT adapter → new LoRA\\\\n    logger.info(\\\\\\\"Loading base model: %s\\\\\\\", args.base_model)\\\\n    local_rank = int(os.environ.get(\\\\\\\"LOCAL_RANK\\\\\\\", 0))\\\\n    model_kwargs = dict(\\\\n        trust_remote_code=True,\\\\n        attn_implementation=\\\\\\\"sdpa\\\\\\\",\\\\n        device_map={\\\\\\\"\\\\\\\": local_rank},\\\\n    )\\\\n    if args.quantize:\\\\n        logger.info(\\\\\\\"Using 4-bit QLoRA quantization\\\\\\\")\\\\n        model_kwargs[\\\\\\\"quantization_config\\\\\\\"] = BitsAndBytesConfig(\\\\n            load_in_4bit=True,\\\\n            bnb_4bit_compute_dtype=torch.bfloat16,\\\\n            bnb_4bit_quant_type=\\\\\\\"nf4\\\\\\\",\\\\n            bnb_4bit_use_double_quant=True,\\\\n        )\\\\n    else:\\\\n        model_kwargs[\\\\\\\"torch_dtype\\\\\\\"] = torch.bfloat16 if args.bf16 else torch.float16\\\\n\\\\n    model = AutoModelForCausalLM.from_pretrained(args.base_model, **model_kwargs)\\\\n\\\\n    if args.sft_adapter:\\\\n        logger.info(\\\\\\\"Merging SFT adapter: %s\\\\\\\", args.sft_adapter)\\\\n        model = PeftModel.from_pretrained(model, args.sft_adapter)\\\\n        model = model.merge_and_unload()\\\\n\\\\n    model.config.use_cache = False\\\\n    model.gradient_checkpointing_enable()\\\\n\\\\n    # Fresh LoRA for RSFT (与 SFT warmup 相同结构)\\\\n    lora_config = LoraConfig(\\\\n        task_type=TaskType.CAUSAL_LM,\\\\n        r=args.lora_rank,\\\\n        lora_alpha=args.lora_alpha,\\\\n        lora_dropout=args.lora_dropout,\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.3}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\\n\\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\\n\\n输入: JSONL，每行 {\\\"doc_id\\\": ..., \\\"input\\\": ..., \\\"output\\\": ..., \\\"ced_score\\\": ..., ...}\\n输出: QLoRA adapter checkpoint\\n依赖: transformers, trl, peft, bitsandbytes, datasets\\n\\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\\\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport os\\n\\nimport torch\\nfrom datasets import Dataset\\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\\nfrom torch.utils.data import WeightedRandomSampler\\nfrom transformers import (\\n    AutoModelForCausalLM,\\n    AutoTokenizer,\\n    BitsAndBytesConfig,\\n)\\nfrom trl import SFTConfig, SFTTrainer\\n\\nfrom freige.training.sft_trainer import SYSTEM_PROMPT\\n\\nlogging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s %(levelname)s %(message)s\\\")\\nlogger = logging.getLogger(__name__)\\n\\nDEFAULT_BASE_MODEL = \\\"/root/autodl-tmp/models/Qwen3-4B\\\"\\nDEFAULT_SFT_ADAPTER = \\\"/root/autodl-tmp/sft_output\\\"\\n\\n\\ndef load_rsft_data(data_path: str, tokenizer, max_length: int = 2048):\\n    \\\"\\\"\\\"加载 CED 筛选后的 RSFT 数据，格式化为 chat template 文本。\\n\\n    每行 JSONL 的 input 字段作为 user message，output 字段作为 assistant response，\\n    经 apply_chat_template 拼接后用于 SFT 训练。超过 max_length 的样本被跳过\\n    而非截断，避免训练在不完整 JSON 输出上。\\n\\n    Returns:\\n        (Dataset, list[float]): 训练数据集和对应的 CED scores\\n    \\\"\\\"\\\"\\n    samples = []\\n    with open(data_path) as f:\\n        for line in f:\\n            if line.strip():\\n                samples.append(json.loads(line))\\n\\n    logger.info(\\\"Loaded %d RSFT samples from %s\\\", len(samples), data_path)\\n\\n    formatted = []\\n    ced_scores = []\\n    skipped = 0\\n    for s in samples:\\n        messages = [\\n            {\\\"role\\\": \\\"system\\\", \\\"content\\\": SYSTEM_PROMPT},\\n            {\\\"role\\\": \\\"user\\\", \\\"content\\\": s[\\\"input\\\"]},\\n            {\\\"role\\\": \\\"assistant\\\", \\\"content\\\": s[\\\"output\\\"]},\\n        ]\\n        text = tokenizer.apply_chat_template(\\n            messages,\\n            tokenize=False,\\n            add_generation_prompt=False,\\n            enable_thinking=False,\\n        )\\n        token_len = len(tokenizer.encode(text, add_special_tokens=False))\\n        if token_len > max_length:\\n            skipped += 1\\n            continue\\n        formatted.append({\\\"text\\\": text})\\n        ced_scores.append(s.get(\\\"ced_score\\\", 1.0))\\n\\n    if skipped:\\n        logger.warning(\\\"Skipped %d samples exceeding max_length=%d\\\", skipped, max_length)\\n\\n    if ced_scores:\\n        logger.info(\\n            \\\"Prepared %d RSFT samples (CED scores: min=%.3f, max=%.3f, mean=%.3f)\\\",\\n            len(formatted), min(ced_scores), max(ced_scores),\\n            sum(ced_scores) / len(ced_scores),\\n        )\\n    return Dataset.from_list(formatted), ced_scores\\n\\n\\nclass WeightedSFTTrainer(SFTTrainer):\\n    \\\"\\\"\\\"SFTTrainer with CED score-weighted sampling.\\n\\n    高 CED score 的样本被更频繁采样。使用 WeightedRandomSampler 实现，\\n    适用于单机训练。多机 DDP 场景下 Accelerate 会替换 sampler，\\n    此时 weighted_sampling 不生效，需改用数据集层面的过采样。\\n    \\\"\\\"\\\"\\n\\n    def __init__(self, *args, sample_weights=None, **kwargs):\\n        super().__init__(*args, **kwargs)\\n        self.sample_weights = sample_weights\\n\\n    def _get_train_sampler(self, dataset=None):\\n        if self.sample_weights is not None:\\n            ds = dataset if dataset is not None else self.train_dataset\\n            return WeightedRandomSampler(\\n                weights=self.sample_weights,\\n                num_samples=len(ds),\\n                replacement=True,\\n            )\\n        return super()._get_train_sampler(dataset)\\n\\n\\ndef main():\\n    parser = argparse.ArgumentParser(description=\\\"FREIGE RSFT Training\\\")\\n    parser.add_argument(\\\"--base_model\\\", type=str, default=DEFAULT_BASE_MODEL)\\n    parser.add_argument(\\\"--sft_adapter\\\", type=str, default=DEFAULT_SFT_ADAPTER,\\n                        help=\\\"SFT warmup adapter 路径 (merge 后训练新 LoRA)\\\")\\n    parser.add_argument(\\\"--rsft_data_path\\\", type=str, required=True,\\n                        help=\\\"CED 筛选后的 RSFT 训练数据 (JSONL)\\\")\\n    parser.add_argument(\\\"--output_dir\\\", type=str, required=True)\\n    parser.add_argument(\\\"--learning_rate\\\", type=float, default=2e-5)\\n    parser.add_argument(\\\"--num_epochs\\\", type=int, default=3)\\n    parser.add_argument(\\\"--per_device_batch_size\\\", type=int, default=4)\\n    parser.add_argument(\\\"--gradient_accumulation_steps\\\", type=int, default=4)\\n    parser.add_argument(\\\"--warmup_steps\\\", type=int, default=100)\\n    parser.add_argument(\\\"--save_steps\\\", type=int, default=50)\\n    parser.add_argument(\\\"--save_total_limit\\\", type=int, default=5)\\n    parser.add_argument(\\\"--max_length\\\", type=int, default=2048)\\n    parser.add_argument(\\\"--seed\\\", type=int, default=42)\\n    parser.add_argument(\\\"--wandb_project\\\", type=str, default=\\\"freige-rsft\\\")\\n    parser.add_argument(\\\"--wandb_run_name\\\", type=str, default=None)\\n    parser.add_argument(\\\"--weighted_sampling\\\", action=\\\"store_true\\\",\\n                        help=\\\"按 CED score 加权采样（高分样本更频繁）\\\")\\n    parser.add_argument(\\\"--quantize\\\", action=\\\"store_true\\\",\\n                        help=\\\"启用 4-bit QLoRA 量化\\\")\\n    parser.add_argument(\\\"--lora_rank\\\", type=int, default=64)\\n    parser.add_argument(\\\"--lora_alpha\\\", type=int, default=128)\\n    parser.add_argument(\\\"--lora_dropout\\\", type=float, default=0.05)\\n    parser.add_argument(\\\"--bf16\\\", action=\\\"store_true\\\", default=True)\\n    parser.add_argument(\\\"--deepspeed\\\", type=str, default=None,\\n                        help=\\\"DeepSpeed 配置文件路径\\\")\\n    args = parser.parse_args()\\n\\n    # W&B\\n    if args.wandb_project and \\\"WANDB_API_KEY\\\" in os.environ:\\n        os.environ[\\\"WANDB_PROJECT\\\"] = args.wandb_project\\n        if args.wandb_run_name:\\n            os.environ[\\\"WANDB_NAME\\\"] = args.wandb_run_name\\n\\n    # Tokenizer\\n    logger.info(\\\"Loading tokenizer: %s\\\", args.base_model)\\n    tokenizer = AutoTokenizer.from_pretrained(\\n        args.base_model, trust_remote_code=True, padding_side=\\\"right\\\",\\n    )\\n    if tokenizer.pad_token is None:\\n        tokenizer.pad_token = tokenizer.eos_token\\n\\n    # Data\\n    logger.info(\\\"Loading RSFT data: %s\\\", args.rsft_data_path)\\n    train_dataset, ced_scores = load_rsft_data(\\n        args.rsft_data_path, tokenizer, args.max_length,\\n    )\\n\\n    # Model: base → merge SFT adapter → new LoRA\\n    logger.info(\\\"Loading base model: %s\\\", args.base_model)\\n    local_rank = int(os.environ.get(\\\"LOCAL_RANK\\\", 0))\\n    model_kwargs = dict(\\n        trust_remote_code=True,\\n        attn_implementation=\\\"sdpa\\\",\\n        device_map={\\\"\\\": local_rank},\\n    )\\n    if args.quantize:\\n        logger.info(\\\"Using 4-bit QLoRA quantization\\\")\\n        model_kwargs[\\\"quantization_config\\\"] = BitsAndBytesConfig(\\n            load_in_4bit=True,\\n            bnb_4bit_compute_dtype=torch.bfloat16,\\n            bnb_4bit_quant_type=\\\"nf4\\\",\\n            bnb_4bit_use_double_quant=True,\\n        )\\n    else:\\n        model_kwargs[\\\"torch_dtype\\\"] = torch.bfloat16 if args.bf16 else torch.float16\\n\\n    model = AutoModelForCausalLM.from_pretrained(args.base_model, **model_kwargs)\\n\\n    if args.sft_adapter:\\n        logger.info(\\\"Merging SFT adapter: %s\\\", args.sft_adapter)\\n        model = PeftModel.from_pretrained(model, args.sft_adapter)\\n        model = model.merge_and_unload()\\n\\n    model.config.use_cache = False\\n    model.gradient_checkpointing_enable()\\n\\n    # Fresh LoRA for RSFT (与 SFT warmup 相同结构)\\n    lora_config = LoraConfig(\\n        task_type=TaskType.CAUSAL_LM,\\n        r=args.lora_rank,\\n        lora_alpha=args.lora_alpha,\\n        lora_dropout=args.lora_dropout,\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.3}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 20_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01Hnv4YvQWm3B8gYeuBsKsTy`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "find /root/autodl-tmp/freige -name \"*.py\" -path \"*/eval*\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "4eb6d521-2f92-404a-9bcd-5801a0196f4e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QmnapXnLhQ8nXNRRNZHUAK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7656,
      "cache_read_input_tokens": 25000,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7656
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 21 · 2026-05-15T02:25:11.828Z_

<details><summary>↩ Tool result · `toolu_01Hnv4YvQWm3B8gYeuBsKsTy`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/freige/freige/eval/__init__.py\\n/root/autodl-tmp/freige/eval/__init__.py\\n/root/autodl-tmp/freige/eval/evaluator.py\\n/root/autodl-tmp/freige/eval/inference.py\\n/root/autodl-tmp/freige/eval/batch_eval.py\\n/root/autodl-tmp/freige/eval/find_best_checkpoint.py\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.31}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "b33d5476-6471-4feb-bebd-c159f05c6be2",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/freige/freige/eval/__init__.py\\\\n/root/autodl-tmp/freige/eval/__init__.py\\\\n/root/autodl-tmp/freige/eval/evaluator.py\\\\n/root/autodl-tmp/freige/eval/inference.py\\\\n/root/autodl-tmp/freige/eval/batch_eval.py\\\\n/root/autodl-tmp/freige/eval/find_best_checkpoint.py\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.31}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/freige/freige/eval/__init__.py\\n/root/autodl-tmp/freige/eval/__init__.py\\n/root/autodl-tmp/freige/eval/evaluator.py\\n/root/autodl-tmp/freige/eval/inference.py\\n/root/autodl-tmp/freige/eval/batch_eval.py\\n/root/autodl-tmp/freige/eval/find_best_checkpoint.py\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.31}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 22_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01JyQJjkQ87EUix3ZiZqWwfN`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "python3 -c \"import pickle; args=pickle.load(open('/root/autodl-tmp/sft_output/training_args.bin','rb')); print(f'lr={args.learning_rate}, epochs={args.num_train_epochs}, bs={args.per_device_train_batch_size}, gas={args.gradient_accumulation_steps}, warmup={args.warmup_ratio}, max_len={getattr(args,\\\"max_length\\\",\\\"N/A\\\")}')\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "a4481e2e-4fa6-40c0-8011-efa3dc90fda1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QmnapXnLhQ8nXNRRNZHUAK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7656,
      "cache_read_input_tokens": 25000,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7656
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 23 · 2026-05-15T02:25:13.694Z_

<details><summary>↩ Tool result · `toolu_01JyQJjkQ87EUix3ZiZqWwfN`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter ';' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "546d5c2d-ad65-417d-8750-50966f25c451",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"[ssh_read_only] Command blocked: Shell metacharacter ';' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter ';' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 24_

<details><summary>Logged reasoning block</summary>

```text
The python command with semicolons was blocked in read-only mode. Let me use ssh_execute for that, or restructure the command. Let me also read the evaluator module and check the training_args.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "162a1df4-793c-4f65-8349-b4df143780e7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013sjboPNKBe5p9b46GgZAUN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5270,
      "cache_read_input_tokens": 32656,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5270
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 25_

需要用 ssh_execute 读取 training_args.bin，同时读取 evaluator 和 inference 模块。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "ddd07f66-8314-42df-ae33-d06cf2572987",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013sjboPNKBe5p9b46GgZAUN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5270,
      "cache_read_input_tokens": 32656,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5270
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 26_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_execute · `toolu_01XzD4BuiQmpN4B5qpfhqmMi`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python3 -c \"\nimport pickle\nargs = pickle.load(open('/root/autodl-tmp/sft_output/training_args.bin','rb'))\nprint(f'lr={args.learning_rate}')\nprint(f'epochs={args.num_train_epochs}')\nprint(f'bs={args.per_device_train_batch_size}')\nprint(f'gas={args.gradient_accumulation_steps}')\nprint(f'warmup_ratio={args.warmup_ratio}')\nprint(f'max_length={getattr(args, \\\"max_length\\\", \\\"N/A\\\")}')\nprint(f'seed={args.seed}')\nprint(f'bf16={args.bf16}')\nprint(f'save_strategy={args.save_strategy}')\nprint(f'eval_strategy={args.eval_strategy}')\n\"\n",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "5caa5c6f-e688-4216-ba6f-c62b21dea694",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013sjboPNKBe5p9b46GgZAUN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5270,
      "cache_read_input_tokens": 32656,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5270
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 27 · 2026-05-15T02:25:22.838Z_

<details><summary>↩ Tool result · `toolu_01XzD4BuiQmpN4B5qpfhqmMi`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"Encountered a bad command exit code!\\n\\nCommand: 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python3 -c \\\"\\\\nimport pickle\\\\nargs = pickle.load(open(\\\\'/root/autodl-tmp/sft_output/training_args.bin\\\\',\\\\'rb\\\\'))\\\\nprint(f\\\\'lr={args.learning_rate}\\\\')\\\\nprint(f\\\\'epochs={args.num_train_epochs}\\\\')\\\\nprint(f\\\\'bs={args.per_device_train_batch_size}\\\\')\\\\nprint(f\\\\'gas={args.gradient_accumulation_steps}\\\\')\\\\nprint(f\\\\'warmup_ratio={args.warmup_ratio}\\\\')\\\\nprint(f\\\\'max_length={getattr(args, \\\\\\\\\\\"max_length\\\\\\\\\\\", \\\\\\\\\\\"N/A\\\\\\\\\\\")}\\\\')\\\\nprint(f\\\\'seed={args.seed}\\\\')\\\\nprint(f\\\\'bf16={args.bf16}\\\\')\\\\nprint(f\\\\'save_strategy={args.save_strategy}\\\\')\\\\nprint(f\\\\'eval_strategy={args.eval_strategy}\\\\')\\\\n\\\"\\\\n'\\n\\nExit code: 1\\n\\nStdout:\\n\\n\\n\\nStderr:\\n\\nTraceback (most recent call last):\\n  File \\\"&lt;string>\\\", line 3, in &lt;module>\\n_pickle.UnpicklingError: A load persistent id instruction was encountered, but no persistent_load function was specified.\\n\\n\", \"metadata\": {\"elapsed_seconds\": 0.46}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "6cb0e0a4-e6fa-4c65-94d5-998337f43195",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"Encountered a bad command exit code!\\\\n\\\\nCommand: 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python3 -c \\\\\\\"\\\\\\\\nimport pickle\\\\\\\\nargs = pickle.load(open(\\\\\\\\'/root/autodl-tmp/sft_output/training_args.bin\\\\\\\\',\\\\\\\\'rb\\\\\\\\'))\\\\\\\\nprint(f\\\\\\\\'lr={args.learning_rate}\\\\\\\\')\\\\\\\\nprint(f\\\\\\\\'epochs={args.num_train_epochs}\\\\\\\\')\\\\\\\\nprint(f\\\\\\\\'bs={args.per_device_train_batch_size}\\\\\\\\')\\\\\\\\nprint(f\\\\\\\\'gas={args.gradient_accumulation_steps}\\\\\\\\')\\\\\\\\nprint(f\\\\\\\\'warmup_ratio={args.warmup_ratio}\\\\\\\\')\\\\\\\\nprint(f\\\\\\\\'max_length={getattr(args, \\\\\\\\\\\\\\\\\\\\\\\"max_length\\\\\\\\\\\\\\\\\\\\\\\", \\\\\\\\\\\\\\\\\\\\\\\"N/A\\\\\\\\\\\\\\\\\\\\\\\")}\\\\\\\\')\\\\\\\\nprint(f\\\\\\\\'seed={args.seed}\\\\\\\\')\\\\\\\\nprint(f\\\\\\\\'bf16={args.bf16}\\\\\\\\')\\\\\\\\nprint(f\\\\\\\\'save_strategy={args.save_strategy}\\\\\\\\')\\\\\\\\nprint(f\\\\\\\\'eval_strategy={args.eval_strategy}\\\\\\\\')\\\\\\\\n\\\\\\\"\\\\\\\\n'\\\\n\\\\nExit code: 1\\\\n\\\\nStdout:\\\\n\\\\n\\\\n\\\\nStderr:\\\\n\\\\nTraceback (most recent call last):\\\\n  File \\\\\\\"&lt;string>\\\\\\\", line 3, in &lt;module>\\\\n_pickle.UnpicklingError: A load persistent id instruction was encountered, but no persistent_load function was specified.\\\\n\\\\n\\\", \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.46}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"Encountered a bad command exit code!\\n\\nCommand: 'source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && python3 -c \\\"\\\\nimport pickle\\\\nargs = pickle.load(open(\\\\'/root/autodl-tmp/sft_output/training_args.bin\\\\',\\\\'rb\\\\'))\\\\nprint(f\\\\'lr={args.learning_rate}\\\\')\\\\nprint(f\\\\'epochs={args.num_train_epochs}\\\\')\\\\nprint(f\\\\'bs={args.per_device_train_batch_size}\\\\')\\\\nprint(f\\\\'gas={args.gradient_accumulation_steps}\\\\')\\\\nprint(f\\\\'warmup_ratio={args.warmup_ratio}\\\\')\\\\nprint(f\\\\'max_length={getattr(args, \\\\\\\\\\\"max_length\\\\\\\\\\\", \\\\\\\\\\\"N/A\\\\\\\\\\\")}\\\\')\\\\nprint(f\\\\'seed={args.seed}\\\\')\\\\nprint(f\\\\'bf16={args.bf16}\\\\')\\\\nprint(f\\\\'save_strategy={args.save_strategy}\\\\')\\\\nprint(f\\\\'eval_strategy={args.eval_strategy}\\\\')\\\\n\\\"\\\\n'\\n\\nExit code: 1\\n\\nStdout:\\n\\n\\n\\nStderr:\\n\\nTraceback (most recent call last):\\n  File \\\"&lt;string>\\\", line 3, in &lt;module>\\n_pickle.UnpicklingError: A load persistent id instruction was encountered, but no persistent_load function was specified.\\n\\n\", \"metadata\": {\"elapsed_seconds\": 0.46}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 28_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01KekCTqqya6iY7gBng8JgpW`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "cat /root/autodl-tmp/freige/eval/evaluator.py",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "6103bd9a-c47d-4a28-8992-c814e302d7d2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013sjboPNKBe5p9b46GgZAUN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5270,
      "cache_read_input_tokens": 32656,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5270
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 29_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01RfUVXH9hpPHT7KQeijaAX5`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "cat /root/autodl-tmp/freige/eval/inference.py",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "f30e9232-29bd-4b06-a9d2-6ccc8bd65f25",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_013sjboPNKBe5p9b46GgZAUN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5270,
      "cache_read_input_tokens": 32656,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5270
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 30 · 2026-05-15T02:25:23.653Z_

<details><summary>↩ Tool result · `toolu_01KekCTqqya6iY7gBng8JgpW`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"DocRED 关系抽取评测模块。\\n\\n指标:\\n  - F1 / Ign-F1: 关系三元组级别 micro-F1，Ign-F1 排除训练集中出现的三元组\\n  - Evi-F1: 对正确预测的三元组，计算 evidence 句子级 F1\\n  - EDCR: Evidence Distractor Citation Rate，预测 evidence 中非 gold 的比例\\n\\n输入: 预测列表 + gold 标注列表（每个元素为文档级标注）\\n输出: 指标字典\\n\\\"\\\"\\\"\\n\\nimport json\\nimport logging\\nfrom collections import defaultdict\\nfrom typing import Optional\\n\\nlogger = logging.getLogger(__name__)\\n\\n\\ndef _triple_key(doc_id: str, head: str, tail: str, relation: str) -> tuple:\\n    return (doc_id, head.lower().strip(), tail.lower().strip(), relation.lower().strip())\\n\\n\\nclass DocREDEvaluator:\\n    \\\"\\\"\\\"DocRED 评测器。\\n\\n    Args:\\n        train_triples: 训练集中的三元组集合，用于计算 Ign-F1。\\n                       每个元素为 (doc_title, head_name, tail_name, relation)。\\n                       为 None 时 Ign-F1 = F1。\\n    \\\"\\\"\\\"\\n\\n    def __init__(self, train_triples: Optional[set[tuple]] = None):\\n        self.train_triples = train_triples or set()\\n\\n    @classmethod\\n    def from_train_file(cls, train_path: str) -> \\\"DocREDEvaluator\\\":\\n        \\\"\\\"\\\"从训练集 JSON 文件构建 evaluator，自动提取训练集三元组。\\\"\\\"\\\"\\n        from freige.data.docred_processor import DOCRED_REL_INFO\\n\\n        with open(train_path) as f:\\n            train_data = json.load(f)\\n\\n        train_triples = set()\\n        for doc in train_data:\\n            doc_id = doc.get(\\\"title\\\", \\\"\\\")\\n            vertex_set = doc[\\\"vertexSet\\\"]\\n            for label in doc.get(\\\"labels\\\", []):\\n                h_name = vertex_set[label[\\\"h\\\"]][0][\\\"name\\\"]\\n                t_name = vertex_set[label[\\\"t\\\"]][0][\\\"name\\\"]\\n                rel_name = DOCRED_REL_INFO.get(label[\\\"r\\\"], label[\\\"r\\\"])\\n                train_triples.add(\\n                    _triple_key(doc_id, h_name, t_name, rel_name)\\n                )\\n\\n        logger.info(\\\"Loaded %d training triples for Ign-F1\\\", len(train_triples))\\n        return cls(train_triples=train_triples)\\n\\n    def compute_f1(\\n        self,\\n        predictions: list[dict],\\n        gold: list[dict],\\n    ) -> dict:\\n        \\\"\\\"\\\"计算 F1 和 Ign-F1。\\\"\\\"\\\"\\n        pred_set = set()\\n        for p in predictions:\\n            pred_set.add(_triple_key(\\n                p[\\\"doc_id\\\"], p[\\\"head\\\"], p[\\\"tail\\\"], p[\\\"relation\\\"]\\n            ))\\n\\n        gold_set = set()\\n        for g in gold:\\n            gold_set.add(_triple_key(\\n                g[\\\"doc_id\\\"], g[\\\"head\\\"], g[\\\"tail\\\"], g[\\\"relation\\\"]\\n            ))\\n\\n        tp = pred_set & gold_set\\n        precision = len(tp) / len(pred_set) if pred_set else 0.0\\n        recall = len(tp) / len(gold_set) if gold_set else 0.0\\n        f1 = 2 * precision * recall / (precision + recall) if (precision + recall) > 0 else 0.0\\n\\n        pred_ign = pred_set - self.train_triples\\n        gold_ign = gold_set - self.train_triples\\n        tp_ign = pred_ign & gold_ign\\n        ign_prec = len(tp_ign) / len(pred_ign) if pred_ign else 0.0\\n        ign_rec = len(tp_ign) / len(gold_ign) if gold_ign else 0.0\\n        ign_f1 = (\\n            2 * ign_prec * ign_rec / (ign_prec + ign_rec)\\n            if (ign_prec + ign_rec) > 0 else 0.0\\n        )\\n\\n        return {\\n            \\\"precision\\\": precision,\\n            \\\"recall\\\": recall,\\n            \\\"f1\\\": f1,\\n            \\\"ign_precision\\\": ign_prec,\\n            \\\"ign_recall\\\": ign_rec,\\n            \\\"ign_f1\\\": ign_f1,\\n            \\\"tp\\\": len(tp),\\n            \\\"pred_count\\\": len(pred_set),\\n            \\\"gold_count\\\": len(gold_set),\\n        }\\n\\n    def compute_evi_f1(\\n        self,\\n        predictions: list[dict],\\n        gold: list[dict],\\n    ) -> dict:\\n        \\\"\\\"\\\"计算 Evidence F1（句子级）。\\\"\\\"\\\"\\n        gold_map = {}\\n        for g in gold:\\n            key = _triple_key(g[\\\"doc_id\\\"], g[\\\"head\\\"], g[\\\"tail\\\"], g[\\\"relation\\\"])\\n            gold_map.setdefault(key, set()).update(g.get(\\\"evidence\\\", []))\\n\\n        total_tp = 0\\n        total_pred = 0\\n        total_gold = 0\\n        n_evaluated = 0\\n\\n        for p in predictions:\\n            key = _triple_key(p[\\\"doc_id\\\"], p[\\\"head\\\"], p[\\\"tail\\\"], p[\\\"relation\\\"])\\n            if key not in gold_map:\\n                continue\\n\\n            pred_evi = set(p.get(\\\"evidence\\\", []))\\n            gold_evi = gold_map[key]\\n\\n            tp = len(pred_evi & gold\\n\\n... [截断: 输出过长，省略 3969 字符] ...\\n\\n       except json.JSONDecodeError:\\n                    return False\\n            return False\\n\\n    @staticmethod\\n    def _parse_raw_json_list(text: str) -> Optional[list]:\\n        try:\\n            obj = json.loads(text)\\n            if isinstance(obj, list):\\n                return obj\\n        except json.JSONDecodeError:\\n            start = text.find(\\\"[\\\")\\n            end = text.rfind(\\\"]\\\") + 1\\n            if start >= 0 and end > start:\\n                try:\\n                    obj = json.loads(text[start:end])\\n                    if isinstance(obj, list):\\n                        return obj\\n                except json.JSONDecodeError:\\n                    pass\\n        return None\\n\\n    def evaluate(\\n        self,\\n        predictions: list[dict],\\n        gold: list[dict],\\n        raw_outputs: Optional[list[dict]] = None,\\n    ) -> dict:\\n        \\\"\\\"\\\"运行所有评测指标。\\\"\\\"\\\"\\n        f1_metrics = self.compute_f1(predictions, gold)\\n        evi_metrics = self.compute_evi_f1(predictions, gold)\\n        edcr_metrics = self.compute_edcr(predictions, gold)\\n        result = {**f1_metrics, **evi_metrics, **edcr_metrics}\\n        if raw_outputs is not None:\\n            result.update(self.compute_format_compliance(raw_outputs))\\n        return result\\n\\n\\n\\n\\ndef _try_parse_json_list(text):\\n    try:\\n        obj = json.loads(text)\\n        if isinstance(obj, list):\\n            return obj\\n    except json.JSONDecodeError:\\n        pass\\n    return None\\n\\n\\ndef _repair_truncated_json(text):\\n    stripped = text.rstrip().rstrip(\\\",\\\")\\n    for suffix in [\\\"]\\\", \\\"}]\\\", '\\\"' + '}' + ']', \\\"null}]\\\"]:\\n        result = _try_parse_json_list(stripped + suffix)\\n        if result is not None:\\n            return result\\n\\n    last_brace = text.rfind(\\\"}\\\")\\n    if last_brace > 0:\\n        result = _try_parse_json_list(text[: last_brace + 1] + \\\"]\\\")\\n        if result is not None:\\n            return result\\n\\n    return None\\n\\n\\ndef _get_field(d, *keys):\\n    for k in keys:\\n        if k in d:\\n            return d[k]\\n    return None\\n\\n\\ndef _normalize_triples(triples):\\n    results = []\\n    for t in triples:\\n        if not isinstance(t, dict):\\n            continue\\n        head = _get_field(t, \\\"head\\\", \\\"head_entity\\\")\\n        tail = _get_field(t, \\\"tail\\\", \\\"tail_entity\\\")\\n        relation = _get_field(t, \\\"relation\\\", \\\"type\\\", \\\"label\\\")\\n        if head is None or tail is None or relation is None:\\n            continue\\n        evidence = _get_field(t, \\\"evidence\\\", \\\"sentence_ids\\\") or []\\n        results.append({\\n            \\\"head\\\": str(head),\\n            \\\"relation\\\": str(relation).lower().strip(),\\n            \\\"tail\\\": str(tail),\\n            \\\"evidence\\\": evidence,\\n        })\\n    return results\\n\\n\\ndef parse_model_output(output_text: str) -> tuple[list[dict], bool]:\\n    text = output_text.strip()\\n\\n    parsed = _try_parse_json_list(text)\\n    if parsed is not None:\\n        return _normalize_triples(parsed), True\\n\\n    start = text.find(\\\"[\\\")\\n    if start >= 0:\\n        end = text.rfind(\\\"]\\\")\\n        if end > start:\\n            parsed = _try_parse_json_list(text[start : end + 1])\\n            if parsed is not None:\\n                return _normalize_triples(parsed), True\\n\\n        repaired = _repair_truncated_json(text[start:])\\n        if repaired is not None:\\n            return _normalize_triples(repaired), True\\n\\n    return [], False\\n\\ndef gold_from_docred(\\n    docred_data: list[dict],\\n) -> list[dict]:\\n    \\\"\\\"\\\"将 DocRED 原始数据转为评测用 gold 格式。\\\"\\\"\\\"\\n    from freige.data.docred_processor import DOCRED_REL_INFO\\n\\n    gold = []\\n    for doc in docred_data:\\n        doc_id = doc.get(\\\"title\\\", \\\"\\\")\\n        vertex_set = doc[\\\"vertexSet\\\"]\\n        for label in doc.get(\\\"labels\\\", []):\\n            h_name = vertex_set[label[\\\"h\\\"]][0][\\\"name\\\"]\\n            t_name = vertex_set[label[\\\"t\\\"]][0][\\\"name\\\"]\\n            gold.append({\\n                \\\"doc_id\\\": doc_id,\\n                \\\"head\\\": h_name,\\n                \\\"tail\\\": t_name,\\n                \\\"relation\\\": DOCRED_REL_INFO.get(label[\\\"r\\\"], label[\\\"r\\\"]),\\n                \\\"evidence\\\": label.get(\\\"evidence\\\", []),\\n            })\\n    return gold\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.77}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "add9486c-a5a1-42e4-8b31-be0026074e93",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\"\\\\\\\"\\\\\\\"DocRED 关系抽取评测模块。\\\\n\\\\n指标:\\\\n  - F1 / Ign-F1: 关系三元组级别 micro-F1，Ign-F1 排除训练集中出现的三元组\\\\n  - Evi-F1: 对正确预测的三元组，计算 evidence 句子级 F1\\\\n  - EDCR: Evidence Distractor Citation Rate，预测 evidence 中非 gold 的比例\\\\n\\\\n输入: 预测列表 + gold 标注列表（每个元素为文档级标注）\\\\n输出: 指标字典\\\\n\\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\nimport json\\\\nimport logging\\\\nfrom collections import defaultdict\\\\nfrom typing import Optional\\\\n\\\\nlogger = logging.getLogger(__name__)\\\\n\\\\n\\\\ndef _triple_key(doc_id: str, head: str, tail: str, relation: str) -> tuple:\\\\n    return (doc_id, head.lower().strip(), tail.lower().strip(), relation.lower().strip())\\\\n\\\\n\\\\nclass DocREDEvaluator:\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"DocRED 评测器。\\\\n\\\\n    Args:\\\\n        train_triples: 训练集中的三元组集合，用于计算 Ign-F1。\\\\n                       每个元素为 (doc_title, head_name, tail_name, relation)。\\\\n                       为 None 时 Ign-F1 = F1。\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\n    def __init__(self, train_triples: Optional[set[tuple]] = None):\\\\n        self.train_triples = train_triples or set()\\\\n\\\\n    @classmethod\\\\n    def from_train_file(cls, train_path: str) -> \\\\\\\"DocREDEvaluator\\\\\\\":\\\\n        \\\\\\\"\\\\\\\"\\\\\\\"从训练集 JSON 文件构建 evaluator，自动提取训练集三元组。\\\\\\\"\\\\\\\"\\\\\\\"\\\\n        from freige.data.docred_processor import DOCRED_REL_INFO\\\\n\\\\n        with open(train_path) as f:\\\\n            train_data = json.load(f)\\\\n\\\\n        train_triples = set()\\\\n        for doc in train_data:\\\\n            doc_id = doc.get(\\\\\\\"title\\\\\\\", \\\\\\\"\\\\\\\")\\\\n            vertex_set = doc[\\\\\\\"vertexSet\\\\\\\"]\\\\n            for label in doc.get(\\\\\\\"labels\\\\\\\", []):\\\\n                h_name = vertex_set[label[\\\\\\\"h\\\\\\\"]][0][\\\\\\\"name\\\\\\\"]\\\\n                t_name = vertex_set[label[\\\\\\\"t\\\\\\\"]][0][\\\\\\\"name\\\\\\\"]\\\\n                rel_name = DOCRED_REL_INFO.get(label[\\\\\\\"r\\\\\\\"], label[\\\\\\\"r\\\\\\\"])\\\\n                train_triples.add(\\\\n                    _triple_key(doc_id, h_name, t_name, rel_name)\\\\n                )\\\\n\\\\n        logger.info(\\\\\\\"Loaded %d training triples for Ign-F1\\\\\\\", len(train_triples))\\\\n        return cls(train_triples=train_triples)\\\\n\\\\n    def compute_f1(\\\\n        self,\\\\n        predictions: list[dict],\\\\n        gold: list[dict],\\\\n    ) -> dict:\\\\n        \\\\\\\"\\\\\\\"\\\\\\\"计算 F1 和 Ign-F1。\\\\\\\"\\\\\\\"\\\\\\\"\\\\n        pred_set = set()\\\\n        for p in predictions:\\\\n            pred_set.add(_triple_key(\\\\n                p[\\\\\\\"doc_id\\\\\\\"], p[\\\\\\\"head\\\\\\\"], p[\\\\\\\"tail\\\\\\\"], p[\\\\\\\"relation\\\\\\\"]\\\\n            ))\\\\n\\\\n        gold_set = set()\\\\n        for g in gold:\\\\n            gold_set.add(_triple_key(\\\\n                g[\\\\\\\"doc_id\\\\\\\"], g[\\\\\\\"head\\\\\\\"], g[\\\\\\\"tail\\\\\\\"], g[\\\\\\\"relation\\\\\\\"]\\\\n            ))\\\\n\\\\n        tp = pred_set & gold_set\\\\n        precision = len(tp) / len(pred_set) if pred_set else 0.0\\\\n        recall = len(tp) / len(gold_set) if gold_set else 0.0\\\\n        f1 = 2 * precision * recall / (precision + recall) if (precision + recall) > 0 else 0.0\\\\n\\\\n        pred_ign = pred_set - self.train_triples\\\\n        gold_ign = gold_set - self.train_triples\\\\n        tp_ign = pred_ign & gold_ign\\\\n        ign_prec = len(tp_ign) / len(pred_ign) if pred_ign else 0.0\\\\n        ign_rec = len(tp_ign) / len(gold_ign) if gold_ign else 0.0\\\\n        ign_f1 = (\\\\n            2 * ign_prec * ign_rec / (ign_prec + ign_rec)\\\\n            if (ign_prec + ign_rec) > 0 else 0.0\\\\n        )\\\\n\\\\n        return {\\\\n            \\\\\\\"precision\\\\\\\": precision,\\\\n            \\\\\\\"recall\\\\\\\": recall,\\\\n            \\\\\\\"f1\\\\\\\": f1,\\\\n            \\\\\\\"ign_precision\\\\\\\": ign_prec,\\\\n            \\\\\\\"ign_recall\\\\\\\": ign_rec,\\\\n            \\\\\\\"ign_f1\\\\\\\": ign_f1,\\\\n            \\\\\\\"tp\\\\\\\": len(tp),\\\\n            \\\\\\\"pred_count\\\\\\\": len(pred_set),\\\\n            \\\\\\\"gold_count\\\\\\\": len(gold_set),\\\\n        }\\\\n\\\\n    def compute_evi_f1(\\\\n        self,\\\\n        predictions: list[dict],\\\\n        gold: list[dict],\\\\n    ) -> dict:\\\\n        \\\\\\\"\\\\\\\"\\\\\\\"计算 Evidence F1（句子级）。\\\\\\\"\\\\\\\"\\\\\\\"\\\\n        gold_map = {}\\\\n        for g in gold:\\\\n            key = _triple_key(g[\\\\\\\"doc_id\\\\\\\"], g[\\\\\\\"head\\\\\\\"], g[\\\\\\\"tail\\\\\\\"], g[\\\\\\\"relation\\\\\\\"])\\\\n            gold_map.setdefault(key, set()).update(g.get(\\\\\\\"evidence\\\\\\\", []))\\\\n\\\\n        total_tp = 0\\\\n        total_pred = 0\\\\n        total_gold = 0\\\\n        n_evaluated = 0\\\\n\\\\n        for p in predictions:\\\\n            key = _triple_key(p[\\\\\\\"doc_id\\\\\\\"], p[\\\\\\\"head\\\\\\\"], p[\\\\\\\"tail\\\\\\\"], p[\\\\\\\"relation\\\\\\\"])\\\\n            if key not in gold_map:\\\\n                continue\\\\n\\\\n            pred_evi = set(p.get(\\\\\\\"evidence\\\\\\\", []))\\\\n            gold_evi = gold_map[key]\\\\n\\\\n            tp = len(pred_evi & gold\\\\n\\\\n... [截断: 输出过长，省略 3969 字符] ...\\\\n\\\\n       except json.JSONDecodeError:\\\\n                    return False\\\\n            return False\\\\n\\\\n    @staticmethod\\\\n    def _parse_raw_json_list(text: str) -> Optional[list]:\\\\n        try:\\\\n            obj = json.loads(text)\\\\n            if isinstance(obj, list):\\\\n                return obj\\\\n        except json.JSONDecodeError:\\\\n            start = text.find(\\\\\\\"[\\\\\\\")\\\\n            end = text.rfind(\\\\\\\"]\\\\\\\") + 1\\\\n            if start >= 0 and end > start:\\\\n                try:\\\\n                    obj = json.loads(text[start:end])\\\\n                    if isinstance(obj, list):\\\\n                        return obj\\\\n                except json.JSONDecodeError:\\\\n                    pass\\\\n        return None\\\\n\\\\n    def evaluate(\\\\n        self,\\\\n        predictions: list[dict],\\\\n        gold: list[dict],\\\\n        raw_outputs: Optional[list[dict]] = None,\\\\n    ) -> dict:\\\\n        \\\\\\\"\\\\\\\"\\\\\\\"运行所有评测指标。\\\\\\\"\\\\\\\"\\\\\\\"\\\\n        f1_metrics = self.compute_f1(predictions, gold)\\\\n        evi_metrics = self.compute_evi_f1(predictions, gold)\\\\n        edcr_metrics = self.compute_edcr(predictions, gold)\\\\n        result = {**f1_metrics, **evi_metrics, **edcr_metrics}\\\\n        if raw_outputs is not None:\\\\n            result.update(self.compute_format_compliance(raw_outputs))\\\\n        return result\\\\n\\\\n\\\\n\\\\n\\\\ndef _try_parse_json_list(text):\\\\n    try:\\\\n        obj = json.loads(text)\\\\n        if isinstance(obj, list):\\\\n            return obj\\\\n    except json.JSONDecodeError:\\\\n        pass\\\\n    return None\\\\n\\\\n\\\\ndef _repair_truncated_json(text):\\\\n    stripped = text.rstrip().rstrip(\\\\\\\",\\\\\\\")\\\\n    for suffix in [\\\\\\\"]\\\\\\\", \\\\\\\"}]\\\\\\\", '\\\\\\\"' + '}' + ']', \\\\\\\"null}]\\\\\\\"]:\\\\n        result = _try_parse_json_list(stripped + suffix)\\\\n        if result is not None:\\\\n            return result\\\\n\\\\n    last_brace = text.rfind(\\\\\\\"}\\\\\\\")\\\\n    if last_brace > 0:\\\\n        result = _try_parse_json_list(text[: last_brace + 1] + \\\\\\\"]\\\\\\\")\\\\n        if result is not None:\\\\n            return result\\\\n\\\\n    return None\\\\n\\\\n\\\\ndef _get_field(d, *keys):\\\\n    for k in keys:\\\\n        if k in d:\\\\n            return d[k]\\\\n    return None\\\\n\\\\n\\\\ndef _normalize_triples(triples):\\\\n    results = []\\\\n    for t in triples:\\\\n        if not isinstance(t, dict):\\\\n            continue\\\\n        head = _get_field(t, \\\\\\\"head\\\\\\\", \\\\\\\"head_entity\\\\\\\")\\\\n        tail = _get_field(t, \\\\\\\"tail\\\\\\\", \\\\\\\"tail_entity\\\\\\\")\\\\n        relation = _get_field(t, \\\\\\\"relation\\\\\\\", \\\\\\\"type\\\\\\\", \\\\\\\"label\\\\\\\")\\\\n        if head is None or tail is None or relation is None:\\\\n            continue\\\\n        evidence = _get_field(t, \\\\\\\"evidence\\\\\\\", \\\\\\\"sentence_ids\\\\\\\") or []\\\\n        results.append({\\\\n            \\\\\\\"head\\\\\\\": str(head),\\\\n            \\\\\\\"relation\\\\\\\": str(relation).lower().strip(),\\\\n            \\\\\\\"tail\\\\\\\": str(tail),\\\\n            \\\\\\\"evidence\\\\\\\": evidence,\\\\n        })\\\\n    return results\\\\n\\\\n\\\\ndef parse_model_output(output_text: str) -> tuple[list[dict], bool]:\\\\n    text = output_text.strip()\\\\n\\\\n    parsed = _try_parse_json_list(text)\\\\n    if parsed is not None:\\\\n        return _normalize_triples(parsed), True\\\\n\\\\n    start = text.find(\\\\\\\"[\\\\\\\")\\\\n    if start >= 0:\\\\n        end = text.rfind(\\\\\\\"]\\\\\\\")\\\\n        if end > start:\\\\n            parsed = _try_parse_json_list(text[start : end + 1])\\\\n            if parsed is not None:\\\\n                return _normalize_triples(parsed), True\\\\n\\\\n        repaired = _repair_truncated_json(text[start:])\\\\n        if repaired is not None:\\\\n            return _normalize_triples(repaired), True\\\\n\\\\n    return [], False\\\\n\\\\ndef gold_from_docred(\\\\n    docred_data: list[dict],\\\\n) -> list[dict]:\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"将 DocRED 原始数据转为评测用 gold 格式。\\\\\\\"\\\\\\\"\\\\\\\"\\\\n    from freige.data.docred_processor import DOCRED_REL_INFO\\\\n\\\\n    gold = []\\\\n    for doc in docred_data:\\\\n        doc_id = doc.get(\\\\\\\"title\\\\\\\", \\\\\\\"\\\\\\\")\\\\n        vertex_set = doc[\\\\\\\"vertexSet\\\\\\\"]\\\\n        for label in doc.get(\\\\\\\"labels\\\\\\\", []):\\\\n            h_name = vertex_set[label[\\\\\\\"h\\\\\\\"]][0][\\\\\\\"name\\\\\\\"]\\\\n            t_name = vertex_set[label[\\\\\\\"t\\\\\\\"]][0][\\\\\\\"name\\\\\\\"]\\\\n            gold.append({\\\\n                \\\\\\\"doc_id\\\\\\\": doc_id,\\\\n                \\\\\\\"head\\\\\\\": h_name,\\\\n                \\\\\\\"tail\\\\\\\": t_name,\\\\n                \\\\\\\"relation\\\\\\\": DOCRED_REL_INFO.get(label[\\\\\\\"r\\\\\\\"], label[\\\\\\\"r\\\\\\\"]),\\\\n                \\\\\\\"evidence\\\\\\\": label.get(\\\\\\\"evidence\\\\\\\", []),\\\\n            })\\\\n    return gold\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.77}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"DocRED 关系抽取评测模块。\\n\\n指标:\\n  - F1 / Ign-F1: 关系三元组级别 micro-F1，Ign-F1 排除训练集中出现的三元组\\n  - Evi-F1: 对正确预测的三元组，计算 evidence 句子级 F1\\n  - EDCR: Evidence Distractor Citation Rate，预测 evidence 中非 gold 的比例\\n\\n输入: 预测列表 + gold 标注列表（每个元素为文档级标注）\\n输出: 指标字典\\n\\\"\\\"\\\"\\n\\nimport json\\nimport logging\\nfrom collections import defaultdict\\nfrom typing import Optional\\n\\nlogger = logging.getLogger(__name__)\\n\\n\\ndef _triple_key(doc_id: str, head: str, tail: str, relation: str) -> tuple:\\n    return (doc_id, head.lower().strip(), tail.lower().strip(), relation.lower().strip())\\n\\n\\nclass DocREDEvaluator:\\n    \\\"\\\"\\\"DocRED 评测器。\\n\\n    Args:\\n        train_triples: 训练集中的三元组集合，用于计算 Ign-F1。\\n                       每个元素为 (doc_title, head_name, tail_name, relation)。\\n                       为 None 时 Ign-F1 = F1。\\n    \\\"\\\"\\\"\\n\\n    def __init__(self, train_triples: Optional[set[tuple]] = None):\\n        self.train_triples = train_triples or set()\\n\\n    @classmethod\\n    def from_train_file(cls, train_path: str) -> \\\"DocREDEvaluator\\\":\\n        \\\"\\\"\\\"从训练集 JSON 文件构建 evaluator，自动提取训练集三元组。\\\"\\\"\\\"\\n        from freige.data.docred_processor import DOCRED_REL_INFO\\n\\n        with open(train_path) as f:\\n            train_data = json.load(f)\\n\\n        train_triples = set()\\n        for doc in train_data:\\n            doc_id = doc.get(\\\"title\\\", \\\"\\\")\\n            vertex_set = doc[\\\"vertexSet\\\"]\\n            for label in doc.get(\\\"labels\\\", []):\\n                h_name = vertex_set[label[\\\"h\\\"]][0][\\\"name\\\"]\\n                t_name = vertex_set[label[\\\"t\\\"]][0][\\\"name\\\"]\\n                rel_name = DOCRED_REL_INFO.get(label[\\\"r\\\"], label[\\\"r\\\"])\\n                train_triples.add(\\n                    _triple_key(doc_id, h_name, t_name, rel_name)\\n                )\\n\\n        logger.info(\\\"Loaded %d training triples for Ign-F1\\\", len(train_triples))\\n        return cls(train_triples=train_triples)\\n\\n    def compute_f1(\\n        self,\\n        predictions: list[dict],\\n        gold: list[dict],\\n    ) -> dict:\\n        \\\"\\\"\\\"计算 F1 和 Ign-F1。\\\"\\\"\\\"\\n        pred_set = set()\\n        for p in predictions:\\n            pred_set.add(_triple_key(\\n                p[\\\"doc_id\\\"], p[\\\"head\\\"], p[\\\"tail\\\"], p[\\\"relation\\\"]\\n            ))\\n\\n        gold_set = set()\\n        for g in gold:\\n            gold_set.add(_triple_key(\\n                g[\\\"doc_id\\\"], g[\\\"head\\\"], g[\\\"tail\\\"], g[\\\"relation\\\"]\\n            ))\\n\\n        tp = pred_set & gold_set\\n        precision = len(tp) / len(pred_set) if pred_set else 0.0\\n        recall = len(tp) / len(gold_set) if gold_set else 0.0\\n        f1 = 2 * precision * recall / (precision + recall) if (precision + recall) > 0 else 0.0\\n\\n        pred_ign = pred_set - self.train_triples\\n        gold_ign = gold_set - self.train_triples\\n        tp_ign = pred_ign & gold_ign\\n        ign_prec = len(tp_ign) / len(pred_ign) if pred_ign else 0.0\\n        ign_rec = len(tp_ign) / len(gold_ign) if gold_ign else 0.0\\n        ign_f1 = (\\n            2 * ign_prec * ign_rec / (ign_prec + ign_rec)\\n            if (ign_prec + ign_rec) > 0 else 0.0\\n        )\\n\\n        return {\\n            \\\"precision\\\": precision,\\n            \\\"recall\\\": recall,\\n            \\\"f1\\\": f1,\\n            \\\"ign_precision\\\": ign_prec,\\n            \\\"ign_recall\\\": ign_rec,\\n            \\\"ign_f1\\\": ign_f1,\\n            \\\"tp\\\": len(tp),\\n            \\\"pred_count\\\": len(pred_set),\\n            \\\"gold_count\\\": len(gold_set),\\n        }\\n\\n    def compute_evi_f1(\\n        self,\\n        predictions: list[dict],\\n        gold: list[dict],\\n    ) -> dict:\\n        \\\"\\\"\\\"计算 Evidence F1（句子级）。\\\"\\\"\\\"\\n        gold_map = {}\\n        for g in gold:\\n            key = _triple_key(g[\\\"doc_id\\\"], g[\\\"head\\\"], g[\\\"tail\\\"], g[\\\"relation\\\"])\\n            gold_map.setdefault(key, set()).update(g.get(\\\"evidence\\\", []))\\n\\n        total_tp = 0\\n        total_pred = 0\\n        total_gold = 0\\n        n_evaluated = 0\\n\\n        for p in predictions:\\n            key = _triple_key(p[\\\"doc_id\\\"], p[\\\"head\\\"], p[\\\"tail\\\"], p[\\\"relation\\\"])\\n            if key not in gold_map:\\n                continue\\n\\n            pred_evi = set(p.get(\\\"evidence\\\", []))\\n            gold_evi = gold_map[key]\\n\\n            tp = len(pred_evi & gold\\n\\n... [截断: 输出过长，省略 3969 字符] ...\\n\\n       except json.JSONDecodeError:\\n                    return False\\n            return False\\n\\n    @staticmethod\\n    def _parse_raw_json_list(text: str) -> Optional[list]:\\n        try:\\n            obj = json.loads(text)\\n            if isinstance(obj, list):\\n                return obj\\n        except json.JSONDecodeError:\\n            start = text.find(\\\"[\\\")\\n            end = text.rfind(\\\"]\\\") + 1\\n            if start >= 0 and end > start:\\n                try:\\n                    obj = json.loads(text[start:end])\\n                    if isinstance(obj, list):\\n                        return obj\\n                except json.JSONDecodeError:\\n                    pass\\n        return None\\n\\n    def evaluate(\\n        self,\\n        predictions: list[dict],\\n        gold: list[dict],\\n        raw_outputs: Optional[list[dict]] = None,\\n    ) -> dict:\\n        \\\"\\\"\\\"运行所有评测指标。\\\"\\\"\\\"\\n        f1_metrics = self.compute_f1(predictions, gold)\\n        evi_metrics = self.compute_evi_f1(predictions, gold)\\n        edcr_metrics = self.compute_edcr(predictions, gold)\\n        result = {**f1_metrics, **evi_metrics, **edcr_metrics}\\n        if raw_outputs is not None:\\n            result.update(self.compute_format_compliance(raw_outputs))\\n        return result\\n\\n\\n\\n\\ndef _try_parse_json_list(text):\\n    try:\\n        obj = json.loads(text)\\n        if isinstance(obj, list):\\n            return obj\\n    except json.JSONDecodeError:\\n        pass\\n    return None\\n\\n\\ndef _repair_truncated_json(text):\\n    stripped = text.rstrip().rstrip(\\\",\\\")\\n    for suffix in [\\\"]\\\", \\\"}]\\\", '\\\"' + '}' + ']', \\\"null}]\\\"]:\\n        result = _try_parse_json_list(stripped + suffix)\\n        if result is not None:\\n            return result\\n\\n    last_brace = text.rfind(\\\"}\\\")\\n    if last_brace > 0:\\n        result = _try_parse_json_list(text[: last_brace + 1] + \\\"]\\\")\\n        if result is not None:\\n            return result\\n\\n    return None\\n\\n\\ndef _get_field(d, *keys):\\n    for k in keys:\\n        if k in d:\\n            return d[k]\\n    return None\\n\\n\\ndef _normalize_triples(triples):\\n    results = []\\n    for t in triples:\\n        if not isinstance(t, dict):\\n            continue\\n        head = _get_field(t, \\\"head\\\", \\\"head_entity\\\")\\n        tail = _get_field(t, \\\"tail\\\", \\\"tail_entity\\\")\\n        relation = _get_field(t, \\\"relation\\\", \\\"type\\\", \\\"label\\\")\\n        if head is None or tail is None or relation is None:\\n            continue\\n        evidence = _get_field(t, \\\"evidence\\\", \\\"sentence_ids\\\") or []\\n        results.append({\\n            \\\"head\\\": str(head),\\n            \\\"relation\\\": str(relation).lower().strip(),\\n            \\\"tail\\\": str(tail),\\n            \\\"evidence\\\": evidence,\\n        })\\n    return results\\n\\n\\ndef parse_model_output(output_text: str) -> tuple[list[dict], bool]:\\n    text = output_text.strip()\\n\\n    parsed = _try_parse_json_list(text)\\n    if parsed is not None:\\n        return _normalize_triples(parsed), True\\n\\n    start = text.find(\\\"[\\\")\\n    if start >= 0:\\n        end = text.rfind(\\\"]\\\")\\n        if end > start:\\n            parsed = _try_parse_json_list(text[start : end + 1])\\n            if parsed is not None:\\n                return _normalize_triples(parsed), True\\n\\n        repaired = _repair_truncated_json(text[start:])\\n        if repaired is not None:\\n            return _normalize_triples(repaired), True\\n\\n    return [], False\\n\\ndef gold_from_docred(\\n    docred_data: list[dict],\\n) -> list[dict]:\\n    \\\"\\\"\\\"将 DocRED 原始数据转为评测用 gold 格式。\\\"\\\"\\\"\\n    from freige.data.docred_processor import DOCRED_REL_INFO\\n\\n    gold = []\\n    for doc in docred_data:\\n        doc_id = doc.get(\\\"title\\\", \\\"\\\")\\n        vertex_set = doc[\\\"vertexSet\\\"]\\n        for label in doc.get(\\\"labels\\\", []):\\n            h_name = vertex_set[label[\\\"h\\\"]][0][\\\"name\\\"]\\n            t_name = vertex_set[label[\\\"t\\\"]][0][\\\"name\\\"]\\n            gold.append({\\n                \\\"doc_id\\\": doc_id,\\n                \\\"head\\\": h_name,\\n                \\\"tail\\\": t_name,\\n                \\\"relation\\\": DOCRED_REL_INFO.get(label[\\\"r\\\"], label[\\\"r\\\"]),\\n                \\\"evidence\\\": label.get(\\\"evidence\\\", []),\\n            })\\n    return gold\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.77}}"
    }
  }
}
```

</details>

---

### Tool result

_source line 31 · 2026-05-15T02:25:24.036Z_

<details><summary>↩ Tool result · `toolu_01RfUVXH9hpPHT7KQeijaAX5`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"推理+评测完整流程: 加载 Qwen3-4B + LoRA adapter → 批量推理 → 解析输出 → 计算 F1/Evi-F1/EDCR。\\n\\n输入:\\n  - base model (Qwen3-4B) + 可选 LoRA adapter (SFT/GRPO checkpoint)\\n  - DocRED JSON 数据目录 (含 dev.json, train_annotated.json)\\n\\n输出 (保存到 --output_dir):\\n  - metrics.json: F1, Ign-F1, Evi-F1, EDCR, format_compliance_rate, n_truncated 等\\n  - predictions.json: 每个文档的详细预测 (doc_id, raw_output, parsed_triples, gold_triples, truncated, format_ok)\\n\\n依赖: transformers, peft, bitsandbytes, torch, tqdm\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport time\\nfrom pathlib import Path\\n\\nimport torch\\nfrom peft import PeftModel\\nfrom transformers import AutoModelForCausalLM, AutoTokenizer, BitsAndBytesConfig\\nfrom tqdm import tqdm\\n\\nfrom freige.data.docred_processor import DocREDProcessor, SPLIT_FILENAMES\\nfrom freige.eval.evaluator import DocREDEvaluator, gold_from_docred, parse_model_output\\n\\nlogging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s %(levelname)s %(message)s\\\")\\nlogger = logging.getLogger(__name__)\\n\\nSYSTEM_PROMPT = (\\n    \\\"You are an information extraction model. Given a document with numbered sentences \\\"\\n    \\\"and a list of entities, extract all relation triples. For each triple, provide the \\\"\\n    \\\"head entity, relation type, tail entity, and the sentence IDs that serve as evidence. \\\"\\n    \\\"Output as a JSON list.\\\"\\n)\\n\\n\\n# ---------------------------------------------------------------------------\\n# A. 模型加载\\n# ---------------------------------------------------------------------------\\n\\ndef load_model_and_tokenizer(model_path, adapter_path=None, sft_adapter_path=None, quantize=True):\\n    \\\"\\\"\\\"加载 Qwen3-4B + 可选 LoRA adapter (4-bit QLoRA)。\\n\\n    Args:\\n        model_path: base model 路径\\n        adapter_path: LoRA adapter 路径（SFT 或 GRPO checkpoint），None 则不加载\\n    Returns:\\n        (model, tokenizer)\\n    \\\"\\\"\\\"\\n    logger.info(\\\"Loading tokenizer: %s\\\", model_path)\\n    tokenizer = AutoTokenizer.from_pretrained(\\n        model_path,\\n        trust_remote_code=True,\\n        padding_side=\\\"left\\\",\\n    )\\n    if tokenizer.pad_token is None:\\n        tokenizer.pad_token = tokenizer.eos_token\\n\\n    logger.info(\\\"Loading model: %s\\\", model_path)\\n    model_kwargs = dict(\\n        trust_remote_code=True,\\n        attn_implementation=\\\"sdpa\\\",\\n        device_map=\\\"auto\\\",\\n    )\\n    if quantize:\\n        model_kwargs[\\\"quantization_config\\\"] = BitsAndBytesConfig(\\n            load_in_4bit=True,\\n            bnb_4bit_compute_dtype=torch.bfloat16,\\n            bnb_4bit_quant_type=\\\"nf4\\\",\\n            bnb_4bit_use_double_quant=True,\\n        )\\n    else:\\n        model_kwargs[\\\"torch_dtype\\\"] = torch.bfloat16\\n\\n    model = AutoModelForCausalLM.from_pretrained(model_path, **model_kwargs)\\n\\n    if sft_adapter_path:\\n        logger.info(\\\"Loading & merging SFT adapter: %s\\\", sft_adapter_path)\\n        model = PeftModel.from_pretrained(model, sft_adapter_path)\\n        model = model.merge_and_unload()\\n\\n    if adapter_path:\\n        logger.info(\\\"Loading LoRA adapter: %s\\\", adapter_path)\\n        model = PeftModel.from_pretrained(model, adapter_path)\\n\\n    model.eval()\\n    return model, tokenizer\\n\\n\\n# ---------------------------------------------------------------------------\\n# B. Prompt 构造\\n# ---------------------------------------------------------------------------\\n\\ndef build_prompt(tokenizer, instruction, input_text):\\n    \\\"\\\"\\\"构建与训练一致的 Qwen3 chat prompt（enable_thinking=False）。\\\"\\\"\\\"\\n    messages = [\\n        {\\\"role\\\": \\\"system\\\", \\\"content\\\": SYSTEM_PROMPT},\\n        {\\\"role\\\": \\\"user\\\", \\\"content\\\": f\\\"{instruction}\\\\n\\\\n{input_text}\\\"},\\n    ]\\n    return tokenizer.apply_chat_template(\\n        messages,\\n        tokenize=False,\\n        add_generation_prompt=True,\\n        enable_thinking=False,\\n    )\\n\\n\\ndef prepare_eval_data(data_dir, split, tokenizer):\\n    \\\"\\\"\\\"加载 DocRED 数据，构建 eval prompts、gold 标注和 per-doc gold map。\\\"\\\"\\\"\\n    processor = DocREDProcessor(data_dir=data_dir)\\n    samples = processor.process(split)\\n    groups = processor.group_by_document(samples)\\n\\n    eval_items = []\\n    for doc_id, doc_samples in groups.items():\\n        sft_sample = processor.format_sf\\n\\n... [截断: 输出过长，省略 5467 字符] ...\\n\\nrse.BooleanOptionalAction,\\n                        default=True, help=\\\"4-bit NF4 quantization（default: on）\\\")\\n    args = parser.parse_args()\\n\\n    torch.manual_seed(args.seed)\\n    if torch.cuda.is_available():\\n        torch.cuda.manual_seed_all(args.seed)\\n\\n    output_dir = Path(args.output_dir)\\n    output_dir.mkdir(parents=True, exist_ok=True)\\n\\n    # 自动检测 model_path 是 adapter 还是完整模型\\n    adapter_config = Path(args.model_path) / \\\"adapter_config.json\\\"\\n    if adapter_config.exists():\\n        base_model_path = args.base_model\\n        adapter_path = args.model_path\\n        logger.info(\\\"Detected adapter at %s, base: %s\\\", adapter_path, base_model_path)\\n    else:\\n        base_model_path = args.model_path\\n        adapter_path = None\\n        logger.info(\\\"Full model: %s (no adapter)\\\", base_model_path)\\n\\n    model, tokenizer = load_model_and_tokenizer(\\n        base_model_path, adapter_path, sft_adapter_path=args.sft_adapter,\\n        quantize=args.quantize,\\n    )\\n    eval_items, gold, gold_by_doc = prepare_eval_data(\\n        args.data_path, args.split, tokenizer\\n    )\\n\\n    t0 = time.time()\\n    raw_results = run_inference(\\n        model, tokenizer, eval_items, args.batch_size, args.max_new_tokens\\n    )\\n    elapsed = time.time() - t0\\n    logger.info(\\\"Inference: %.1fs (%.2f s/doc)\\\", elapsed, elapsed / max(len(eval_items), 1))\\n\\n    # 展平为 evaluator 格式\\n    all_predictions = []\\n    raw_outputs_for_eval = []\\n    for r in raw_results:\\n        doc_id = r[\\\"doc_id\\\"]\\n        for triple in r[\\\"parsed_triples\\\"]:\\n            all_predictions.append({\\n                \\\"doc_id\\\": doc_id,\\n                \\\"head\\\": triple[\\\"head\\\"],\\n                \\\"tail\\\": triple[\\\"tail\\\"],\\n                \\\"relation\\\": triple[\\\"relation\\\"],\\n                \\\"evidence\\\": triple.get(\\\"evidence\\\", []),\\n            })\\n        raw_outputs_for_eval.append({\\\"doc_id\\\": doc_id, \\\"raw_text\\\": r[\\\"raw_output\\\"]})\\n\\n    metrics = evaluate(all_predictions, gold, raw_outputs_for_eval, args.data_path, args.split)\\n\\n    n_truncated = sum(1 for r in raw_results if r[\\\"truncated\\\"])\\n    n_format_ok = sum(1 for r in raw_results if r[\\\"format_ok\\\"])\\n    n_total = len(raw_results)\\n    metrics[\\\"n_documents\\\"] = n_total\\n    metrics[\\\"n_predictions\\\"] = len(all_predictions)\\n    metrics[\\\"n_truncated\\\"] = n_truncated\\n    metrics[\\\"n_format_ok\\\"] = n_format_ok\\n    metrics[\\\"format_ok_rate\\\"] = n_format_ok / n_total if n_total else 0.0\\n    metrics[\\\"inference_time_seconds\\\"] = round(elapsed, 1)\\n    metrics[\\\"config\\\"] = vars(args)\\n\\n    # 保存 metrics.json\\n    metrics_path = output_dir / \\\"metrics.json\\\"\\n    with open(metrics_path, \\\"w\\\") as f:\\n        json.dump(metrics, f, indent=2, ensure_ascii=False)\\n    logger.info(\\\"Metrics → %s\\\", metrics_path)\\n\\n    # 保存 predictions.json（每文档详细信息）\\n    detailed = []\\n    for r in raw_results:\\n        doc_id = r[\\\"doc_id\\\"]\\n        doc_gold = gold_by_doc.get(doc_id, [])\\n        gold_triples = [\\n            {\\\"head\\\": g[\\\"head\\\"], \\\"tail\\\": g[\\\"tail\\\"], \\\"relation\\\": g[\\\"relation\\\"],\\n             \\\"evidence\\\": g.get(\\\"evidence\\\", [])}\\n            for g in doc_gold\\n        ]\\n        detailed.append({\\n            \\\"doc_id\\\": doc_id,\\n            \\\"raw_output\\\": r[\\\"raw_output\\\"],\\n            \\\"parsed_triples\\\": r[\\\"parsed_triples\\\"],\\n            \\\"gold_triples\\\": gold_triples,\\n            \\\"truncated\\\": r[\\\"truncated\\\"],\\n            \\\"format_ok\\\": r[\\\"format_ok\\\"],\\n        })\\n\\n    pred_path = output_dir / \\\"predictions.json\\\"\\n    with open(pred_path, \\\"w\\\") as f:\\n        json.dump(detailed, f, indent=2, ensure_ascii=False)\\n    logger.info(\\\"Predictions → %s\\\", pred_path)\\n\\n    # 控制台汇总\\n    print(\\\"\\\\n\\\" + \\\"=\\\" * 50)\\n    print(f\\\"  F1:          {metrics['f1']:.4f}\\\")\\n    print(f\\\"  Ign-F1:      {metrics['ign_f1']:.4f}\\\")\\n    print(f\\\"  Evi-F1:      {metrics['evi_f1']:.4f}\\\")\\n    print(f\\\"  EDCR:        {metrics.get('edcr', 0):.4f}\\\")\\n    print(f\\\"  Format OK:   {n_format_ok}/{n_total} ({metrics['format_ok_rate']:.1%})\\\")\\n    print(f\\\"  Truncated:   {n_truncated}/{n_total}\\\")\\n    print(f\\\"  Predictions: {len(all_predictions)}\\\")\\n    print(\\\"=\\\" * 50)\\n\\n\\nif __name__ == \\\"__main__\\\":\\n    main()\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.37}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "1347f498-0c4c-4fd2-abee-8763143712d1",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\"\\\\\\\"\\\\\\\"推理+评测完整流程: 加载 Qwen3-4B + LoRA adapter → 批量推理 → 解析输出 → 计算 F1/Evi-F1/EDCR。\\\\n\\\\n输入:\\\\n  - base model (Qwen3-4B) + 可选 LoRA adapter (SFT/GRPO checkpoint)\\\\n  - DocRED JSON 数据目录 (含 dev.json, train_annotated.json)\\\\n\\\\n输出 (保存到 --output_dir):\\\\n  - metrics.json: F1, Ign-F1, Evi-F1, EDCR, format_compliance_rate, n_truncated 等\\\\n  - predictions.json: 每个文档的详细预测 (doc_id, raw_output, parsed_triples, gold_triples, truncated, format_ok)\\\\n\\\\n依赖: transformers, peft, bitsandbytes, torch, tqdm\\\\n\\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\nimport argparse\\\\nimport json\\\\nimport logging\\\\nimport time\\\\nfrom pathlib import Path\\\\n\\\\nimport torch\\\\nfrom peft import PeftModel\\\\nfrom transformers import AutoModelForCausalLM, AutoTokenizer, BitsAndBytesConfig\\\\nfrom tqdm import tqdm\\\\n\\\\nfrom freige.data.docred_processor import DocREDProcessor, SPLIT_FILENAMES\\\\nfrom freige.eval.evaluator import DocREDEvaluator, gold_from_docred, parse_model_output\\\\n\\\\nlogging.basicConfig(level=logging.INFO, format=\\\\\\\"%(asctime)s %(levelname)s %(message)s\\\\\\\")\\\\nlogger = logging.getLogger(__name__)\\\\n\\\\nSYSTEM_PROMPT = (\\\\n    \\\\\\\"You are an information extraction model. Given a document with numbered sentences \\\\\\\"\\\\n    \\\\\\\"and a list of entities, extract all relation triples. For each triple, provide the \\\\\\\"\\\\n    \\\\\\\"head entity, relation type, tail entity, and the sentence IDs that serve as evidence. \\\\\\\"\\\\n    \\\\\\\"Output as a JSON list.\\\\\\\"\\\\n)\\\\n\\\\n\\\\n# ---------------------------------------------------------------------------\\\\n# A. 模型加载\\\\n# ---------------------------------------------------------------------------\\\\n\\\\ndef load_model_and_tokenizer(model_path, adapter_path=None, sft_adapter_path=None, quantize=True):\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"加载 Qwen3-4B + 可选 LoRA adapter (4-bit QLoRA)。\\\\n\\\\n    Args:\\\\n        model_path: base model 路径\\\\n        adapter_path: LoRA adapter 路径（SFT 或 GRPO checkpoint），None 则不加载\\\\n    Returns:\\\\n        (model, tokenizer)\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"\\\\n    logger.info(\\\\\\\"Loading tokenizer: %s\\\\\\\", model_path)\\\\n    tokenizer = AutoTokenizer.from_pretrained(\\\\n        model_path,\\\\n        trust_remote_code=True,\\\\n        padding_side=\\\\\\\"left\\\\\\\",\\\\n    )\\\\n    if tokenizer.pad_token is None:\\\\n        tokenizer.pad_token = tokenizer.eos_token\\\\n\\\\n    logger.info(\\\\\\\"Loading model: %s\\\\\\\", model_path)\\\\n    model_kwargs = dict(\\\\n        trust_remote_code=True,\\\\n        attn_implementation=\\\\\\\"sdpa\\\\\\\",\\\\n        device_map=\\\\\\\"auto\\\\\\\",\\\\n    )\\\\n    if quantize:\\\\n        model_kwargs[\\\\\\\"quantization_config\\\\\\\"] = BitsAndBytesConfig(\\\\n            load_in_4bit=True,\\\\n            bnb_4bit_compute_dtype=torch.bfloat16,\\\\n            bnb_4bit_quant_type=\\\\\\\"nf4\\\\\\\",\\\\n            bnb_4bit_use_double_quant=True,\\\\n        )\\\\n    else:\\\\n        model_kwargs[\\\\\\\"torch_dtype\\\\\\\"] = torch.bfloat16\\\\n\\\\n    model = AutoModelForCausalLM.from_pretrained(model_path, **model_kwargs)\\\\n\\\\n    if sft_adapter_path:\\\\n        logger.info(\\\\\\\"Loading & merging SFT adapter: %s\\\\\\\", sft_adapter_path)\\\\n        model = PeftModel.from_pretrained(model, sft_adapter_path)\\\\n        model = model.merge_and_unload()\\\\n\\\\n    if adapter_path:\\\\n        logger.info(\\\\\\\"Loading LoRA adapter: %s\\\\\\\", adapter_path)\\\\n        model = PeftModel.from_pretrained(model, adapter_path)\\\\n\\\\n    model.eval()\\\\n    return model, tokenizer\\\\n\\\\n\\\\n# ---------------------------------------------------------------------------\\\\n# B. Prompt 构造\\\\n# ---------------------------------------------------------------------------\\\\n\\\\ndef build_prompt(tokenizer, instruction, input_text):\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"构建与训练一致的 Qwen3 chat prompt（enable_thinking=False）。\\\\\\\"\\\\\\\"\\\\\\\"\\\\n    messages = [\\\\n        {\\\\\\\"role\\\\\\\": \\\\\\\"system\\\\\\\", \\\\\\\"content\\\\\\\": SYSTEM_PROMPT},\\\\n        {\\\\\\\"role\\\\\\\": \\\\\\\"user\\\\\\\", \\\\\\\"content\\\\\\\": f\\\\\\\"{instruction}\\\\\\\\n\\\\\\\\n{input_text}\\\\\\\"},\\\\n    ]\\\\n    return tokenizer.apply_chat_template(\\\\n        messages,\\\\n        tokenize=False,\\\\n        add_generation_prompt=True,\\\\n        enable_thinking=False,\\\\n    )\\\\n\\\\n\\\\ndef prepare_eval_data(data_dir, split, tokenizer):\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"加载 DocRED 数据，构建 eval prompts、gold 标注和 per-doc gold map。\\\\\\\"\\\\\\\"\\\\\\\"\\\\n    processor = DocREDProcessor(data_dir=data_dir)\\\\n    samples = processor.process(split)\\\\n    groups = processor.group_by_document(samples)\\\\n\\\\n    eval_items = []\\\\n    for doc_id, doc_samples in groups.items():\\\\n        sft_sample = processor.format_sf\\\\n\\\\n... [截断: 输出过长，省略 5467 字符] ...\\\\n\\\\nrse.BooleanOptionalAction,\\\\n                        default=True, help=\\\\\\\"4-bit NF4 quantization（default: on）\\\\\\\")\\\\n    args = parser.parse_args()\\\\n\\\\n    torch.manual_seed(args.seed)\\\\n    if torch.cuda.is_available():\\\\n        torch.cuda.manual_seed_all(args.seed)\\\\n\\\\n    output_dir = Path(args.output_dir)\\\\n    output_dir.mkdir(parents=True, exist_ok=True)\\\\n\\\\n    # 自动检测 model_path 是 adapter 还是完整模型\\\\n    adapter_config = Path(args.model_path) / \\\\\\\"adapter_config.json\\\\\\\"\\\\n    if adapter_config.exists():\\\\n        base_model_path = args.base_model\\\\n        adapter_path = args.model_path\\\\n        logger.info(\\\\\\\"Detected adapter at %s, base: %s\\\\\\\", adapter_path, base_model_path)\\\\n    else:\\\\n        base_model_path = args.model_path\\\\n        adapter_path = None\\\\n        logger.info(\\\\\\\"Full model: %s (no adapter)\\\\\\\", base_model_path)\\\\n\\\\n    model, tokenizer = load_model_and_tokenizer(\\\\n        base_model_path, adapter_path, sft_adapter_path=args.sft_adapter,\\\\n        quantize=args.quantize,\\\\n    )\\\\n    eval_items, gold, gold_by_doc = prepare_eval_data(\\\\n        args.data_path, args.split, tokenizer\\\\n    )\\\\n\\\\n    t0 = time.time()\\\\n    raw_results = run_inference(\\\\n        model, tokenizer, eval_items, args.batch_size, args.max_new_tokens\\\\n    )\\\\n    elapsed = time.time() - t0\\\\n    logger.info(\\\\\\\"Inference: %.1fs (%.2f s/doc)\\\\\\\", elapsed, elapsed / max(len(eval_items), 1))\\\\n\\\\n    # 展平为 evaluator 格式\\\\n    all_predictions = []\\\\n    raw_outputs_for_eval = []\\\\n    for r in raw_results:\\\\n        doc_id = r[\\\\\\\"doc_id\\\\\\\"]\\\\n        for triple in r[\\\\\\\"parsed_triples\\\\\\\"]:\\\\n            all_predictions.append({\\\\n                \\\\\\\"doc_id\\\\\\\": doc_id,\\\\n                \\\\\\\"head\\\\\\\": triple[\\\\\\\"head\\\\\\\"],\\\\n                \\\\\\\"tail\\\\\\\": triple[\\\\\\\"tail\\\\\\\"],\\\\n                \\\\\\\"relation\\\\\\\": triple[\\\\\\\"relation\\\\\\\"],\\\\n                \\\\\\\"evidence\\\\\\\": triple.get(\\\\\\\"evidence\\\\\\\", []),\\\\n            })\\\\n        raw_outputs_for_eval.append({\\\\\\\"doc_id\\\\\\\": doc_id, \\\\\\\"raw_text\\\\\\\": r[\\\\\\\"raw_output\\\\\\\"]})\\\\n\\\\n    metrics = evaluate(all_predictions, gold, raw_outputs_for_eval, args.data_path, args.split)\\\\n\\\\n    n_truncated = sum(1 for r in raw_results if r[\\\\\\\"truncated\\\\\\\"])\\\\n    n_format_ok = sum(1 for r in raw_results if r[\\\\\\\"format_ok\\\\\\\"])\\\\n    n_total = len(raw_results)\\\\n    metrics[\\\\\\\"n_documents\\\\\\\"] = n_total\\\\n    metrics[\\\\\\\"n_predictions\\\\\\\"] = len(all_predictions)\\\\n    metrics[\\\\\\\"n_truncated\\\\\\\"] = n_truncated\\\\n    metrics[\\\\\\\"n_format_ok\\\\\\\"] = n_format_ok\\\\n    metrics[\\\\\\\"format_ok_rate\\\\\\\"] = n_format_ok / n_total if n_total else 0.0\\\\n    metrics[\\\\\\\"inference_time_seconds\\\\\\\"] = round(elapsed, 1)\\\\n    metrics[\\\\\\\"config\\\\\\\"] = vars(args)\\\\n\\\\n    # 保存 metrics.json\\\\n    metrics_path = output_dir / \\\\\\\"metrics.json\\\\\\\"\\\\n    with open(metrics_path, \\\\\\\"w\\\\\\\") as f:\\\\n        json.dump(metrics, f, indent=2, ensure_ascii=False)\\\\n    logger.info(\\\\\\\"Metrics → %s\\\\\\\", metrics_path)\\\\n\\\\n    # 保存 predictions.json（每文档详细信息）\\\\n    detailed = []\\\\n    for r in raw_results:\\\\n        doc_id = r[\\\\\\\"doc_id\\\\\\\"]\\\\n        doc_gold = gold_by_doc.get(doc_id, [])\\\\n        gold_triples = [\\\\n            {\\\\\\\"head\\\\\\\": g[\\\\\\\"head\\\\\\\"], \\\\\\\"tail\\\\\\\": g[\\\\\\\"tail\\\\\\\"], \\\\\\\"relation\\\\\\\": g[\\\\\\\"relation\\\\\\\"],\\\\n             \\\\\\\"evidence\\\\\\\": g.get(\\\\\\\"evidence\\\\\\\", [])}\\\\n            for g in doc_gold\\\\n        ]\\\\n        detailed.append({\\\\n            \\\\\\\"doc_id\\\\\\\": doc_id,\\\\n            \\\\\\\"raw_output\\\\\\\": r[\\\\\\\"raw_output\\\\\\\"],\\\\n            \\\\\\\"parsed_triples\\\\\\\": r[\\\\\\\"parsed_triples\\\\\\\"],\\\\n            \\\\\\\"gold_triples\\\\\\\": gold_triples,\\\\n            \\\\\\\"truncated\\\\\\\": r[\\\\\\\"truncated\\\\\\\"],\\\\n            \\\\\\\"format_ok\\\\\\\": r[\\\\\\\"format_ok\\\\\\\"],\\\\n        })\\\\n\\\\n    pred_path = output_dir / \\\\\\\"predictions.json\\\\\\\"\\\\n    with open(pred_path, \\\\\\\"w\\\\\\\") as f:\\\\n        json.dump(detailed, f, indent=2, ensure_ascii=False)\\\\n    logger.info(\\\\\\\"Predictions → %s\\\\\\\", pred_path)\\\\n\\\\n    # 控制台汇总\\\\n    print(\\\\\\\"\\\\\\\\n\\\\\\\" + \\\\\\\"=\\\\\\\" * 50)\\\\n    print(f\\\\\\\"  F1:          {metrics['f1']:.4f}\\\\\\\")\\\\n    print(f\\\\\\\"  Ign-F1:      {metrics['ign_f1']:.4f}\\\\\\\")\\\\n    print(f\\\\\\\"  Evi-F1:      {metrics['evi_f1']:.4f}\\\\\\\")\\\\n    print(f\\\\\\\"  EDCR:        {metrics.get('edcr', 0):.4f}\\\\\\\")\\\\n    print(f\\\\\\\"  Format OK:   {n_format_ok}/{n_total} ({metrics['format_ok_rate']:.1%})\\\\\\\")\\\\n    print(f\\\\\\\"  Truncated:   {n_truncated}/{n_total}\\\\\\\")\\\\n    print(f\\\\\\\"  Predictions: {len(all_predictions)}\\\\\\\")\\\\n    print(\\\\\\\"=\\\\\\\" * 50)\\\\n\\\\n\\\\nif __name__ == \\\\\\\"__main__\\\\\\\":\\\\n    main()\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.37}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"推理+评测完整流程: 加载 Qwen3-4B + LoRA adapter → 批量推理 → 解析输出 → 计算 F1/Evi-F1/EDCR。\\n\\n输入:\\n  - base model (Qwen3-4B) + 可选 LoRA adapter (SFT/GRPO checkpoint)\\n  - DocRED JSON 数据目录 (含 dev.json, train_annotated.json)\\n\\n输出 (保存到 --output_dir):\\n  - metrics.json: F1, Ign-F1, Evi-F1, EDCR, format_compliance_rate, n_truncated 等\\n  - predictions.json: 每个文档的详细预测 (doc_id, raw_output, parsed_triples, gold_triples, truncated, format_ok)\\n\\n依赖: transformers, peft, bitsandbytes, torch, tqdm\\n\\\"\\\"\\\"\\n\\nimport argparse\\nimport json\\nimport logging\\nimport time\\nfrom pathlib import Path\\n\\nimport torch\\nfrom peft import PeftModel\\nfrom transformers import AutoModelForCausalLM, AutoTokenizer, BitsAndBytesConfig\\nfrom tqdm import tqdm\\n\\nfrom freige.data.docred_processor import DocREDProcessor, SPLIT_FILENAMES\\nfrom freige.eval.evaluator import DocREDEvaluator, gold_from_docred, parse_model_output\\n\\nlogging.basicConfig(level=logging.INFO, format=\\\"%(asctime)s %(levelname)s %(message)s\\\")\\nlogger = logging.getLogger(__name__)\\n\\nSYSTEM_PROMPT = (\\n    \\\"You are an information extraction model. Given a document with numbered sentences \\\"\\n    \\\"and a list of entities, extract all relation triples. For each triple, provide the \\\"\\n    \\\"head entity, relation type, tail entity, and the sentence IDs that serve as evidence. \\\"\\n    \\\"Output as a JSON list.\\\"\\n)\\n\\n\\n# ---------------------------------------------------------------------------\\n# A. 模型加载\\n# ---------------------------------------------------------------------------\\n\\ndef load_model_and_tokenizer(model_path, adapter_path=None, sft_adapter_path=None, quantize=True):\\n    \\\"\\\"\\\"加载 Qwen3-4B + 可选 LoRA adapter (4-bit QLoRA)。\\n\\n    Args:\\n        model_path: base model 路径\\n        adapter_path: LoRA adapter 路径（SFT 或 GRPO checkpoint），None 则不加载\\n    Returns:\\n        (model, tokenizer)\\n    \\\"\\\"\\\"\\n    logger.info(\\\"Loading tokenizer: %s\\\", model_path)\\n    tokenizer = AutoTokenizer.from_pretrained(\\n        model_path,\\n        trust_remote_code=True,\\n        padding_side=\\\"left\\\",\\n    )\\n    if tokenizer.pad_token is None:\\n        tokenizer.pad_token = tokenizer.eos_token\\n\\n    logger.info(\\\"Loading model: %s\\\", model_path)\\n    model_kwargs = dict(\\n        trust_remote_code=True,\\n        attn_implementation=\\\"sdpa\\\",\\n        device_map=\\\"auto\\\",\\n    )\\n    if quantize:\\n        model_kwargs[\\\"quantization_config\\\"] = BitsAndBytesConfig(\\n            load_in_4bit=True,\\n            bnb_4bit_compute_dtype=torch.bfloat16,\\n            bnb_4bit_quant_type=\\\"nf4\\\",\\n            bnb_4bit_use_double_quant=True,\\n        )\\n    else:\\n        model_kwargs[\\\"torch_dtype\\\"] = torch.bfloat16\\n\\n    model = AutoModelForCausalLM.from_pretrained(model_path, **model_kwargs)\\n\\n    if sft_adapter_path:\\n        logger.info(\\\"Loading & merging SFT adapter: %s\\\", sft_adapter_path)\\n        model = PeftModel.from_pretrained(model, sft_adapter_path)\\n        model = model.merge_and_unload()\\n\\n    if adapter_path:\\n        logger.info(\\\"Loading LoRA adapter: %s\\\", adapter_path)\\n        model = PeftModel.from_pretrained(model, adapter_path)\\n\\n    model.eval()\\n    return model, tokenizer\\n\\n\\n# ---------------------------------------------------------------------------\\n# B. Prompt 构造\\n# ---------------------------------------------------------------------------\\n\\ndef build_prompt(tokenizer, instruction, input_text):\\n    \\\"\\\"\\\"构建与训练一致的 Qwen3 chat prompt（enable_thinking=False）。\\\"\\\"\\\"\\n    messages = [\\n        {\\\"role\\\": \\\"system\\\", \\\"content\\\": SYSTEM_PROMPT},\\n        {\\\"role\\\": \\\"user\\\", \\\"content\\\": f\\\"{instruction}\\\\n\\\\n{input_text}\\\"},\\n    ]\\n    return tokenizer.apply_chat_template(\\n        messages,\\n        tokenize=False,\\n        add_generation_prompt=True,\\n        enable_thinking=False,\\n    )\\n\\n\\ndef prepare_eval_data(data_dir, split, tokenizer):\\n    \\\"\\\"\\\"加载 DocRED 数据，构建 eval prompts、gold 标注和 per-doc gold map。\\\"\\\"\\\"\\n    processor = DocREDProcessor(data_dir=data_dir)\\n    samples = processor.process(split)\\n    groups = processor.group_by_document(samples)\\n\\n    eval_items = []\\n    for doc_id, doc_samples in groups.items():\\n        sft_sample = processor.format_sf\\n\\n... [截断: 输出过长，省略 5467 字符] ...\\n\\nrse.BooleanOptionalAction,\\n                        default=True, help=\\\"4-bit NF4 quantization（default: on）\\\")\\n    args = parser.parse_args()\\n\\n    torch.manual_seed(args.seed)\\n    if torch.cuda.is_available():\\n        torch.cuda.manual_seed_all(args.seed)\\n\\n    output_dir = Path(args.output_dir)\\n    output_dir.mkdir(parents=True, exist_ok=True)\\n\\n    # 自动检测 model_path 是 adapter 还是完整模型\\n    adapter_config = Path(args.model_path) / \\\"adapter_config.json\\\"\\n    if adapter_config.exists():\\n        base_model_path = args.base_model\\n        adapter_path = args.model_path\\n        logger.info(\\\"Detected adapter at %s, base: %s\\\", adapter_path, base_model_path)\\n    else:\\n        base_model_path = args.model_path\\n        adapter_path = None\\n        logger.info(\\\"Full model: %s (no adapter)\\\", base_model_path)\\n\\n    model, tokenizer = load_model_and_tokenizer(\\n        base_model_path, adapter_path, sft_adapter_path=args.sft_adapter,\\n        quantize=args.quantize,\\n    )\\n    eval_items, gold, gold_by_doc = prepare_eval_data(\\n        args.data_path, args.split, tokenizer\\n    )\\n\\n    t0 = time.time()\\n    raw_results = run_inference(\\n        model, tokenizer, eval_items, args.batch_size, args.max_new_tokens\\n    )\\n    elapsed = time.time() - t0\\n    logger.info(\\\"Inference: %.1fs (%.2f s/doc)\\\", elapsed, elapsed / max(len(eval_items), 1))\\n\\n    # 展平为 evaluator 格式\\n    all_predictions = []\\n    raw_outputs_for_eval = []\\n    for r in raw_results:\\n        doc_id = r[\\\"doc_id\\\"]\\n        for triple in r[\\\"parsed_triples\\\"]:\\n            all_predictions.append({\\n                \\\"doc_id\\\": doc_id,\\n                \\\"head\\\": triple[\\\"head\\\"],\\n                \\\"tail\\\": triple[\\\"tail\\\"],\\n                \\\"relation\\\": triple[\\\"relation\\\"],\\n                \\\"evidence\\\": triple.get(\\\"evidence\\\", []),\\n            })\\n        raw_outputs_for_eval.append({\\\"doc_id\\\": doc_id, \\\"raw_text\\\": r[\\\"raw_output\\\"]})\\n\\n    metrics = evaluate(all_predictions, gold, raw_outputs_for_eval, args.data_path, args.split)\\n\\n    n_truncated = sum(1 for r in raw_results if r[\\\"truncated\\\"])\\n    n_format_ok = sum(1 for r in raw_results if r[\\\"format_ok\\\"])\\n    n_total = len(raw_results)\\n    metrics[\\\"n_documents\\\"] = n_total\\n    metrics[\\\"n_predictions\\\"] = len(all_predictions)\\n    metrics[\\\"n_truncated\\\"] = n_truncated\\n    metrics[\\\"n_format_ok\\\"] = n_format_ok\\n    metrics[\\\"format_ok_rate\\\"] = n_format_ok / n_total if n_total else 0.0\\n    metrics[\\\"inference_time_seconds\\\"] = round(elapsed, 1)\\n    metrics[\\\"config\\\"] = vars(args)\\n\\n    # 保存 metrics.json\\n    metrics_path = output_dir / \\\"metrics.json\\\"\\n    with open(metrics_path, \\\"w\\\") as f:\\n        json.dump(metrics, f, indent=2, ensure_ascii=False)\\n    logger.info(\\\"Metrics → %s\\\", metrics_path)\\n\\n    # 保存 predictions.json（每文档详细信息）\\n    detailed = []\\n    for r in raw_results:\\n        doc_id = r[\\\"doc_id\\\"]\\n        doc_gold = gold_by_doc.get(doc_id, [])\\n        gold_triples = [\\n            {\\\"head\\\": g[\\\"head\\\"], \\\"tail\\\": g[\\\"tail\\\"], \\\"relation\\\": g[\\\"relation\\\"],\\n             \\\"evidence\\\": g.get(\\\"evidence\\\", [])}\\n            for g in doc_gold\\n        ]\\n        detailed.append({\\n            \\\"doc_id\\\": doc_id,\\n            \\\"raw_output\\\": r[\\\"raw_output\\\"],\\n            \\\"parsed_triples\\\": r[\\\"parsed_triples\\\"],\\n            \\\"gold_triples\\\": gold_triples,\\n            \\\"truncated\\\": r[\\\"truncated\\\"],\\n            \\\"format_ok\\\": r[\\\"format_ok\\\"],\\n        })\\n\\n    pred_path = output_dir / \\\"predictions.json\\\"\\n    with open(pred_path, \\\"w\\\") as f:\\n        json.dump(detailed, f, indent=2, ensure_ascii=False)\\n    logger.info(\\\"Predictions → %s\\\", pred_path)\\n\\n    # 控制台汇总\\n    print(\\\"\\\\n\\\" + \\\"=\\\" * 50)\\n    print(f\\\"  F1:          {metrics['f1']:.4f}\\\")\\n    print(f\\\"  Ign-F1:      {metrics['ign_f1']:.4f}\\\")\\n    print(f\\\"  Evi-F1:      {metrics['evi_f1']:.4f}\\\")\\n    print(f\\\"  EDCR:        {metrics.get('edcr', 0):.4f}\\\")\\n    print(f\\\"  Format OK:   {n_format_ok}/{n_total} ({metrics['format_ok_rate']:.1%})\\\")\\n    print(f\\\"  Truncated:   {n_truncated}/{n_total}\\\")\\n    print(f\\\"  Predictions: {len(all_predictions)}\\\")\\n    print(\\\"=\\\" * 50)\\n\\n\\nif __name__ == \\\"__main__\\\":\\n    main()\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.37}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 32_

<details><summary>Logged reasoning block</summary>

```text
Let me try to read the training_args.bin differently, and also check for accelerate configs and the RSFT data.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "389f90a7-0623-47bc-acc8-fd5cfc9b497f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018pPfCTnSqQG2mYUciyhAyK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8094,
      "cache_read_input_tokens": 37926,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8094
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 33_

training_args.bin 解析失败（pickle 兼容问题）。从 SFT trainer 源码知道默认超参。继续检查 accelerate 配置和 RSFT 数据状态。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "22dc9426-eee8-4035-bea1-2dff3ebce894",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018pPfCTnSqQG2mYUciyhAyK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8094,
      "cache_read_input_tokens": 37926,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8094
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 34_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_011HC2EF7ot7WjbgUqN976Bn`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "find /root/autodl-tmp/freige -name \"accelerate*\" -o -name \"deepspeed*\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "750db6c0-ccd5-49f3-91eb-0fca87a2da64",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018pPfCTnSqQG2mYUciyhAyK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8094,
      "cache_read_input_tokens": 37926,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8094
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 35 · 2026-05-15T02:25:29.865Z_

<details><summary>↩ Tool result · `toolu_011HC2EF7ot7WjbgUqN976Bn`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/freige/configs/deepspeed_zero2.json\\n/root/autodl-tmp/freige/configs/deepspeed_zero3.json\\n/root/autodl-tmp/freige/configs/accelerate_4gpu.yaml\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.31}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "0d677704-478b-4f97-9096-af2076a0e404",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/freige/configs/deepspeed_zero2.json\\\\n/root/autodl-tmp/freige/configs/deepspeed_zero3.json\\\\n/root/autodl-tmp/freige/configs/accelerate_4gpu.yaml\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.31}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/freige/configs/deepspeed_zero2.json\\n/root/autodl-tmp/freige/configs/deepspeed_zero3.json\\n/root/autodl-tmp/freige/configs/accelerate_4gpu.yaml\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.31}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 36_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01UoGVqwkvwspHnWXC6H3nhd`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "ls -la /root/autodl-tmp/rsft_filtered/",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "c8eeab63-4aeb-45c0-8730-a52388faea89",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018pPfCTnSqQG2mYUciyhAyK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8094,
      "cache_read_input_tokens": 37926,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8094
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 37 · 2026-05-15T02:25:30.799Z_

<details><summary>↩ Tool result · `toolu_01UoGVqwkvwspHnWXC6H3nhd`</summary>

```text
{"result":"{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"ls: cannot access '/root/autodl-tmp/rsft_filtered/': No such file or directory\\n\", \"return_code\": 2}, \"error\": \"exit code 2\", \"metadata\": {\"elapsed_seconds\": 0.31}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "670b464c-2d9d-461c-a1b2-23b1d14edadd",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"ls: cannot access '/root/autodl-tmp/rsft_filtered/': No such file or directory\\\\n\\\", \\\"return_code\\\": 2}, \\\"error\\\": \\\"exit code 2\\\", \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.31}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"ls: cannot access '/root/autodl-tmp/rsft_filtered/': No such file or directory\\n\", \"return_code\": 2}, \"error\": \"exit code 2\", \"metadata\": {\"elapsed_seconds\": 0.31}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 38_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01VqcUgZL1uKgTG13GkzB6Re`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "grep -r \"eval_dataset\\|eval_strategy\\|evaluation\\|compute_metrics\" /root/autodl-tmp/freige/training/rsft_trainer.py",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "0b91ee36-f08e-4eb5-9eaa-c231bbd6f9db",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018pPfCTnSqQG2mYUciyhAyK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 8094,
      "cache_read_input_tokens": 37926,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 8094
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 39 · 2026-05-15T02:25:31.763Z_

<details><summary>↩ Tool result · `toolu_01VqcUgZL1uKgTG13GkzB6Re`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "cf4303cd-1b15-4864-9097-7b962c4f841e",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 40_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01XJkzXNnyxL4JQUD84W1Zsu`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "grep -n \"eval\" /root/autodl-tmp/freige/training/rsft_trainer.py",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "bbb73ff9-d756-4eed-91fb-4b1b87f1e237",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KVy9xjRWfuoaWYPgVyJ3sd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 881,
      "cache_read_input_tokens": 46020,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 881
      },
      "output_tokens": 65,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 41 · 2026-05-15T02:25:38.514Z_

<details><summary>↩ Tool result · `toolu_01XJkzXNnyxL4JQUD84W1Zsu`</summary>

```text
{"result":"{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 1}, \"error\": \"exit code 1\", \"metadata\": {\"elapsed_seconds\": 0.32}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "c5bcb5d5-d948-482f-8781-a1fb5b9c2a1f",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 1}, \\\"error\\\": \\\"exit code 1\\\", \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.32}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 1}, \"error\": \"exit code 1\", \"metadata\": {\"elapsed_seconds\": 0.32}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 42_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_016AuVoYeMuRdHzCLA9XNUMZ`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "cat /root/autodl-tmp/freige/configs/accelerate_4gpu.yaml",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "6ae2f8dd-803b-4476-a59e-3e207ad17823",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KVy9xjRWfuoaWYPgVyJ3sd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 881,
      "cache_read_input_tokens": 46020,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 881
      },
      "output_tokens": 65,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 43 · 2026-05-15T02:25:39.457Z_

<details><summary>↩ Tool result · `toolu_016AuVoYeMuRdHzCLA9XNUMZ`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"compute_environment: LOCAL_MACHINE\\ndistributed_type: DEEPSPEED\\ndeepspeed_config:\\n  deepspeed_config_file: /root/autodl-tmp/freige/configs/deepspeed_zero2.json\\n  zero3_init_flag: false\\nmachine_rank: 0\\nmain_training_function: main\\nnum_machines: 1\\nnum_processes: 4\\nuse_cpu: false\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.31}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "86926a6f-bbc3-4466-bd54-a67aa51d2a62",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"compute_environment: LOCAL_MACHINE\\\\ndistributed_type: DEEPSPEED\\\\ndeepspeed_config:\\\\n  deepspeed_config_file: /root/autodl-tmp/freige/configs/deepspeed_zero2.json\\\\n  zero3_init_flag: false\\\\nmachine_rank: 0\\\\nmain_training_function: main\\\\nnum_machines: 1\\\\nnum_processes: 4\\\\nuse_cpu: false\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.31}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"compute_environment: LOCAL_MACHINE\\ndistributed_type: DEEPSPEED\\ndeepspeed_config:\\n  deepspeed_config_file: /root/autodl-tmp/freige/configs/deepspeed_zero2.json\\n  zero3_init_flag: false\\nmachine_rank: 0\\nmain_training_function: main\\nnum_machines: 1\\nnum_processes: 4\\nuse_cpu: false\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.31}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 44_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01U1Ly2fnLnZipBCUBCAjavL`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "cat /root/autodl-tmp/freige/configs/deepspeed_zero2.json",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "08457ed8-370e-4f61-b07e-50ec87fc619f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KVy9xjRWfuoaWYPgVyJ3sd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 881,
      "cache_read_input_tokens": 46020,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 881
      },
      "output_tokens": 65,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 45 · 2026-05-15T02:25:39.891Z_

<details><summary>↩ Tool result · `toolu_01U1Ly2fnLnZipBCUBCAjavL`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"bf16\\\": {\\\"enabled\\\": true},\\n  \\\"zero_optimization\\\": {\\n    \\\"stage\\\": 2,\\n    \\\"offload_optimizer\\\": {\\\"device\\\": \\\"cpu\\\", \\\"pin_memory\\\": true},\\n    \\\"allgather_partitions\\\": true,\\n    \\\"allgather_bucket_size\\\": 2e8,\\n    \\\"overlap_comm\\\": true,\\n    \\\"reduce_scatter\\\": true,\\n    \\\"reduce_bucket_size\\\": 2e8,\\n    \\\"contiguous_gradients\\\": true\\n  },\\n  \\\"gradient_accumulation_steps\\\": \\\"auto\\\",\\n  \\\"gradient_clipping\\\": \\\"auto\\\",\\n  \\\"train_batch_size\\\": \\\"auto\\\",\\n  \\\"train_micro_batch_size_per_gpu\\\": \\\"auto\\\"\\n}\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.32}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "b3f58a4b-fb44-4c46-9887-57a6b0c6a509",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"{\\\\n  \\\\\\\"bf16\\\\\\\": {\\\\\\\"enabled\\\\\\\": true},\\\\n  \\\\\\\"zero_optimization\\\\\\\": {\\\\n    \\\\\\\"stage\\\\\\\": 2,\\\\n    \\\\\\\"offload_optimizer\\\\\\\": {\\\\\\\"device\\\\\\\": \\\\\\\"cpu\\\\\\\", \\\\\\\"pin_memory\\\\\\\": true},\\\\n    \\\\\\\"allgather_partitions\\\\\\\": true,\\\\n    \\\\\\\"allgather_bucket_size\\\\\\\": 2e8,\\\\n    \\\\\\\"overlap_comm\\\\\\\": true,\\\\n    \\\\\\\"reduce_scatter\\\\\\\": true,\\\\n    \\\\\\\"reduce_bucket_size\\\\\\\": 2e8,\\\\n    \\\\\\\"contiguous_gradients\\\\\\\": true\\\\n  },\\\\n  \\\\\\\"gradient_accumulation_steps\\\\\\\": \\\\\\\"auto\\\\\\\",\\\\n  \\\\\\\"gradient_clipping\\\\\\\": \\\\\\\"auto\\\\\\\",\\\\n  \\\\\\\"train_batch_size\\\\\\\": \\\\\\\"auto\\\\\\\",\\\\n  \\\\\\\"train_micro_batch_size_per_gpu\\\\\\\": \\\\\\\"auto\\\\\\\"\\\\n}\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.32}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"{\\n  \\\"bf16\\\": {\\\"enabled\\\": true},\\n  \\\"zero_optimization\\\": {\\n    \\\"stage\\\": 2,\\n    \\\"offload_optimizer\\\": {\\\"device\\\": \\\"cpu\\\", \\\"pin_memory\\\": true},\\n    \\\"allgather_partitions\\\": true,\\n    \\\"allgather_bucket_size\\\": 2e8,\\n    \\\"overlap_comm\\\": true,\\n    \\\"reduce_scatter\\\": true,\\n    \\\"reduce_bucket_size\\\": 2e8,\\n    \\\"contiguous_gradients\\\": true\\n  },\\n  \\\"gradient_accumulation_steps\\\": \\\"auto\\\",\\n  \\\"gradient_clipping\\\": \\\"auto\\\",\\n  \\\"train_batch_size\\\": \\\"auto\\\",\\n  \\\"train_micro_batch_size_per_gpu\\\": \\\"auto\\\"\\n}\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.32}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 46_

<details><summary>Logged reasoning block</summary>

```text
Now I have a full picture. Let me summarize my findings:

## Analysis of rsft_trainer.py vs sft_trainer.py

### Already Correct (Training Framework Reuse):
1. **LoRA config**: Same - r=64, alpha=128, dropout=0.05, same target_modules (q/k/v/o/gate/up/down_proj) ✅
2. **SFT adapter merge**: rsft_trainer loads base model → merges SFT adapter → creates fresh LoRA ✅
3. **Training framework**: Uses SFTConfig + SFTTrainer (via WeightedSFTTrainer subclass) ✅


4. **CED data loading**: Loads JSONL with ced_score, formats as chat template ✅
5. **Weighted sampling**: WeightedSFTTrainer supports CED score-weighted sampling ✅
6. **DeepSpeed support**: --deepspeed flag, configs exist (accelerate_4gpu.yaml + deepspeed_zero2.json) ✅
7. **Multi-GPU**: accelerate launch supported, 4 GPU config ready ✅
8. **bf16**: Default True ✅
9. **gradient_checkpointing**: Enabled ✅

### Key Differences (RSFT vs SFT defaults):
- SFT: lr=2e-4, bs

=1, gas=16, warmup_ratio=0.05, epochs=3, max_length=4096
- RSFT: lr=2e-5 (10x lower), bs=4, gas=4, warmup_steps=100, epochs=3, max_length=2048

The RSFT hyperparameters reflect a more conservative approach since we're fine-tuning from an already-trained model, and the data tends to be shorter sequences.

### Missing / Issues:

The big gap is that rsft_trainer.py has no evaluation setup at all—no eval_dataset, eval_strategy, or eval callbacks. There's also no rel_f1 or evidence quality evaluation, even though the evaluator module exists.

### What needs to be added:

I need to implement a custom evaluation callback that runs inference on the dev set and computes relation F1, evidence F1, and EDCR metrics, then logs them to W&B. The standard SFTTrainer only gives us loss and perplexity, so I'll need to hook into the training loop to compute the actual task-specific metrics.

My approach is to create a callback that periodically switches to eval mode, generates predictions on a subset of the dev set, parses the outputs, and compares them against the gold annotations using the existing DocREDEvaluator. I'll need to load the eval data, wire up the callback to the trainer, and make sure it integrates with the inference module's data requirements.

The inference module provides helper functions for loading eval data, running inference, and computing metrics, but I need to account for the fact that during training with LoRA and gradient checkpointing, I'll need to temporarily disable gradient checkpointing and enable use_cache before calling generate. Let me check the project structure to see where the code lives so I can start implementing this.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "dc9d2b2f-01f6-47af-bd5e-9eb5feb86ea6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01D96ELxnZSYjMAiA4MwHnDF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1151,
      "cache_read_input_tokens": 46901,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1151
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 47_

Let me check if there's a local copy of the code to edit.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "79976799-e943-46ce-a3bf-e18d18f584e4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01D96ELxnZSYjMAiA4MwHnDF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1151,
      "cache_read_input_tokens": 46901,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1151
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 48_

<details open><summary>🔧 Tool call — Glob · `toolu_01PyxwtNkoZcwC5N5HNy5j2P`</summary>

```json
{
  "pattern": "**/*.py",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "e4dec5ae-a078-4252-9349-cd39df444b2f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01D96ELxnZSYjMAiA4MwHnDF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1151,
      "cache_read_input_tokens": 46901,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1151
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 49 · 2026-05-15T02:26:08.459Z_

<details><summary>↩ Tool result · `toolu_01PyxwtNkoZcwC5N5HNy5j2P`</summary>

```text
artifacts/freige/__init__.py
artifacts/freige/data/__init__.py
artifacts/freige/rewards/__init__.py
artifacts/freige/analysis/__init__.py
artifacts/freige/training/__init__.py
artifacts/freige/eval/__init__.py
artifacts/freige/data/docred_processor.py
artifacts/freige/rewards/ced_reward.py
artifacts/freige/eval/evaluator.py
artifacts/freige/analysis/ced_signal_validation.py
artifacts/freige/training/smoke_test.py
artifacts/freige/training/sft_trainer.py
artifacts/freige/training/grpo_trainer.py
artifacts/freige/eval/find_best_checkpoint.py
artifacts/freige/eval/batch_eval.py
artifacts/freige/training/rsft_trainer.py
artifacts/diversity_probe.py
artifacts/freige/training/rsft_generate.py
artifacts/freige/training/rsft_score_filter.py
artifacts/freige/training/merge_shards.py
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "cdcc8fe3-1f73-4ab0-a6d1-68b72fa781fc",
  "tool_use_result": {
    "filenames": [
      "artifacts/freige/__init__.py",
      "artifacts/freige/data/__init__.py",
      "artifacts/freige/rewards/__init__.py",
      "artifacts/freige/analysis/__init__.py",
      "artifacts/freige/training/__init__.py",
      "artifacts/freige/eval/__init__.py",
      "artifacts/freige/data/docred_processor.py",
      "artifacts/freige/rewards/ced_reward.py",
      "artifacts/freige/eval/evaluator.py",
      "artifacts/freige/analysis/ced_signal_validation.py",
      "artifacts/freige/training/smoke_test.py",
      "artifacts/freige/training/sft_trainer.py",
      "artifacts/freige/training/grpo_trainer.py",
      "artifacts/freige/eval/find_best_checkpoint.py",
      "artifacts/freige/eval/batch_eval.py",
      "artifacts/freige/training/rsft_trainer.py",
      "artifacts/diversity_probe.py",
      "artifacts/freige/training/rsft_generate.py",
      "artifacts/freige/training/rsft_score_filter.py",
      "artifacts/freige/training/merge_shards.py"
    ],
    "durationMs": 16,
    "numFiles": 20,
    "truncated": false
  }
}
```

</details>

---

### Tool call

_source line 50_

<details open><summary>🔧 Tool call — Read · `toolu_01DyMwLATK9y7crpipLSx1DF`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "985476c6-ed4d-4ebd-aee6-0b952d95427c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KeCmFzrLSEopkoVv7w83q3",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1577,
      "cache_read_input_tokens": 48052,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1577
      },
      "output_tokens": 65,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 51 · 2026-05-15T02:26:13.558Z_

<details><summary>↩ Tool result · `toolu_01DyMwLATK9y7crpipLSx1DF`</summary>

```text
1	"""RSFT (Rejection Sampling Fine-Tuning) 训练脚本。
2	
3	从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。
4	流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。
5	
6	输入: JSONL，每行 {"doc_id": ..., "input": ..., "output": ..., "ced_score": ..., ...}
7	输出: QLoRA adapter checkpoint
8	依赖: transformers, trl, peft, bitsandbytes, datasets
9	
10	单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output
11	多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \
12	            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output
13	"""
14	
15	import argparse
16	import json
17	import logging
18	import os
19	
20	import torch
21	from datasets import Dataset
22	from peft import LoraConfig, PeftModel, TaskType, get_peft_model
23	from torch.utils.data import WeightedRandomSampler
24	from transformers import (
25	    AutoModelForCausalLM,
26	    AutoTokenizer,
27	    BitsAndBytesConfig,
28	)
29	from trl import SFTConfig, SFTTrainer
30	
31	from freige.training.sft_trainer import SYSTEM_PROMPT
32	
33	logging.basicConfig(level=logging.INFO, format="%(asctime)s %(levelname)s %(message)s")
34	logger = logging.getLogger(__name__)
35	
36	DEFAULT_BASE_MODEL = "/root/autodl-tmp/models/Qwen3-4B"
37	DEFAULT_SFT_ADAPTER = "/root/autodl-tmp/sft_output"
38	
39	
40	def load_rsft_data(data_path: str, tokenizer, max_length: int = 2048):
41	    """加载 CED 筛选后的 RSFT 数据，格式化为 chat template 文本。
42	
43	    每行 JSONL 的 input 字段作为 user message，output 字段作为 assistant response，
44	    经 apply_chat_template 拼接后用于 SFT 训练。超过 max_length 的样本被跳过
45	    而非截断，避免训练在不完整 JSON 输出上。
46	
47	    Returns:
48	        (Dataset, list[float]): 训练数据集和对应的 CED scores
49	    """
50	    samples = []
51	    with open(data_path) as f:
52	        for line in f:
53	            if line.strip():
54	                samples.append(json.loads(line))
55	
56	    logger.info("Loaded %d RSFT samples from %s", len(samples), data_path)
57	
58	    formatted = []
59	    ced_scores = []
60	    skipped = 0
61	    for s in samples:
62	        messages = [
63	            {"role": "system", "content": SYSTEM_PROMPT},
64	            {"role": "user", "content": s["input"]},
65	            {"role": "assistant", "content": s["output"]},
66	        ]
67	        text = tokenizer.apply_chat_template(
68	            messages,
69	            tokenize=False,
70	            add_generation_prompt=False,
71	            enable_thinking=False,
72	        )
73	        token_len = len(tokenizer.encode(text, add_special_tokens=False))
74	        if token_len > max_length:
75	            skipped += 1
76	            continue
77	        formatted.append({"text": text})
78	        ced_scores.append(s.get("ced_score", 1.0))
79	
80	    if skipped:
81	        logger.warning("Skipped %d samples exceeding max_length=%d", skipped, max_length)
82	
83	    if ced_scores:
84	        logger.info(
85	            "Prepared %d RSFT samples (CED scores: min=%.3f, max=%.3f, mean=%.3f)",
86	            len(formatted), min(ced_scores), max(ced_scores),
87	            sum(ced_scores) / len(ced_scores),
88	        )
89	    return Dataset.from_list(formatted), ced_scores
90	
91	
92	class WeightedSFTTrainer(SFTTrainer):
93	    """SFTTrainer with CED score-weighted sampling.
94	
95	    高 CED score 的样本被更频繁采样。使用 WeightedRandomSampler 实现，
96	    适用于单机训练。多机 DDP 场景下 Accelerate 会替换 sampler，
97	    此时 weighted_sampling 不生效，需改用数据集层面的过采样。
98	    """
99	
100	    def __init__(self, *args, sample_weights=None, **kwargs):
101	        super().__init__(*args, **kwargs)
102	        self.sample_weights = sample_weights
103	
104	    def _get_train_sampler(self, dataset=None):
105	        if self.sample_weights is not None:
106	            ds = dataset if dataset is not None else self.train_dataset
107	            return WeightedRandomSampler(
108	                weights=self.sample_weights,
109	                num_samples=len(ds),
110	                replacement=True,
111	            )
112	        return super()._get_train_sampler(dataset)
113	
114	
115	def main():
116	    parser = argparse.ArgumentParser(description="FREIGE RSFT Training")
117	    parser.add_argument("--base_model", type=str, default=DEFAULT_BASE_MODEL)
118	    parser.add_argument("--sft_adapter", type=str, default=DEFAULT_SFT_ADAPTER,
119	                        help="SFT warmup adapter 路径 (merge 后训练新 LoRA)")
120	    parser.add_argument("--rsft_data_path", type=str, required=True,
121	                        help="CED 筛选后的 RSFT 训练数据 (JSONL)")
122	    parser.add_argument("--output_dir", type=str, required=True)
123	    parser.add_argument("--learning_rate", type=float, default=2e-5)
124	    parser.add_argument("--num_epochs", type=int, default=3)
125	    parser.add_argument("--per_device_batch_size", type=int, default=4)
126	    parser.add_argument("--gradient_accumulation_steps", type=int, default=4)
127	    parser.add_argument("--warmup_steps", type=int, default=100)
128	    parser.add_argument("--save_steps", type=int, default=50)
129	    parser.add_argument("--save_total_limit", type=int, default=5)
130	    parser.add_argument("--max_length", type=int, default=2048)
131	    parser.add_argument("--seed", type=int, default=42)
132	    parser.add_argument("--wandb_project", type=str, default="freige-rsft")
133	    parser.add_argument("--wandb_run_name", type=str, default=None)
134	    parser.add_argument("--weighted_sampling", action="store_true",
135	                        help="按 CED score 加权采样（高分样本更频繁）")
136	    parser.add_argument("--quantize", action="store_true",
137	                        help="启用 4-bit QLoRA 量化")
138	    parser.add_argument("--lora_rank", type=int, default=64)
139	    parser.add_argument("--lora_alpha", type=int, default=128)
140	    parser.add_argument("--lora_dropout", type=float, default=0.05)
141	    parser.add_argument("--bf16", action="store_true", default=True)
142	    parser.add_argument("--deepspeed", type=str, default=None,
143	                        help="DeepSpeed 配置文件路径")
144	    args = parser.parse_args()
145	
146	    # W&B
147	    if args.wandb_project and "WANDB_API_KEY" in os.environ:
148	        os.environ["WANDB_PROJECT"] = args.wandb_project
149	        if args.wandb_run_name:
150	            os.environ["WANDB_NAME"] = args.wandb_run_name
151	
152	    # Tokenizer
153	    logger.info("Loading tokenizer: %s", args.base_model)
154	    tokenizer = AutoTokenizer.from_pretrained(
155	        args.base_model, trust_remote_code=True, padding_side="right",
156	    )
157	    if tokenizer.pad_token is None:
158	        tokenizer.pad_token = tokenizer.eos_token
159	
160	    # Data
161	    logger.info("Loading RSFT data: %s", args.rsft_data_path)
162	    train_dataset, ced_scores = load_rsft_data(
163	        args.rsft_data_path, tokenizer, args.max_length,
164	    )
165	
166	    # Model: base → merge SFT adapter → new LoRA
167	    logger.info("Loading base model: %s", args.base_model)
168	    local_rank = int(os.environ.get("LOCAL_RANK", 0))
169	    model_kwargs = dict(
170	        trust_remote_code=True,
171	        attn_implementation="sdpa",
172	        device_map={"": local_rank},
173	    )
174	    if args.quantize:
175	        logger.info("Using 4-bit QLoRA quantization")
176	        model_kwargs["quantization_config"] = BitsAndBytesConfig(
177	            load_in_4bit=True,
178	            bnb_4bit_compute_dtype=torch.bfloat16,
179	            bnb_4bit_quant_type="nf4",
180	            bnb_4bit_use_double_quant=True,
181	        )
182	    else:
183	        model_kwargs["torch_dtype"] = torch.bfloat16 if args.bf16 else torch.float16
184	
185	    model = AutoModelForCausalLM.from_pretrained(args.base_model, **model_kwargs)
186	
187	    if args.sft_adapter:
188	        logger.info("Merging SFT adapter: %s", args.sft_adapter)
189	        model = PeftModel.from_pretrained(model, args.sft_adapter)
190	        model = model.merge_and_unload()
191	
192	    model.config.use_cache = False
193	    model.gradient_checkpointing_enable()
194	
195	    # Fresh LoRA for RSFT (与 SFT warmup 相同结构)
196	    lora_config = LoraConfig(
197	        task_type=TaskType.CAUSAL_LM,
198	        r=args.lora_rank,
199	        lora_alpha=args.lora_alpha,
200	        lora_dropout=args.lora_dropout,
201	        target_modules=["q_proj", "k_proj", "v_proj", "o_proj",
202	                         "gate_proj", "up_proj", "down_proj"],
203	    )
204	    model = get_peft_model(model, lora_config)
205	    model.print_trainable_parameters()
206	
207	    # Training config
208	    training_args = SFTConfig(
209	        output_dir=args.output_dir,
210	        num_train_epochs=args.num_epochs,
211	        per_device_train_batch_size=args.per_device_batch_size,
212	        gradient_accumulation_steps=args.gradient_accumulation_steps,
213	        learning_rate=args.learning_rate,
214	        warmup_steps=args.warmup_steps,
215	        bf16=args.bf16,
216	        logging_steps=10,
217	        save_strategy="steps",
218	        save_steps=args.save_steps,
219	        save_total_limit=args.save_total_limit,
220	        seed=args.seed,
221	        max_length=args.max_length,
222	        dataset_text_field="text",
223	        report_to="wandb" if "WANDB_API_KEY" in os.environ else "none",
224	        gradient_checkpointing=True,
225	        gradient_checkpointing_kwargs={"use_reentrant": False},
226	        deepspeed=args.deepspeed,
227	    )
228	
229	    sample_weights = ced_scores if args.weighted_sampling else None
230	
231	    trainer = WeightedSFTTrainer(
232	        model=model,
233	        args=training_args,
234	        train_dataset=train_dataset,
235	        processing_class=tokenizer,
236	        sample_weights=sample_weights,
237	    )
238	
239	    logger.info(
240	        "Starting RSFT training (%d samples, weighted=%s)...",
241	        len(train_dataset), args.weighted_sampling,
242	    )
243	    trainer.train()
244	
245	    logger.info("Saving model to %s", args.output_dir)
246	    trainer.save_model(args.output_dir)
247	    tokenizer.save_pretrained(args.output_dir)
248	    logger.info("RSFT training complete.")
249	
250	
251	if __name__ == "__main__":
252	    main()
253	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "f2752d13-92bd-4d8f-ae35-d8e18fd8e3b3",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py",
      "content": "\"\"\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\n\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\n\n输入: JSONL，每行 {\"doc_id\": ..., \"input\": ..., \"output\": ..., \"ced_score\": ..., ...}\n输出: QLoRA adapter checkpoint\n依赖: transformers, trl, peft, bitsandbytes, datasets\n\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n\"\"\"\n\nimport argparse\nimport json\nimport logging\nimport os\n\nimport torch\nfrom datasets import Dataset\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\nfrom torch.utils.data import WeightedRandomSampler\nfrom transformers import (\n    AutoModelForCausalLM,\n    AutoTokenizer,\n    BitsAndBytesConfig,\n)\nfrom trl import SFTConfig, SFTTrainer\n\nfrom freige.training.sft_trainer import SYSTEM_PROMPT\n\nlogging.basicConfig(level=logging.INFO, format=\"%(asctime)s %(levelname)s %(message)s\")\nlogger = logging.getLogger(__name__)\n\nDEFAULT_BASE_MODEL = \"/root/autodl-tmp/models/Qwen3-4B\"\nDEFAULT_SFT_ADAPTER = \"/root/autodl-tmp/sft_output\"\n\n\ndef load_rsft_data(data_path: str, tokenizer, max_length: int = 2048):\n    \"\"\"加载 CED 筛选后的 RSFT 数据，格式化为 chat template 文本。\n\n    每行 JSONL 的 input 字段作为 user message，output 字段作为 assistant response，\n    经 apply_chat_template 拼接后用于 SFT 训练。超过 max_length 的样本被跳过\n    而非截断，避免训练在不完整 JSON 输出上。\n\n    Returns:\n        (Dataset, list[float]): 训练数据集和对应的 CED scores\n    \"\"\"\n    samples = []\n    with open(data_path) as f:\n        for line in f:\n            if line.strip():\n                samples.append(json.loads(line))\n\n    logger.info(\"Loaded %d RSFT samples from %s\", len(samples), data_path)\n\n    formatted = []\n    ced_scores = []\n    skipped = 0\n    for s in samples:\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": s[\"input\"]},\n            {\"role\": \"assistant\", \"content\": s[\"output\"]},\n        ]\n        text = tokenizer.apply_chat_template(\n            messages,\n            tokenize=False,\n            add_generation_prompt=False,\n            enable_thinking=False,\n        )\n        token_len = len(tokenizer.encode(text, add_special_tokens=False))\n        if token_len > max_length:\n            skipped += 1\n            continue\n        formatted.append({\"text\": text})\n        ced_scores.append(s.get(\"ced_score\", 1.0))\n\n    if skipped:\n        logger.warning(\"Skipped %d samples exceeding max_length=%d\", skipped, max_length)\n\n    if ced_scores:\n        logger.info(\n            \"Prepared %d RSFT samples (CED scores: min=%.3f, max=%.3f, mean=%.3f)\",\n            len(formatted), min(ced_scores), max(ced_scores),\n            sum(ced_scores) / len(ced_scores),\n        )\n    return Dataset.from_list(formatted), ced_scores\n\n\nclass WeightedSFTTrainer(SFTTrainer):\n    \"\"\"SFTTrainer with CED score-weighted sampling.\n\n    高 CED score 的样本被更频繁采样。使用 WeightedRandomSampler 实现，\n    适用于单机训练。多机 DDP 场景下 Accelerate 会替换 sampler，\n    此时 weighted_sampling 不生效，需改用数据集层面的过采样。\n    \"\"\"\n\n    def __init__(self, *args, sample_weights=None, **kwargs):\n        super().__init__(*args, **kwargs)\n        self.sample_weights = sample_weights\n\n    def _get_train_sampler(self, dataset=None):\n        if self.sample_weights is not None:\n            ds = dataset if dataset is not None else self.train_dataset\n            return WeightedRandomSampler(\n                weights=self.sample_weights,\n                num_samples=len(ds),\n                replacement=True,\n            )\n        return super()._get_train_sampler(dataset)\n\n\ndef main():\n    parser = argparse.ArgumentParser(description=\"FREIGE RSFT Training\")\n    parser.add_argument(\"--base_model\", type=str, default=DEFAULT_BASE_MODEL)\n    parser.add_argument(\"--sft_adapter\", type=str, default=DEFAULT_SFT_ADAPTER,\n                        help=\"SFT warmup adapter 路径 (merge 后训练新 LoRA)\")\n    parser.add_argument(\"--rsft_data_path\", type=str, required=True,\n                        help=\"CED 筛选后的 RSFT 训练数据 (JSONL)\")\n    parser.add_argument(\"--output_dir\", type=str, required=True)\n    parser.add_argument(\"--learning_rate\", type=float, default=2e-5)\n    parser.add_argument(\"--num_epochs\", type=int, default=3)\n    parser.add_argument(\"--per_device_batch_size\", type=int, default=4)\n    parser.add_argument(\"--gradient_accumulation_steps\", type=int, default=4)\n    parser.add_argument(\"--warmup_steps\", type=int, default=100)\n    parser.add_argument(\"--save_steps\", type=int, default=50)\n    parser.add_argument(\"--save_total_limit\", type=int, default=5)\n    parser.add_argument(\"--max_length\", type=int, default=2048)\n    parser.add_argument(\"--seed\", type=int, default=42)\n    parser.add_argument(\"--wandb_project\", type=str, default=\"freige-rsft\")\n    parser.add_argument(\"--wandb_run_name\", type=str, default=None)\n    parser.add_argument(\"--weighted_sampling\", action=\"store_true\",\n                        help=\"按 CED score 加权采样（高分样本更频繁）\")\n    parser.add_argument(\"--quantize\", action=\"store_true\",\n                        help=\"启用 4-bit QLoRA 量化\")\n    parser.add_argument(\"--lora_rank\", type=int, default=64)\n    parser.add_argument(\"--lora_alpha\", type=int, default=128)\n    parser.add_argument(\"--lora_dropout\", type=float, default=0.05)\n    parser.add_argument(\"--bf16\", action=\"store_true\", default=True)\n    parser.add_argument(\"--deepspeed\", type=str, default=None,\n                        help=\"DeepSpeed 配置文件路径\")\n    args = parser.parse_args()\n\n    # W&B\n    if args.wandb_project and \"WANDB_API_KEY\" in os.environ:\n        os.environ[\"WANDB_PROJECT\"] = args.wandb_project\n        if args.wandb_run_name:\n            os.environ[\"WANDB_NAME\"] = args.wandb_run_name\n\n    # Tokenizer\n    logger.info(\"Loading tokenizer: %s\", args.base_model)\n    tokenizer = AutoTokenizer.from_pretrained(\n        args.base_model, trust_remote_code=True, padding_side=\"right\",\n    )\n    if tokenizer.pad_token is None:\n        tokenizer.pad_token = tokenizer.eos_token\n\n    # Data\n    logger.info(\"Loading RSFT data: %s\", args.rsft_data_path)\n    train_dataset, ced_scores = load_rsft_data(\n        args.rsft_data_path, tokenizer, args.max_length,\n    )\n\n    # Model: base → merge SFT adapter → new LoRA\n    logger.info(\"Loading base model: %s\", args.base_model)\n    local_rank = int(os.environ.get(\"LOCAL_RANK\", 0))\n    model_kwargs = dict(\n        trust_remote_code=True,\n        attn_implementation=\"sdpa\",\n        device_map={\"\": local_rank},\n    )\n    if args.quantize:\n        logger.info(\"Using 4-bit QLoRA quantization\")\n        model_kwargs[\"quantization_config\"] = BitsAndBytesConfig(\n            load_in_4bit=True,\n            bnb_4bit_compute_dtype=torch.bfloat16,\n            bnb_4bit_quant_type=\"nf4\",\n            bnb_4bit_use_double_quant=True,\n        )\n    else:\n        model_kwargs[\"torch_dtype\"] = torch.bfloat16 if args.bf16 else torch.float16\n\n    model = AutoModelForCausalLM.from_pretrained(args.base_model, **model_kwargs)\n\n    if args.sft_adapter:\n        logger.info(\"Merging SFT adapter: %s\", args.sft_adapter)\n        model = PeftModel.from_pretrained(model, args.sft_adapter)\n        model = model.merge_and_unload()\n\n    model.config.use_cache = False\n    model.gradient_checkpointing_enable()\n\n    # Fresh LoRA for RSFT (与 SFT warmup 相同结构)\n    lora_config = LoraConfig(\n        task_type=TaskType.CAUSAL_LM,\n        r=args.lora_rank,\n        lora_alpha=args.lora_alpha,\n        lora_dropout=args.lora_dropout,\n        target_modules=[\"q_proj\", \"k_proj\", \"v_proj\", \"o_proj\",\n                         \"gate_proj\", \"up_proj\", \"down_proj\"],\n    )\n    model = get_peft_model(model, lora_config)\n    model.print_trainable_parameters()\n\n    # Training config\n    training_args = SFTConfig(\n        output_dir=args.output_dir,\n        num_train_epochs=args.num_epochs,\n        per_device_train_batch_size=args.per_device_batch_size,\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\n        learning_rate=args.learning_rate,\n        warmup_steps=args.warmup_steps,\n        bf16=args.bf16,\n        logging_steps=10,\n        save_strategy=\"steps\",\n        save_steps=args.save_steps,\n        save_total_limit=args.save_total_limit,\n        seed=args.seed,\n        max_length=args.max_length,\n        dataset_text_field=\"text\",\n        report_to=\"wandb\" if \"WANDB_API_KEY\" in os.environ else \"none\",\n        gradient_checkpointing=True,\n        gradient_checkpointing_kwargs={\"use_reentrant\": False},\n        deepspeed=args.deepspeed,\n    )\n\n    sample_weights = ced_scores if args.weighted_sampling else None\n\n    trainer = WeightedSFTTrainer(\n        model=model,\n        args=training_args,\n        train_dataset=train_dataset,\n        processing_class=tokenizer,\n        sample_weights=sample_weights,\n    )\n\n    logger.info(\n        \"Starting RSFT training (%d samples, weighted=%s)...\",\n        len(train_dataset), args.weighted_sampling,\n    )\n    trainer.train()\n\n    logger.info(\"Saving model to %s\", args.output_dir)\n    trainer.save_model(args.output_dir)\n    tokenizer.save_pretrained(args.output_dir)\n    logger.info(\"RSFT training complete.\")\n\n\nif __name__ == \"__main__\":\n    main()\n",
      "numLines": 253,
      "startLine": 1,
      "totalLines": 253
    }
  }
}
```

</details>

---

### Assistant

_source line 52_

<details><summary>Logged reasoning block</summary>

```text
Now I have a clear picture. Let me also read the eval/inference.py from the local copy to understand the full interface.

Key findings:
1. **Training framework**: RSFT correctly reuses SFT framework (SFTConfig/SFTTrainer, same LoRA structure, same target_modules, same chat template via SYSTEM_PROMPT import)
2. **SFT adapter merge**: Correctly implemented (load base → PeftModel.from_pretrained(sft_adapter) → merge_and_unload → new LoRA)
3. **Hyperparams**: RSFT defaults differ from SFT but intentionally:
   - SFT: lr=2e-4, bs=1, gas=16, warmup_ratio=0.05, max_length=4096
   - RSFT: lr=2e-5 (10x lower - good for continuing from warmup), bs=4, gas=4, warmup_steps=100, max_length=2048
4. **Critical gap**: There's no evaluation pipeline at all—no eval dataset, strategy, metrics, or callbacks configured.

I need to add evaluation support by introducing command-line arguments for the DocRED dev set path and evaluation frequency, then implement a custom evaluation callback.

Building evaluation callback...
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "79d1223e-82b3-4881-ab13-29572ca189cd",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018efBncuTqqu4acS5Xnb7w1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3876,
      "cache_read_input_tokens": 49629,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3876
      },
      "output_tokens": 9,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 53_

<details open><summary>🔧 Tool call — Read · `toolu_01L5kV45YCSCatXfQEzvCRi6`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/eval/evaluator.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "7d7e54a3-16f2-4439-a6de-973325ab9605",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018efBncuTqqu4acS5Xnb7w1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3876,
      "cache_read_input_tokens": 49629,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3876
      },
      "output_tokens": 9,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 54 · 2026-05-15T02:26:26.687Z_

<details><summary>↩ Tool result · `toolu_01L5kV45YCSCatXfQEzvCRi6`</summary>

```text
1	"""DocRED 关系抽取评测模块。
2	
3	指标:
4	  - F1 / Ign-F1: 关系三元组级别 micro-F1，Ign-F1 排除训练集中出现的三元组
5	  - Evi-F1: 对正确预测的三元组，计算 evidence 句子级 F1
6	  - EDCR: Evidence Distractor Citation Rate，预测 evidence 中非 gold 的比例
7	
8	输入: 预测列表 + gold 标注列表（每个元素为文档级标注）
9	输出: 指标字典
10	"""
11	
12	import json
13	import logging
14	from collections import defaultdict
15	from typing import Optional
16	
17	logger = logging.getLogger(__name__)
18	
19	
20	def _triple_key(doc_id: str, head: str, tail: str, relation: str) -> tuple:
21	    return (doc_id, head.lower().strip(), tail.lower().strip(), relation)
22	
23	
24	class DocREDEvaluator:
25	    """DocRED 评测器。
26	
27	    Args:
28	        train_triples: 训练集中的三元组集合，用于计算 Ign-F1。
29	                       每个元素为 (doc_title, head_name, tail_name, relation)。
30	                       为 None 时 Ign-F1 = F1。
31	    """
32	
33	    def __init__(self, train_triples: Optional[set[tuple]] = None):
34	        self.train_triples = train_triples or set()
35	
36	    @classmethod
37	    def from_train_file(cls, train_path: str) -> "DocREDEvaluator":
38	        """从训练集 JSON 文件构建 evaluator，自动提取训练集三元组。"""
39	        from freige.data.docred_processor import DOCRED_REL_INFO
40	
41	        with open(train_path) as f:
42	            train_data = json.load(f)
43	
44	        train_triples = set()
45	        for doc in train_data:
46	            doc_id = doc.get("title", "")
47	            vertex_set = doc["vertexSet"]
48	            for label in doc.get("labels", []):
49	                h_name = vertex_set[label["h"]][0]["name"]
50	                t_name = vertex_set[label["t"]][0]["name"]
51	                rel_name = DOCRED_REL_INFO.get(label["r"], label["r"])
52	                train_triples.add(
53	                    _triple_key(doc_id, h_name, t_name, rel_name)
54	                )
55	
56	        logger.info("Loaded %d training triples for Ign-F1", len(train_triples))
57	        return cls(train_triples=train_triples)
58	
59	    def compute_f1(
60	        self,
61	        predictions: list[dict],
62	        gold: list[dict],
63	    ) -> dict:
64	        """计算 F1 和 Ign-F1。
65	
66	        Args:
67	            predictions: [{"doc_id": str, "head": str, "tail": str,
68	                           "relation": str, ...}, ...]
69	            gold: 同上格式
70	
71	        Returns:
72	            {"precision", "recall", "f1", "ign_precision", "ign_recall", "ign_f1"}
73	        """
74	        pred_set = set()
75	        for p in predictions:
76	            pred_set.add(_triple_key(
77	                p["doc_id"], p["head"], p["tail"], p["relation"]
78	            ))
79	
80	        gold_set = set()
81	        for g in gold:
82	            gold_set.add(_triple_key(
83	                g["doc_id"], g["head"], g["tail"], g["relation"]
84	            ))
85	
86	        tp = pred_set & gold_set
87	        precision = len(tp) / len(pred_set) if pred_set else 0.0
88	        recall = len(tp) / len(gold_set) if gold_set else 0.0
89	        f1 = 2 * precision * recall / (precision + recall) if (precision + recall) > 0 else 0.0
90	
91	        pred_ign = pred_set - self.train_triples
92	        gold_ign = gold_set - self.train_triples
93	        tp_ign = pred_ign & gold_ign
94	        ign_prec = len(tp_ign) / len(pred_ign) if pred_ign else 0.0
95	        ign_rec = len(tp_ign) / len(gold_ign) if gold_ign else 0.0
96	        ign_f1 = (
97	            2 * ign_prec * ign_rec / (ign_prec + ign_rec)
98	            if (ign_prec + ign_rec) > 0 else 0.0
99	        )
100	
101	        return {
102	            "precision": precision,
103	            "recall": recall,
104	            "f1": f1,
105	            "ign_precision": ign_prec,
106	            "ign_recall": ign_rec,
107	            "ign_f1": ign_f1,
108	            "tp": len(tp),
109	            "pred_count": len(pred_set),
110	            "gold_count": len(gold_set),
111	        }
112	
113	    def compute_evi_f1(
114	        self,
115	        predictions: list[dict],
116	        gold: list[dict],
117	    ) -> dict:
118	        """计算 Evidence F1（句子级）。
119	
120	        仅对正确预测的三元组计算 evidence 匹配。
121	
122	        Args:
123	            predictions: [{"doc_id", "head", "tail", "relation",
124	                           "evidence": [int, ...]}, ...]
125	            gold: 同上格式
126	
127	        Returns:
128	            {"evi_precision", "evi_recall", "evi_f1", "n_evaluated"}
129	        """
130	        gold_map = {}
131	        for g in gold:
132	            key = _triple_key(g["doc_id"], g["head"], g["tail"], g["relation"])
133	            gold_map.setdefault(key, set()).update(g.get("evidence", []))
134	
135	        total_tp = 0
136	        total_pred = 0
137	        total_gold = 0
138	        n_evaluated = 0
139	
140	        for p in predictions:
141	            key = _triple_key(p["doc_id"], p["head"], p["tail"], p["relation"])
142	            if key not in gold_map:
143	                continue
144	
145	            pred_evi = set(p.get("evidence", []))
146	            gold_evi = gold_map[key]
147	
148	            tp = len(pred_evi & gold_evi)
149	            total_tp += tp
150	            total_pred += len(pred_evi)
151	            total_gold += len(gold_evi)
152	            n_evaluated += 1
153	
154	        evi_prec = total_tp / total_pred if total_pred else 0.0
155	        evi_rec = total_tp / total_gold if total_gold else 0.0
156	        evi_f1 = (
157	            2 * evi_prec * evi_rec / (evi_prec + evi_rec)
158	            if (evi_prec + evi_rec) > 0 else 0.0
159	        )
160	
161	        return {
162	            "evi_precision": evi_prec,
163	            "evi_recall": evi_rec,
164	            "evi_f1": evi_f1,
165	            "n_evaluated": n_evaluated,
166	        }
167	
168	    def compute_edcr(
169	        self,
170	        predictions: list[dict],
171	        gold: list[dict],
172	    ) -> dict:
173	        """计算 EDCR（Evidence Distractor Citation Rate）。
174	
175	        对所有预测的三元组（不限于正确预测），统计其 evidence 中
176	        不在 gold evidence 集合里的句子占比。
177	
178	        EDCR = |pred_evi - gold_evi| / |pred_evi|，越低越好。
179	
180	        Args:
181	            predictions: [{"doc_id", "head", "tail", "relation",
182	                           "evidence": [int, ...]}, ...]
183	            gold: 同上格式
184	
185	        Returns:
186	            {"edcr", "n_distractor_citations", "n_total_citations", "n_evaluated"}
187	        """
188	        gold_map = {}
189	        for g in gold:
190	            key = _triple_key(g["doc_id"], g["head"], g["tail"], g["relation"])
191	            gold_map.setdefault(key, set()).update(g.get("evidence", []))
192	
193	        n_distractor = 0
194	        n_total = 0
195	        n_evaluated = 0
196	
197	        for p in predictions:
198	            pred_evi = set(p.get("evidence", []))
199	            if not pred_evi:
200	                continue
201	
202	            key = _triple_key(p["doc_id"], p["head"], p["tail"], p["relation"])
203	            gold_evi = gold_map.get(key, set())
204	
205	            distractors = pred_evi - gold_evi
206	            n_distractor += len(distractors)
207	            n_total += len(pred_evi)
208	            n_evaluated += 1
209	
210	        edcr = n_distractor / n_total if n_total else 0.0
211	
212	        return {
213	            "edcr": edcr,
214	            "n_distractor_citations": n_distractor,
215	            "n_total_citations": n_total,
216	            "n_evaluated": n_evaluated,
217	        }
218	
219	    def compute_format_compliance(self, raw_outputs: list[dict]) -> dict:
220	        """计算模型输出的格式合规率。
221	
222	        Args:
223	            raw_outputs: [{"doc_id": str, "raw_text": str}, ...]
224	
225	        Returns:
226	            dict with format_compliance_rate, field_compliance_rate,
227	            evidence_format_rate, and counts.
228	        """
229	        required_fields = {"head", "relation", "tail", "evidence"}
230	        n_total = len(raw_outputs)
231	        n_parseable = 0
232	        n_field_complete = 0
233	        n_evidence_valid = 0
234	
235	        for item in raw_outputs:
236	            doc_id = item.get("doc_id", "")
237	            raw_text = item.get("raw_text", "")
238	
239	            parsed = parse_model_output(doc_id, raw_text)
240	            if not parsed and not self._is_parseable_json_list(raw_text):
241	                continue
242	            n_parseable += 1
243	
244	            triples = self._parse_raw_json_list(raw_text)
245	            if triples is None:
246	                continue
247	
248	            all_fields_ok = True
249	            all_evidence_ok = True
250	            for t in triples:
251	                if not isinstance(t, dict) or not required_fields.issubset(t.keys()):
252	                    all_fields_ok = False
253	                    all_evidence_ok = False
254	                    break
255	                evi = t.get("evidence")
256	                if not isinstance(evi, list) or not all(
257	                    isinstance(e, int) and e >= 0 for e in evi
258	                ):
259	                    all_evidence_ok = False
260	
261	            if all_fields_ok:
262	                n_field_complete += 1
263	            if all_fields_ok and all_evidence_ok:
264	                n_evidence_valid += 1
265	
266	        return {
267	            "format_compliance_rate": n_parseable / n_total if n_total else 0.0,
268	            "field_compliance_rate": n_field_complete / n_total if n_total else 0.0,
269	            "evidence_format_rate": n_evidence_valid / n_total if n_total else 0.0,
270	            "n_total": n_total,
271	            "n_parseable": n_parseable,
272	            "n_field_complete": n_field_complete,
273	            "n_evidence_valid": n_evidence_valid,
274	        }
275	
276	    @staticmethod
277	    def _is_parseable_json_list(text: str) -> bool:
278	        try:
279	            obj = json.loads(text)
280	            return isinstance(obj, list)
281	        except json.JSONDecodeError:
282	            start = text.find("[")
283	            end = text.rfind("]") + 1
284	            if start >= 0 and end > start:
285	                try:
286	                    obj = json.loads(text[start:end])
287	                    return isinstance(obj, list)
288	                except json.JSONDecodeError:
289	                    return False
290	            return False
291	
292	    @staticmethod
293	    def _parse_raw_json_list(text: str) -> Optional[list]:
294	        try:
295	            obj = json.loads(text)
296	            if isinstance(obj, list):
297	                return obj
298	        except json.JSONDecodeError:
299	            start = text.find("[")
300	            end = text.rfind("]") + 1
301	            if start >= 0 and end > start:
302	                try:
303	                    obj = json.loads(text[start:end])
304	                    if isinstance(obj, list):
305	                        return obj
306	                except json.JSONDecodeError:
307	                    pass
308	        return None
309	
310	    def evaluate(
311	        self,
312	        predictions: list[dict],
313	        gold: list[dict],
314	        raw_outputs: Optional[list[dict]] = None,
315	    ) -> dict:
316	        """运行所有评测指标。"""
317	        f1_metrics = self.compute_f1(predictions, gold)
318	        evi_metrics = self.compute_evi_f1(predictions, gold)
319	        edcr_metrics = self.compute_edcr(predictions, gold)
320	        result = {**f1_metrics, **evi_metrics, **edcr_metrics}
321	        if raw_outputs is not None:
322	            result.update(self.compute_format_compliance(raw_outputs))
323	        return result
324	
325	
326	def parse_model_output(doc_id: str, output_text: str) -> list[dict]:
327	    """解析模型输出的 JSON 文本为标准预测格式。
328	
329	    模型输出格式:
330	    [{"head": "...", "relation": "...", "tail": "...", "evidence": [0, 3]}, ...]
331	
332	    Returns:
333	        标准预测列表，每个元素包含 doc_id
334	    """
335	    try:
336	        triples = json.loads(output_text)
337	    except json.JSONDecodeError:
338	        start = output_text.find("[")
339	        end = output_text.rfind("]") + 1
340	        if start >= 0 and end > start:
341	            try:
342	                triples = json.loads(output_text[start:end])
343	            except json.JSONDecodeError:
344	                logger.warning("Failed to parse output for doc %s", doc_id)
345	                return []
346	        else:
347	            return []
348	
349	    results = []
350	    for t in triples:
351	        if not isinstance(t, dict):
352	            continue
353	        if "head" not in t or "tail" not in t or "relation" not in t:
354	            continue
355	        results.append({
356	            "doc_id": doc_id,
357	            "head": str(t["head"]),
358	            "tail": str(t["tail"]),
359	            "relation": str(t["relation"]),
360	            "evidence": t.get("evidence", []),
361	        })
362	    return results
363	
364	
365	def gold_from_docred(
366	    docred_data: list[dict],
367	) -> list[dict]:
368	    """将 DocRED 原始数据转为评测用 gold 格式。
369	
370	    将 Wikidata property ID (如 "P17") 映射为 relation name (如 "country")，
371	    与模型训练输出格式对齐。
372	    """
373	    from freige.data.docred_processor import DOCRED_REL_INFO
374	
375	    gold = []
376	    for doc in docred_data:
377	        doc_id = doc.get("title", "")
378	        vertex_set = doc["vertexSet"]
379	        for label in doc.get("labels", []):
380	            h_name = vertex_set[label["h"]][0]["name"]
381	            t_name = vertex_set[label["t"]][0]["name"]
382	            gold.append({
383	                "doc_id": doc_id,
384	                "head": h_name,
385	                "tail": t_name,
386	                "relation": DOCRED_REL_INFO.get(label["r"], label["r"]),
387	                "evidence": label.get("evidence", []),
388	            })
389	    return gold
390	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "149a750a-b68d-4d39-be5b-5629308b0e54",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/eval/evaluator.py",
      "content": "\"\"\"DocRED 关系抽取评测模块。\n\n指标:\n  - F1 / Ign-F1: 关系三元组级别 micro-F1，Ign-F1 排除训练集中出现的三元组\n  - Evi-F1: 对正确预测的三元组，计算 evidence 句子级 F1\n  - EDCR: Evidence Distractor Citation Rate，预测 evidence 中非 gold 的比例\n\n输入: 预测列表 + gold 标注列表（每个元素为文档级标注）\n输出: 指标字典\n\"\"\"\n\nimport json\nimport logging\nfrom collections import defaultdict\nfrom typing import Optional\n\nlogger = logging.getLogger(__name__)\n\n\ndef _triple_key(doc_id: str, head: str, tail: str, relation: str) -> tuple:\n    return (doc_id, head.lower().strip(), tail.lower().strip(), relation)\n\n\nclass DocREDEvaluator:\n    \"\"\"DocRED 评测器。\n\n    Args:\n        train_triples: 训练集中的三元组集合，用于计算 Ign-F1。\n                       每个元素为 (doc_title, head_name, tail_name, relation)。\n                       为 None 时 Ign-F1 = F1。\n    \"\"\"\n\n    def __init__(self, train_triples: Optional[set[tuple]] = None):\n        self.train_triples = train_triples or set()\n\n    @classmethod\n    def from_train_file(cls, train_path: str) -> \"DocREDEvaluator\":\n        \"\"\"从训练集 JSON 文件构建 evaluator，自动提取训练集三元组。\"\"\"\n        from freige.data.docred_processor import DOCRED_REL_INFO\n\n        with open(train_path) as f:\n            train_data = json.load(f)\n\n        train_triples = set()\n        for doc in train_data:\n            doc_id = doc.get(\"title\", \"\")\n            vertex_set = doc[\"vertexSet\"]\n            for label in doc.get(\"labels\", []):\n                h_name = vertex_set[label[\"h\"]][0][\"name\"]\n                t_name = vertex_set[label[\"t\"]][0][\"name\"]\n                rel_name = DOCRED_REL_INFO.get(label[\"r\"], label[\"r\"])\n                train_triples.add(\n                    _triple_key(doc_id, h_name, t_name, rel_name)\n                )\n\n        logger.info(\"Loaded %d training triples for Ign-F1\", len(train_triples))\n        return cls(train_triples=train_triples)\n\n    def compute_f1(\n        self,\n        predictions: list[dict],\n        gold: list[dict],\n    ) -> dict:\n        \"\"\"计算 F1 和 Ign-F1。\n\n        Args:\n            predictions: [{\"doc_id\": str, \"head\": str, \"tail\": str,\n                           \"relation\": str, ...}, ...]\n            gold: 同上格式\n\n        Returns:\n            {\"precision\", \"recall\", \"f1\", \"ign_precision\", \"ign_recall\", \"ign_f1\"}\n        \"\"\"\n        pred_set = set()\n        for p in predictions:\n            pred_set.add(_triple_key(\n                p[\"doc_id\"], p[\"head\"], p[\"tail\"], p[\"relation\"]\n            ))\n\n        gold_set = set()\n        for g in gold:\n            gold_set.add(_triple_key(\n                g[\"doc_id\"], g[\"head\"], g[\"tail\"], g[\"relation\"]\n            ))\n\n        tp = pred_set & gold_set\n        precision = len(tp) / len(pred_set) if pred_set else 0.0\n        recall = len(tp) / len(gold_set) if gold_set else 0.0\n        f1 = 2 * precision * recall / (precision + recall) if (precision + recall) > 0 else 0.0\n\n        pred_ign = pred_set - self.train_triples\n        gold_ign = gold_set - self.train_triples\n        tp_ign = pred_ign & gold_ign\n        ign_prec = len(tp_ign) / len(pred_ign) if pred_ign else 0.0\n        ign_rec = len(tp_ign) / len(gold_ign) if gold_ign else 0.0\n        ign_f1 = (\n            2 * ign_prec * ign_rec / (ign_prec + ign_rec)\n            if (ign_prec + ign_rec) > 0 else 0.0\n        )\n\n        return {\n            \"precision\": precision,\n            \"recall\": recall,\n            \"f1\": f1,\n            \"ign_precision\": ign_prec,\n            \"ign_recall\": ign_rec,\n            \"ign_f1\": ign_f1,\n            \"tp\": len(tp),\n            \"pred_count\": len(pred_set),\n            \"gold_count\": len(gold_set),\n        }\n\n    def compute_evi_f1(\n        self,\n        predictions: list[dict],\n        gold: list[dict],\n    ) -> dict:\n        \"\"\"计算 Evidence F1（句子级）。\n\n        仅对正确预测的三元组计算 evidence 匹配。\n\n        Args:\n            predictions: [{\"doc_id\", \"head\", \"tail\", \"relation\",\n                           \"evidence\": [int, ...]}, ...]\n            gold: 同上格式\n\n        Returns:\n            {\"evi_precision\", \"evi_recall\", \"evi_f1\", \"n_evaluated\"}\n        \"\"\"\n        gold_map = {}\n        for g in gold:\n            key = _triple_key(g[\"doc_id\"], g[\"head\"], g[\"tail\"], g[\"relation\"])\n            gold_map.setdefault(key, set()).update(g.get(\"evidence\", []))\n\n        total_tp = 0\n        total_pred = 0\n        total_gold = 0\n        n_evaluated = 0\n\n        for p in predictions:\n            key = _triple_key(p[\"doc_id\"], p[\"head\"], p[\"tail\"], p[\"relation\"])\n            if key not in gold_map:\n                continue\n\n            pred_evi = set(p.get(\"evidence\", []))\n            gold_evi = gold_map[key]\n\n            tp = len(pred_evi & gold_evi)\n            total_tp += tp\n            total_pred += len(pred_evi)\n            total_gold += len(gold_evi)\n            n_evaluated += 1\n\n        evi_prec = total_tp / total_pred if total_pred else 0.0\n        evi_rec = total_tp / total_gold if total_gold else 0.0\n        evi_f1 = (\n            2 * evi_prec * evi_rec / (evi_prec + evi_rec)\n            if (evi_prec + evi_rec) > 0 else 0.0\n        )\n\n        return {\n            \"evi_precision\": evi_prec,\n            \"evi_recall\": evi_rec,\n            \"evi_f1\": evi_f1,\n            \"n_evaluated\": n_evaluated,\n        }\n\n    def compute_edcr(\n        self,\n        predictions: list[dict],\n        gold: list[dict],\n    ) -> dict:\n        \"\"\"计算 EDCR（Evidence Distractor Citation Rate）。\n\n        对所有预测的三元组（不限于正确预测），统计其 evidence 中\n        不在 gold evidence 集合里的句子占比。\n\n        EDCR = |pred_evi - gold_evi| / |pred_evi|，越低越好。\n\n        Args:\n            predictions: [{\"doc_id\", \"head\", \"tail\", \"relation\",\n                           \"evidence\": [int, ...]}, ...]\n            gold: 同上格式\n\n        Returns:\n            {\"edcr\", \"n_distractor_citations\", \"n_total_citations\", \"n_evaluated\"}\n        \"\"\"\n        gold_map = {}\n        for g in gold:\n            key = _triple_key(g[\"doc_id\"], g[\"head\"], g[\"tail\"], g[\"relation\"])\n            gold_map.setdefault(key, set()).update(g.get(\"evidence\", []))\n\n        n_distractor = 0\n        n_total = 0\n        n_evaluated = 0\n\n        for p in predictions:\n            pred_evi = set(p.get(\"evidence\", []))\n            if not pred_evi:\n                continue\n\n            key = _triple_key(p[\"doc_id\"], p[\"head\"], p[\"tail\"], p[\"relation\"])\n            gold_evi = gold_map.get(key, set())\n\n            distractors = pred_evi - gold_evi\n            n_distractor += len(distractors)\n            n_total += len(pred_evi)\n            n_evaluated += 1\n\n        edcr = n_distractor / n_total if n_total else 0.0\n\n        return {\n            \"edcr\": edcr,\n            \"n_distractor_citations\": n_distractor,\n            \"n_total_citations\": n_total,\n            \"n_evaluated\": n_evaluated,\n        }\n\n    def compute_format_compliance(self, raw_outputs: list[dict]) -> dict:\n        \"\"\"计算模型输出的格式合规率。\n\n        Args:\n            raw_outputs: [{\"doc_id\": str, \"raw_text\": str}, ...]\n\n        Returns:\n            dict with format_compliance_rate, field_compliance_rate,\n            evidence_format_rate, and counts.\n        \"\"\"\n        required_fields = {\"head\", \"relation\", \"tail\", \"evidence\"}\n        n_total = len(raw_outputs)\n        n_parseable = 0\n        n_field_complete = 0\n        n_evidence_valid = 0\n\n        for item in raw_outputs:\n            doc_id = item.get(\"doc_id\", \"\")\n            raw_text = item.get(\"raw_text\", \"\")\n\n            parsed = parse_model_output(doc_id, raw_text)\n            if not parsed and not self._is_parseable_json_list(raw_text):\n                continue\n            n_parseable += 1\n\n            triples = self._parse_raw_json_list(raw_text)\n            if triples is None:\n                continue\n\n            all_fields_ok = True\n            all_evidence_ok = True\n            for t in triples:\n                if not isinstance(t, dict) or not required_fields.issubset(t.keys()):\n                    all_fields_ok = False\n                    all_evidence_ok = False\n                    break\n                evi = t.get(\"evidence\")\n                if not isinstance(evi, list) or not all(\n                    isinstance(e, int) and e >= 0 for e in evi\n                ):\n                    all_evidence_ok = False\n\n            if all_fields_ok:\n                n_field_complete += 1\n            if all_fields_ok and all_evidence_ok:\n                n_evidence_valid += 1\n\n        return {\n            \"format_compliance_rate\": n_parseable / n_total if n_total else 0.0,\n            \"field_compliance_rate\": n_field_complete / n_total if n_total else 0.0,\n            \"evidence_format_rate\": n_evidence_valid / n_total if n_total else 0.0,\n            \"n_total\": n_total,\n            \"n_parseable\": n_parseable,\n            \"n_field_complete\": n_field_complete,\n            \"n_evidence_valid\": n_evidence_valid,\n        }\n\n    @staticmethod\n    def _is_parseable_json_list(text: str) -> bool:\n        try:\n            obj = json.loads(text)\n            return isinstance(obj, list)\n        except json.JSONDecodeError:\n            start = text.find(\"[\")\n            end = text.rfind(\"]\") + 1\n            if start >= 0 and end > start:\n                try:\n                    obj = json.loads(text[start:end])\n                    return isinstance(obj, list)\n                except json.JSONDecodeError:\n                    return False\n            return False\n\n    @staticmethod\n    def _parse_raw_json_list(text: str) -> Optional[list]:\n        try:\n            obj = json.loads(text)\n            if isinstance(obj, list):\n                return obj\n        except json.JSONDecodeError:\n            start = text.find(\"[\")\n            end = text.rfind(\"]\") + 1\n            if start >= 0 and end > start:\n                try:\n                    obj = json.loads(text[start:end])\n                    if isinstance(obj, list):\n                        return obj\n                except json.JSONDecodeError:\n                    pass\n        return None\n\n    def evaluate(\n        self,\n        predictions: list[dict],\n        gold: list[dict],\n        raw_outputs: Optional[list[dict]] = None,\n    ) -> dict:\n        \"\"\"运行所有评测指标。\"\"\"\n        f1_metrics = self.compute_f1(predictions, gold)\n        evi_metrics = self.compute_evi_f1(predictions, gold)\n        edcr_metrics = self.compute_edcr(predictions, gold)\n        result = {**f1_metrics, **evi_metrics, **edcr_metrics}\n        if raw_outputs is not None:\n            result.update(self.compute_format_compliance(raw_outputs))\n        return result\n\n\ndef parse_model_output(doc_id: str, output_text: str) -> list[dict]:\n    \"\"\"解析模型输出的 JSON 文本为标准预测格式。\n\n    模型输出格式:\n    [{\"head\": \"...\", \"relation\": \"...\", \"tail\": \"...\", \"evidence\": [0, 3]}, ...]\n\n    Returns:\n        标准预测列表，每个元素包含 doc_id\n    \"\"\"\n    try:\n        triples = json.loads(output_text)\n    except json.JSONDecodeError:\n        start = output_text.find(\"[\")\n        end = output_text.rfind(\"]\") + 1\n        if start >= 0 and end > start:\n            try:\n                triples = json.loads(output_text[start:end])\n            except json.JSONDecodeError:\n                logger.warning(\"Failed to parse output for doc %s\", doc_id)\n                return []\n        else:\n            return []\n\n    results = []\n    for t in triples:\n        if not isinstance(t, dict):\n            continue\n        if \"head\" not in t or \"tail\" not in t or \"relation\" not in t:\n            continue\n        results.append({\n            \"doc_id\": doc_id,\n            \"head\": str(t[\"head\"]),\n            \"tail\": str(t[\"tail\"]),\n            \"relation\": str(t[\"relation\"]),\n            \"evidence\": t.get(\"evidence\", []),\n        })\n    return results\n\n\ndef gold_from_docred(\n    docred_data: list[dict],\n) -> list[dict]:\n    \"\"\"将 DocRED 原始数据转为评测用 gold 格式。\n\n    将 Wikidata property ID (如 \"P17\") 映射为 relation name (如 \"country\")，\n    与模型训练输出格式对齐。\n    \"\"\"\n    from freige.data.docred_processor import DOCRED_REL_INFO\n\n    gold = []\n    for doc in docred_data:\n        doc_id = doc.get(\"title\", \"\")\n        vertex_set = doc[\"vertexSet\"]\n        for label in doc.get(\"labels\", []):\n            h_name = vertex_set[label[\"h\"]][0][\"name\"]\n            t_name = vertex_set[label[\"t\"]][0][\"name\"]\n            gold.append({\n                \"doc_id\": doc_id,\n                \"head\": h_name,\n                \"tail\": t_name,\n                \"relation\": DOCRED_REL_INFO.get(label[\"r\"], label[\"r\"]),\n                \"evidence\": label.get(\"evidence\", []),\n            })\n    return gold\n",
      "numLines": 390,
      "startLine": 1,
      "totalLines": 390
    }
  }
}
```

</details>

---

### Assistant

_source line 55_

<details><summary>Logged reasoning block</summary>

```text
Now I have the full picture. Let me also check the eval/inference.py locally to understand the generate interface better.

Actually, I've already read the server version which is complete. Let me now check the local version.

Actually, the key issue is clear. Let me now write the modification. I need to add:

1. A `TaskEvalCallback` that runs inference on dev set at the end of each epoch
2. Dev data loading using `DocREDProcessor` (same as SFT trainer)
3. Wire it up with appropriate args

Here's my plan:

### Modifications to rsft_trainer.py:


I'll need to import the callback base class, data processor, evaluator, and output parsing utilities. Then I'll add command-line arguments for the eval data directory, evaluation frequency, dataset size limits, and generation parameters. I'll create a custom callback class that handles the evaluation logic and integrate it with the trainer configuration.

For the callback implementation, I need to run generation on a subset of the dev set at regular intervals, parse the model outputs, compute the DocRED metrics, and log everything to W&B. The tricky part is managing the model state during training—I'll need to temporarily disable gradient checkpointing and enable the KV cache for generation, switch to eval mode for LoRA compatibility, and ensure only the primary process runs evaluation in distributed setups to avoid redundant computation.

Now I'm looking at the inference module to see what I can reuse. The `prepare_eval_data` and `run_inference` functions handle prompt construction and output parsing, which would save me from reimplementing that logic. But there's a complication: the inference module expects the model in eval mode with gradient checkpointing disabled, while during training the model is in training mode with checkpointing active. I'll need to save the current training state, temporarily adjust these settings for inference, then restore everything afterward.

The other issue is that with DeepSpeed or Accelerate, the model is wrapped, so I need to handle that properly with `unwrap_model`. Actually, maybe I should take a lighter approach—just import the data preparation and evaluation utilities directly, then write a simple generation loop in the callback itself rather than trying to reuse the full inference pipeline. Let me check what's actually available in the local eval module first, since the server version had inference.py but I'm not sure if it exists here.

Looking at the file structure, there's no inference.py locally, though it does exist on the server. That's fine since the callback will run on the server anyway. Now I'm designing the callback class to handle end-of-epoch evaluation by generating predictions on the dev set and computing the task-level metrics.

Defining the callback class... Moving the inputs to the model's device, then generating predictions with the configured parameters while preventing gradient computation. I'm extracting just the newly generated tokens, decoding them to text, and parsing the output into structured triples. After collecting all predictions, I evaluate them against the gold standard and log the metrics to Weights & Biases. I need to restore the model's training state after evaluation, making sure to disable caching and re-enable gradient checkpointing. There's a subtlety with accelerate/DeepSpeed where the model might be wrapped, so I should use the unwrap function to access the actual model. I'm also reviewing how the evaluation data is structured from the inference module to ensure I'm handling the data correctly.

Writing evaluation data prep... I'm realizing I can simplify this by using the existing `prepare_eval_data` function from the inference module on the server rather than reimplementing the data preparation logic myself. Let me check what that function returns and whether the evaluator is compatible with it. I'm thinking through the import strategy and realizing that pulling from inference.py might create circular dependencies, though the existing imports in rsft_trainer.py should handle it. For evaluation loss tracking, I need to decide whether to use a held-out portion of the RSFT data itself or pull from the original DocRED dev set, since the RSFT training data comes from CED-filtered generations rather than raw DocRED samples.

The DocRED dev set makes more sense as the evaluation target, but it requires the DocREDProcessor and potentially a data directory path. Since the user's main focus is on rel_f1 and evidence quality metrics, I'll prioritize those and treat standard eval_loss as secondary. My plan is to add the necessary imports and command-line arguments to support loading the DocRED dev set for evaluation.

Adding callback and argument handling...

I need to think through the model unwrapping issue though—when using DeepSpeed, the model passed to the callback might be wrapped or sharded, so I should use `trainer.accelerator.unwrap_model()` to get the base model for generation. But the callback signature only gives me the model directly, not the trainer object. Let me check if I can access the trainer through the callback or if I need to pass it explicitly when creating the callback instance.

For safety with DeepSpeed ZeRO-2, I should only run evaluation on rank 0 to avoid duplication, and since ZeRO-2 keeps all parameters on GPU during the forward pass, generation should work fine. I'll keep the implementation simple: rank 0 only, single-sample generation without batching, and log results to W&B. I also need to check whether `enable_thinking=False` should be passed during generation based on how the SFT trainer handles it.

Looking at how the chat template works, the thinking mode is controlled by the prompt tokens themselves rather than a generate parameter, so since I'm constructing the prompt with `enable_thinking=False`, the generation should naturally be in non-thinking mode. For generation, I need to use `add_generation_prompt=True` to add the assistant turn start token, and I should examine how the inference code builds the prompt to handle the Qwen3 thinking vs non-thinking modes properly.

Building the prompt function...

Now I need to figure out where the eval data comes from. The DocREDProcessor expects a data directory, and I see the trainer accepts `--data_dir` while the inference module uses `--data_path`, so I'll add a separate `--eval_data_dir` argument to handle evaluation data.

I'm going to write a helper function that loads and prepares the evaluation dataset, keeping everything self-contained within the trainer file to avoid unnecessary dependencies.

Writing the eval data preparation function... Building the evaluation pipeline...

Now I need to check what the processor actually returns to understand the structure of the samples I'm working with.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "10754efc-dbd0-4194-8804-5a4e4410684f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JGtBLBPRTiX2ekqS7F4YfP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5507,
      "cache_read_input_tokens": 53505,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5507
      },
      "output_tokens": 9,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 56_

Let me check the DocREDProcessor interface and the data directory structure.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "6b3cf3e0-2e8e-4866-9a54-b25a1c9b9eaa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JGtBLBPRTiX2ekqS7F4YfP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5507,
      "cache_read_input_tokens": 53505,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5507
      },
      "output_tokens": 9,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 57_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01NQ5ghyVnihs6U2YH1obUaC`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "head -80 /root/autodl-tmp/freige/freige/data/docred_processor.py",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "94de3d31-16fe-4df6-9f3d-3cbf79685f6d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JGtBLBPRTiX2ekqS7F4YfP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5507,
      "cache_read_input_tokens": 53505,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5507
      },
      "output_tokens": 9,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 58 · 2026-05-15T02:27:59.538Z_

<details><summary>↩ Tool result · `toolu_01NQ5ghyVnihs6U2YH1obUaC`</summary>

```text
{"result":"{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"head: cannot open '/root/autodl-tmp/freige/freige/data/docred_processor.py' for reading: No such file or directory\\n\", \"return_code\": 1}, \"error\": \"exit code 1\", \"metadata\": {\"elapsed_seconds\": 0.32}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "e8d82681-d902-4cb3-aa13-d0690b6a3269",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"head: cannot open '/root/autodl-tmp/freige/freige/data/docred_processor.py' for reading: No such file or directory\\\\n\\\", \\\"return_code\\\": 1}, \\\"error\\\": \\\"exit code 1\\\", \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.32}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {\"stdout\": \"\", \"stderr\": \"head: cannot open '/root/autodl-tmp/freige/freige/data/docred_processor.py' for reading: No such file or directory\\n\", \"return_code\": 1}, \"error\": \"exit code 1\", \"metadata\": {\"elapsed_seconds\": 0.32}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 59_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01PfZkuF2PBWVLPa3yuPBHrd`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "grep -n \"def format_sft_sample\\|def process\\|def group_by_document\\|class DocREDProcessor\\|SPLIT_FILENAMES\\|data_dir\" /root/autodl-tmp/freige/freige/data/docred_processor.py",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "97de44e0-0ce5-478d-b2a6-5eea102b3368",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JGtBLBPRTiX2ekqS7F4YfP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5507,
      "cache_read_input_tokens": 53505,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5507
      },
      "output_tokens": 9,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 60 · 2026-05-15T02:28:00.696Z_

<details><summary>↩ Tool result · `toolu_01PfZkuF2PBWVLPa3yuPBHrd`</summary>

```text
{"result":"{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "5a354273-a0ea-461f-a0fa-c7a2589972df",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": false, \\\"data\\\": {}, \\\"error\\\": \\\"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\\\", \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": false, \"data\": {}, \"error\": \"[ssh_read_only] Command blocked: Shell metacharacter '|' not allowed in read-only mode. Only read-only commands are permitted (cat/ls/grep/find/tail/head/wc/stat/etc.).\", \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 61_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01PTX6oFGFCAXj6bMGtjLN73`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "find /root/autodl-tmp -name \"dev.json\" -path \"*docred*\" -o -name \"dev.json\" -path \"*data*\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "39dbe4e7-6120-4aec-9088-5fda690718a8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JGtBLBPRTiX2ekqS7F4YfP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5507,
      "cache_read_input_tokens": 53505,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5507
      },
      "output_tokens": 9,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 62 · 2026-05-15T02:28:01.940Z_

<details><summary>↩ Tool result · `toolu_01PTX6oFGFCAXj6bMGtjLN73`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/data/docred/dev.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.31}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "07307333-7dec-455f-9ef5-acae19529919",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"/root/autodl-tmp/data/docred/dev.json\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.31}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"/root/autodl-tmp/data/docred/dev.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.31}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 63_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01BG575m4FR1G6E64FXTEn1a`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "cat /root/autodl-tmp/freige/data/docred_processor.py",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "120f6788-3490-46d6-8196-5fd51653264b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GjJ37LZnUXzdRKjLBzvCsr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5898,
      "cache_read_input_tokens": 59012,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5898
      },
      "output_tokens": 65,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 64 · 2026-05-15T02:28:06.017Z_

<details><summary>↩ Tool result · `toolu_01BG575m4FR1G6E64FXTEn1a`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"DocRED 数据预处理模块。\\n\\n加载 DocRED 数据集（train_annotated / dev / test），解析实体、关系、\\nevidence 标注，构建含 hard negatives 的训练样本。\\n\\n输入: DocRED JSON 文件目录或 HuggingFace dataset\\n输出: List[RelationSample]，每个样本包含 gold evidence 和 hard negative 句子\\n依赖: datasets (可选，用于 HF 加载)\\n\\\"\\\"\\\"\\n\\nimport json\\nimport logging\\nfrom dataclasses import dataclass, field\\nfrom pathlib import Path\\nfrom typing import Optional\\n\\nlogger = logging.getLogger(__name__)\\n\\nDOCRED_REL_INFO = {\\n    \\\"P6\\\": \\\"head of government\\\", \\\"P17\\\": \\\"country\\\", \\\"P19\\\": \\\"place of birth\\\",\\n    \\\"P20\\\": \\\"place of death\\\", \\\"P22\\\": \\\"father\\\", \\\"P25\\\": \\\"mother\\\",\\n    \\\"P26\\\": \\\"spouse\\\", \\\"P27\\\": \\\"country of citizenship\\\", \\\"P30\\\": \\\"continent\\\",\\n    \\\"P31\\\": \\\"instance of\\\", \\\"P35\\\": \\\"head of state\\\", \\\"P36\\\": \\\"capital\\\",\\n    \\\"P37\\\": \\\"official language\\\", \\\"P39\\\": \\\"position held\\\", \\\"P40\\\": \\\"child\\\",\\n    \\\"P50\\\": \\\"author\\\", \\\"P54\\\": \\\"member of sports team\\\", \\\"P57\\\": \\\"director\\\",\\n    \\\"P58\\\": \\\"screenwriter\\\", \\\"P69\\\": \\\"educated at\\\", \\\"P86\\\": \\\"composer\\\",\\n    \\\"P102\\\": \\\"member of political party\\\", \\\"P108\\\": \\\"employer\\\",\\n    \\\"P112\\\": \\\"founded by\\\", \\\"P118\\\": \\\"league\\\", \\\"P123\\\": \\\"publisher\\\",\\n    \\\"P127\\\": \\\"owned by\\\",\\n    \\\"P131\\\": \\\"located in the administrative territorial entity\\\",\\n    \\\"P136\\\": \\\"genre\\\", \\\"P137\\\": \\\"operator\\\", \\\"P140\\\": \\\"religion\\\",\\n    \\\"P150\\\": \\\"contains administrative territorial entity\\\",\\n    \\\"P155\\\": \\\"follows\\\", \\\"P156\\\": \\\"followed by\\\",\\n    \\\"P159\\\": \\\"headquarters location\\\", \\\"P161\\\": \\\"cast member\\\",\\n    \\\"P162\\\": \\\"producer\\\", \\\"P166\\\": \\\"award received\\\", \\\"P170\\\": \\\"creator\\\",\\n    \\\"P171\\\": \\\"parent taxon\\\", \\\"P172\\\": \\\"ethnic group\\\", \\\"P175\\\": \\\"performer\\\",\\n    \\\"P176\\\": \\\"manufacturer\\\", \\\"P178\\\": \\\"developer\\\", \\\"P179\\\": \\\"series\\\",\\n    \\\"P190\\\": \\\"sister city\\\", \\\"P194\\\": \\\"legislative body\\\",\\n    \\\"P205\\\": \\\"basin country\\\",\\n    \\\"P206\\\": \\\"located in or next to body of water\\\",\\n    \\\"P241\\\": \\\"military branch\\\", \\\"P264\\\": \\\"record label\\\",\\n    \\\"P272\\\": \\\"production company\\\", \\\"P276\\\": \\\"location\\\",\\n    \\\"P279\\\": \\\"subclass of\\\", \\\"P355\\\": \\\"subsidiary\\\", \\\"P361\\\": \\\"part of\\\",\\n    \\\"P364\\\": \\\"original language of work\\\", \\\"P400\\\": \\\"platform\\\",\\n    \\\"P403\\\": \\\"mouth of the watercourse\\\", \\\"P449\\\": \\\"original network\\\",\\n    \\\"P463\\\": \\\"member of\\\", \\\"P488\\\": \\\"chairperson\\\",\\n    \\\"P495\\\": \\\"country of origin\\\", \\\"P527\\\": \\\"has part\\\",\\n    \\\"P551\\\": \\\"residence\\\", \\\"P569\\\": \\\"date of birth\\\",\\n    \\\"P570\\\": \\\"date of death\\\", \\\"P571\\\": \\\"inception\\\",\\n    \\\"P576\\\": \\\"dissolved, abolished or demolished\\\",\\n    \\\"P577\\\": \\\"publication date\\\", \\\"P580\\\": \\\"start time\\\",\\n    \\\"P582\\\": \\\"end time\\\", \\\"P585\\\": \\\"point in time\\\", \\\"P607\\\": \\\"conflict\\\",\\n    \\\"P674\\\": \\\"characters\\\", \\\"P676\\\": \\\"lyrics by\\\",\\n    \\\"P706\\\": \\\"located on terrain feature\\\", \\\"P710\\\": \\\"participant\\\",\\n    \\\"P737\\\": \\\"influenced by\\\", \\\"P740\\\": \\\"location of formation\\\",\\n    \\\"P749\\\": \\\"parent organization\\\", \\\"P800\\\": \\\"notable work\\\",\\n    \\\"P807\\\": \\\"separated from\\\", \\\"P840\\\": \\\"narrative location\\\",\\n    \\\"P937\\\": \\\"work location\\\", \\\"P1001\\\": \\\"applies to jurisdiction\\\",\\n    \\\"P1056\\\": \\\"product or material produced\\\",\\n    \\\"P1198\\\": \\\"unemployment rate\\\", \\\"P1336\\\": \\\"territory claimed by\\\",\\n    \\\"P1344\\\": \\\"participant of\\\", \\\"P1365\\\": \\\"replaces\\\",\\n    \\\"P1366\\\": \\\"replaced by\\\", \\\"P1376\\\": \\\"capital of\\\",\\n    \\\"P1412\\\": \\\"languages spoken, written or signed\\\",\\n    \\\"P1441\\\": \\\"present in work\\\", \\\"P3373\\\": \\\"sibling\\\",\\n}\\n\\nSPLIT_FILENAMES = {\\n    \\\"train\\\": \\\"train_annotated.json\\\",\\n    \\\"train_annotated\\\": \\\"train_annotated.json\\\",\\n    \\\"train_distant\\\": \\\"train_distant.json\\\",\\n    \\\"dev\\\": \\\"dev.json\\\",\\n    \\\"test\\\": \\\"test.json\\\",\\n}\\n\\n\\n@dataclass\\nclass EntityMention:\\n    name: str\\n    sent_id: int\\n    pos: tuple[int, int]\\n    entity_type: str\\n\\n\\n@dataclass\\nclass Entity:\\n    entity_id: int\\n    mentions: list[EntityMention]\\n\\n    @property\\n    def name(self) -> str:\\n        return self.mentions[0].name\\n\\n    @property\\n    def sent_ids(self) -> set[int]:\\n        return {m.sent_id for m in self.mentions}\\n\\n\\n@dataclass\\nclass RelationSample:\\n    doc_id: str\\n    document: str\\n    sents: list[str]\\n    head: Entity\\n    tail: Entity\\n    relation: str\\n    relation_name: str\\n    evidence_sent_ids: list[int]\\n    hard_negative_sent_ids: list[int]\\n\\n\\nclass DocREDProcessor:\\n    \\\"\\\"\\\"DocRED 数据加载与预处理。\\\"\\\"\\\"\\n\\n    def __init__(self, data_dir: Optional[str] = None):\\n        self.data_dir\\n\\n... [截断: 输出过长，省略 4058 字符] ...\\n\\ntionSample]] = {}\\n        for s in samples:\\n            groups.setdefault(s.doc_id, []).append(s)\\n        return groups\\n\\n    def format_sft_sample(\\n        self, doc_samples: list[RelationSample]\\n    ) -> dict[str, str]:\\n        if not doc_samples:\\n            return {\\\"instruction\\\": \\\"\\\", \\\"input\\\": \\\"\\\", \\\"output\\\": \\\"\\\"}\\n\\n        ref = doc_samples[0]\\n        numbered_sents = \\\"\\\\n\\\".join(\\n            f\\\"[{i}] {s}\\\" for i, s in enumerate(ref.sents)\\n        )\\n\\n        entity_list = set()\\n        for s in doc_samples:\\n            entity_list.add(f\\\"{s.head.name} ({s.head.mentions[0].entity_type})\\\")\\n            entity_list.add(f\\\"{s.tail.name} ({s.tail.mentions[0].entity_type})\\\")\\n        entity_str = \\\", \\\".join(sorted(entity_list))\\n\\n        instruction = (\\n            \\\"Extract all relation triples from the document. \\\"\\n            \\\"For each triple, provide the head entity, relation, tail entity, \\\"\\n            \\\"and the sentence IDs that serve as evidence. \\\"\\n            \\\"Output as a JSON list.\\\"\\n        )\\n\\n        input_text = (\\n            f\\\"Document:\\\\n{numbered_sents}\\\\n\\\\n\\\"\\n            f\\\"Entities: {entity_str}\\\"\\n        )\\n\\n        triples = []\\n        for s in doc_samples:\\n            triples.append({\\n                \\\"head\\\": s.head.name,\\n                \\\"relation\\\": s.relation_name,\\n                \\\"tail\\\": s.tail.name,\\n                \\\"evidence\\\": s.evidence_sent_ids,\\n            })\\n        output_text = json.dumps(triples, ensure_ascii=False)\\n\\n        return {\\n            \\\"instruction\\\": instruction,\\n            \\\"input\\\": input_text,\\n            \\\"output\\\": output_text,\\n        }\\n\\n\\ndef download_docred(output_dir: str) -> Path:\\n    from datasets import load_dataset\\n\\n    out = Path(output_dir)\\n    out.mkdir(parents=True, exist_ok=True)\\n\\n    ds = load_dataset(\\\"thunlp/docred\\\", trust_remote_code=True)\\n    for split_name, split_ds in ds.items():\\n        fname = SPLIT_FILENAMES.get(split_name, f\\\"{split_name}.json\\\")\\n        path = out / fname\\n        data = [row for row in split_ds]\\n        with open(path, \\\"w\\\") as f:\\n            json.dump(data, f, ensure_ascii=False)\\n        logger.info(\\\"Saved %d documents to %s\\\", len(data), path)\\n\\n    return out\\n\\n\\nif __name__ == \\\"__main__\\\":\\n    import argparse\\n    import sys\\n\\n    logging.basicConfig(level=logging.INFO, format=\\\"%(levelname)s: %(message)s\\\")\\n\\n    parser = argparse.ArgumentParser(description=\\\"DocRED 数据预处理\\\")\\n    parser.add_argument(\\\"--data_dir\\\", type=str, default=None)\\n    parser.add_argument(\\\"--split\\\", type=str, default=\\\"dev\\\")\\n    parser.add_argument(\\\"--output\\\", type=str, default=None)\\n    parser.add_argument(\\\"--download\\\", action=\\\"store_true\\\")\\n    args = parser.parse_args()\\n\\n    if args.download:\\n        if not args.data_dir:\\n            print(\\\"--download requires --data_dir\\\", file=sys.stderr)\\n            sys.exit(1)\\n        download_docred(args.data_dir)\\n        sys.exit(0)\\n\\n    processor = DocREDProcessor(data_dir=args.data_dir)\\n    samples = processor.process(args.split)\\n\\n    print(f\\\"Total samples: {len(samples)}\\\")\\n    has_hard_neg = sum(1 for s in samples if s.hard_negative_sent_ids)\\n    print(f\\\"Samples with hard negatives: {has_hard_neg} \\\"\\n          f\\\"({has_hard_neg / len(samples) * 100:.1f}%)\\\")\\n\\n    if samples:\\n        s = samples[0]\\n        print(f\\\"\\\\nExample: {s.head.name} --[{s.relation_name}]--> {s.tail.name}\\\")\\n        print(f\\\"  Evidence sents: {s.evidence_sent_ids}\\\")\\n        print(f\\\"  Hard negatives: {s.hard_negative_sent_ids}\\\")\\n\\n    if args.output:\\n        out_data = []\\n        for s in samples:\\n            out_data.append({\\n                \\\"doc_id\\\": s.doc_id,\\n                \\\"head\\\": s.head.name,\\n                \\\"tail\\\": s.tail.name,\\n                \\\"relation\\\": s.relation,\\n                \\\"relation_name\\\": s.relation_name,\\n                \\\"evidence_sent_ids\\\": s.evidence_sent_ids,\\n                \\\"hard_negative_sent_ids\\\": s.hard_negative_sent_ids,\\n            })\\n        with open(args.output, \\\"w\\\") as f:\\n            json.dump(out_data, f, ensure_ascii=False, indent=2)\\n        print(f\\\"Saved to {args.output}\\\")\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.31}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "c4ccb3e2-7c29-4069-bf65-7a0cc82a898d",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\\\\\"\\\\\\\"\\\\\\\"DocRED 数据预处理模块。\\\\n\\\\n加载 DocRED 数据集（train_annotated / dev / test），解析实体、关系、\\\\nevidence 标注，构建含 hard negatives 的训练样本。\\\\n\\\\n输入: DocRED JSON 文件目录或 HuggingFace dataset\\\\n输出: List[RelationSample]，每个样本包含 gold evidence 和 hard negative 句子\\\\n依赖: datasets (可选，用于 HF 加载)\\\\n\\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\nimport json\\\\nimport logging\\\\nfrom dataclasses import dataclass, field\\\\nfrom pathlib import Path\\\\nfrom typing import Optional\\\\n\\\\nlogger = logging.getLogger(__name__)\\\\n\\\\nDOCRED_REL_INFO = {\\\\n    \\\\\\\"P6\\\\\\\": \\\\\\\"head of government\\\\\\\", \\\\\\\"P17\\\\\\\": \\\\\\\"country\\\\\\\", \\\\\\\"P19\\\\\\\": \\\\\\\"place of birth\\\\\\\",\\\\n    \\\\\\\"P20\\\\\\\": \\\\\\\"place of death\\\\\\\", \\\\\\\"P22\\\\\\\": \\\\\\\"father\\\\\\\", \\\\\\\"P25\\\\\\\": \\\\\\\"mother\\\\\\\",\\\\n    \\\\\\\"P26\\\\\\\": \\\\\\\"spouse\\\\\\\", \\\\\\\"P27\\\\\\\": \\\\\\\"country of citizenship\\\\\\\", \\\\\\\"P30\\\\\\\": \\\\\\\"continent\\\\\\\",\\\\n    \\\\\\\"P31\\\\\\\": \\\\\\\"instance of\\\\\\\", \\\\\\\"P35\\\\\\\": \\\\\\\"head of state\\\\\\\", \\\\\\\"P36\\\\\\\": \\\\\\\"capital\\\\\\\",\\\\n    \\\\\\\"P37\\\\\\\": \\\\\\\"official language\\\\\\\", \\\\\\\"P39\\\\\\\": \\\\\\\"position held\\\\\\\", \\\\\\\"P40\\\\\\\": \\\\\\\"child\\\\\\\",\\\\n    \\\\\\\"P50\\\\\\\": \\\\\\\"author\\\\\\\", \\\\\\\"P54\\\\\\\": \\\\\\\"member of sports team\\\\\\\", \\\\\\\"P57\\\\\\\": \\\\\\\"director\\\\\\\",\\\\n    \\\\\\\"P58\\\\\\\": \\\\\\\"screenwriter\\\\\\\", \\\\\\\"P69\\\\\\\": \\\\\\\"educated at\\\\\\\", \\\\\\\"P86\\\\\\\": \\\\\\\"composer\\\\\\\",\\\\n    \\\\\\\"P102\\\\\\\": \\\\\\\"member of political party\\\\\\\", \\\\\\\"P108\\\\\\\": \\\\\\\"employer\\\\\\\",\\\\n    \\\\\\\"P112\\\\\\\": \\\\\\\"founded by\\\\\\\", \\\\\\\"P118\\\\\\\": \\\\\\\"league\\\\\\\", \\\\\\\"P123\\\\\\\": \\\\\\\"publisher\\\\\\\",\\\\n    \\\\\\\"P127\\\\\\\": \\\\\\\"owned by\\\\\\\",\\\\n    \\\\\\\"P131\\\\\\\": \\\\\\\"located in the administrative territorial entity\\\\\\\",\\\\n    \\\\\\\"P136\\\\\\\": \\\\\\\"genre\\\\\\\", \\\\\\\"P137\\\\\\\": \\\\\\\"operator\\\\\\\", \\\\\\\"P140\\\\\\\": \\\\\\\"religion\\\\\\\",\\\\n    \\\\\\\"P150\\\\\\\": \\\\\\\"contains administrative territorial entity\\\\\\\",\\\\n    \\\\\\\"P155\\\\\\\": \\\\\\\"follows\\\\\\\", \\\\\\\"P156\\\\\\\": \\\\\\\"followed by\\\\\\\",\\\\n    \\\\\\\"P159\\\\\\\": \\\\\\\"headquarters location\\\\\\\", \\\\\\\"P161\\\\\\\": \\\\\\\"cast member\\\\\\\",\\\\n    \\\\\\\"P162\\\\\\\": \\\\\\\"producer\\\\\\\", \\\\\\\"P166\\\\\\\": \\\\\\\"award received\\\\\\\", \\\\\\\"P170\\\\\\\": \\\\\\\"creator\\\\\\\",\\\\n    \\\\\\\"P171\\\\\\\": \\\\\\\"parent taxon\\\\\\\", \\\\\\\"P172\\\\\\\": \\\\\\\"ethnic group\\\\\\\", \\\\\\\"P175\\\\\\\": \\\\\\\"performer\\\\\\\",\\\\n    \\\\\\\"P176\\\\\\\": \\\\\\\"manufacturer\\\\\\\", \\\\\\\"P178\\\\\\\": \\\\\\\"developer\\\\\\\", \\\\\\\"P179\\\\\\\": \\\\\\\"series\\\\\\\",\\\\n    \\\\\\\"P190\\\\\\\": \\\\\\\"sister city\\\\\\\", \\\\\\\"P194\\\\\\\": \\\\\\\"legislative body\\\\\\\",\\\\n    \\\\\\\"P205\\\\\\\": \\\\\\\"basin country\\\\\\\",\\\\n    \\\\\\\"P206\\\\\\\": \\\\\\\"located in or next to body of water\\\\\\\",\\\\n    \\\\\\\"P241\\\\\\\": \\\\\\\"military branch\\\\\\\", \\\\\\\"P264\\\\\\\": \\\\\\\"record label\\\\\\\",\\\\n    \\\\\\\"P272\\\\\\\": \\\\\\\"production company\\\\\\\", \\\\\\\"P276\\\\\\\": \\\\\\\"location\\\\\\\",\\\\n    \\\\\\\"P279\\\\\\\": \\\\\\\"subclass of\\\\\\\", \\\\\\\"P355\\\\\\\": \\\\\\\"subsidiary\\\\\\\", \\\\\\\"P361\\\\\\\": \\\\\\\"part of\\\\\\\",\\\\n    \\\\\\\"P364\\\\\\\": \\\\\\\"original language of work\\\\\\\", \\\\\\\"P400\\\\\\\": \\\\\\\"platform\\\\\\\",\\\\n    \\\\\\\"P403\\\\\\\": \\\\\\\"mouth of the watercourse\\\\\\\", \\\\\\\"P449\\\\\\\": \\\\\\\"original network\\\\\\\",\\\\n    \\\\\\\"P463\\\\\\\": \\\\\\\"member of\\\\\\\", \\\\\\\"P488\\\\\\\": \\\\\\\"chairperson\\\\\\\",\\\\n    \\\\\\\"P495\\\\\\\": \\\\\\\"country of origin\\\\\\\", \\\\\\\"P527\\\\\\\": \\\\\\\"has part\\\\\\\",\\\\n    \\\\\\\"P551\\\\\\\": \\\\\\\"residence\\\\\\\", \\\\\\\"P569\\\\\\\": \\\\\\\"date of birth\\\\\\\",\\\\n    \\\\\\\"P570\\\\\\\": \\\\\\\"date of death\\\\\\\", \\\\\\\"P571\\\\\\\": \\\\\\\"inception\\\\\\\",\\\\n    \\\\\\\"P576\\\\\\\": \\\\\\\"dissolved, abolished or demolished\\\\\\\",\\\\n    \\\\\\\"P577\\\\\\\": \\\\\\\"publication date\\\\\\\", \\\\\\\"P580\\\\\\\": \\\\\\\"start time\\\\\\\",\\\\n    \\\\\\\"P582\\\\\\\": \\\\\\\"end time\\\\\\\", \\\\\\\"P585\\\\\\\": \\\\\\\"point in time\\\\\\\", \\\\\\\"P607\\\\\\\": \\\\\\\"conflict\\\\\\\",\\\\n    \\\\\\\"P674\\\\\\\": \\\\\\\"characters\\\\\\\", \\\\\\\"P676\\\\\\\": \\\\\\\"lyrics by\\\\\\\",\\\\n    \\\\\\\"P706\\\\\\\": \\\\\\\"located on terrain feature\\\\\\\", \\\\\\\"P710\\\\\\\": \\\\\\\"participant\\\\\\\",\\\\n    \\\\\\\"P737\\\\\\\": \\\\\\\"influenced by\\\\\\\", \\\\\\\"P740\\\\\\\": \\\\\\\"location of formation\\\\\\\",\\\\n    \\\\\\\"P749\\\\\\\": \\\\\\\"parent organization\\\\\\\", \\\\\\\"P800\\\\\\\": \\\\\\\"notable work\\\\\\\",\\\\n    \\\\\\\"P807\\\\\\\": \\\\\\\"separated from\\\\\\\", \\\\\\\"P840\\\\\\\": \\\\\\\"narrative location\\\\\\\",\\\\n    \\\\\\\"P937\\\\\\\": \\\\\\\"work location\\\\\\\", \\\\\\\"P1001\\\\\\\": \\\\\\\"applies to jurisdiction\\\\\\\",\\\\n    \\\\\\\"P1056\\\\\\\": \\\\\\\"product or material produced\\\\\\\",\\\\n    \\\\\\\"P1198\\\\\\\": \\\\\\\"unemployment rate\\\\\\\", \\\\\\\"P1336\\\\\\\": \\\\\\\"territory claimed by\\\\\\\",\\\\n    \\\\\\\"P1344\\\\\\\": \\\\\\\"participant of\\\\\\\", \\\\\\\"P1365\\\\\\\": \\\\\\\"replaces\\\\\\\",\\\\n    \\\\\\\"P1366\\\\\\\": \\\\\\\"replaced by\\\\\\\", \\\\\\\"P1376\\\\\\\": \\\\\\\"capital of\\\\\\\",\\\\n    \\\\\\\"P1412\\\\\\\": \\\\\\\"languages spoken, written or signed\\\\\\\",\\\\n    \\\\\\\"P1441\\\\\\\": \\\\\\\"present in work\\\\\\\", \\\\\\\"P3373\\\\\\\": \\\\\\\"sibling\\\\\\\",\\\\n}\\\\n\\\\nSPLIT_FILENAMES = {\\\\n    \\\\\\\"train\\\\\\\": \\\\\\\"train_annotated.json\\\\\\\",\\\\n    \\\\\\\"train_annotated\\\\\\\": \\\\\\\"train_annotated.json\\\\\\\",\\\\n    \\\\\\\"train_distant\\\\\\\": \\\\\\\"train_distant.json\\\\\\\",\\\\n    \\\\\\\"dev\\\\\\\": \\\\\\\"dev.json\\\\\\\",\\\\n    \\\\\\\"test\\\\\\\": \\\\\\\"test.json\\\\\\\",\\\\n}\\\\n\\\\n\\\\n@dataclass\\\\nclass EntityMention:\\\\n    name: str\\\\n    sent_id: int\\\\n    pos: tuple[int, int]\\\\n    entity_type: str\\\\n\\\\n\\\\n@dataclass\\\\nclass Entity:\\\\n    entity_id: int\\\\n    mentions: list[EntityMention]\\\\n\\\\n    @property\\\\n    def name(self) -> str:\\\\n        return self.mentions[0].name\\\\n\\\\n    @property\\\\n    def sent_ids(self) -> set[int]:\\\\n        return {m.sent_id for m in self.mentions}\\\\n\\\\n\\\\n@dataclass\\\\nclass RelationSample:\\\\n    doc_id: str\\\\n    document: str\\\\n    sents: list[str]\\\\n    head: Entity\\\\n    tail: Entity\\\\n    relation: str\\\\n    relation_name: str\\\\n    evidence_sent_ids: list[int]\\\\n    hard_negative_sent_ids: list[int]\\\\n\\\\n\\\\nclass DocREDProcessor:\\\\n    \\\\\\\"\\\\\\\"\\\\\\\"DocRED 数据加载与预处理。\\\\\\\"\\\\\\\"\\\\\\\"\\\\n\\\\n    def __init__(self, data_dir: Optional[str] = None):\\\\n        self.data_dir\\\\n\\\\n... [截断: 输出过长，省略 4058 字符] ...\\\\n\\\\ntionSample]] = {}\\\\n        for s in samples:\\\\n            groups.setdefault(s.doc_id, []).append(s)\\\\n        return groups\\\\n\\\\n    def format_sft_sample(\\\\n        self, doc_samples: list[RelationSample]\\\\n    ) -> dict[str, str]:\\\\n        if not doc_samples:\\\\n            return {\\\\\\\"instruction\\\\\\\": \\\\\\\"\\\\\\\", \\\\\\\"input\\\\\\\": \\\\\\\"\\\\\\\", \\\\\\\"output\\\\\\\": \\\\\\\"\\\\\\\"}\\\\n\\\\n        ref = doc_samples[0]\\\\n        numbered_sents = \\\\\\\"\\\\\\\\n\\\\\\\".join(\\\\n            f\\\\\\\"[{i}] {s}\\\\\\\" for i, s in enumerate(ref.sents)\\\\n        )\\\\n\\\\n        entity_list = set()\\\\n        for s in doc_samples:\\\\n            entity_list.add(f\\\\\\\"{s.head.name} ({s.head.mentions[0].entity_type})\\\\\\\")\\\\n            entity_list.add(f\\\\\\\"{s.tail.name} ({s.tail.mentions[0].entity_type})\\\\\\\")\\\\n        entity_str = \\\\\\\", \\\\\\\".join(sorted(entity_list))\\\\n\\\\n        instruction = (\\\\n            \\\\\\\"Extract all relation triples from the document. \\\\\\\"\\\\n            \\\\\\\"For each triple, provide the head entity, relation, tail entity, \\\\\\\"\\\\n            \\\\\\\"and the sentence IDs that serve as evidence. \\\\\\\"\\\\n            \\\\\\\"Output as a JSON list.\\\\\\\"\\\\n        )\\\\n\\\\n        input_text = (\\\\n            f\\\\\\\"Document:\\\\\\\\n{numbered_sents}\\\\\\\\n\\\\\\\\n\\\\\\\"\\\\n            f\\\\\\\"Entities: {entity_str}\\\\\\\"\\\\n        )\\\\n\\\\n        triples = []\\\\n        for s in doc_samples:\\\\n            triples.append({\\\\n                \\\\\\\"head\\\\\\\": s.head.name,\\\\n                \\\\\\\"relation\\\\\\\": s.relation_name,\\\\n                \\\\\\\"tail\\\\\\\": s.tail.name,\\\\n                \\\\\\\"evidence\\\\\\\": s.evidence_sent_ids,\\\\n            })\\\\n        output_text = json.dumps(triples, ensure_ascii=False)\\\\n\\\\n        return {\\\\n            \\\\\\\"instruction\\\\\\\": instruction,\\\\n            \\\\\\\"input\\\\\\\": input_text,\\\\n            \\\\\\\"output\\\\\\\": output_text,\\\\n        }\\\\n\\\\n\\\\ndef download_docred(output_dir: str) -> Path:\\\\n    from datasets import load_dataset\\\\n\\\\n    out = Path(output_dir)\\\\n    out.mkdir(parents=True, exist_ok=True)\\\\n\\\\n    ds = load_dataset(\\\\\\\"thunlp/docred\\\\\\\", trust_remote_code=True)\\\\n    for split_name, split_ds in ds.items():\\\\n        fname = SPLIT_FILENAMES.get(split_name, f\\\\\\\"{split_name}.json\\\\\\\")\\\\n        path = out / fname\\\\n        data = [row for row in split_ds]\\\\n        with open(path, \\\\\\\"w\\\\\\\") as f:\\\\n            json.dump(data, f, ensure_ascii=False)\\\\n        logger.info(\\\\\\\"Saved %d documents to %s\\\\\\\", len(data), path)\\\\n\\\\n    return out\\\\n\\\\n\\\\nif __name__ == \\\\\\\"__main__\\\\\\\":\\\\n    import argparse\\\\n    import sys\\\\n\\\\n    logging.basicConfig(level=logging.INFO, format=\\\\\\\"%(levelname)s: %(message)s\\\\\\\")\\\\n\\\\n    parser = argparse.ArgumentParser(description=\\\\\\\"DocRED 数据预处理\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--data_dir\\\\\\\", type=str, default=None)\\\\n    parser.add_argument(\\\\\\\"--split\\\\\\\", type=str, default=\\\\\\\"dev\\\\\\\")\\\\n    parser.add_argument(\\\\\\\"--output\\\\\\\", type=str, default=None)\\\\n    parser.add_argument(\\\\\\\"--download\\\\\\\", action=\\\\\\\"store_true\\\\\\\")\\\\n    args = parser.parse_args()\\\\n\\\\n    if args.download:\\\\n        if not args.data_dir:\\\\n            print(\\\\\\\"--download requires --data_dir\\\\\\\", file=sys.stderr)\\\\n            sys.exit(1)\\\\n        download_docred(args.data_dir)\\\\n        sys.exit(0)\\\\n\\\\n    processor = DocREDProcessor(data_dir=args.data_dir)\\\\n    samples = processor.process(args.split)\\\\n\\\\n    print(f\\\\\\\"Total samples: {len(samples)}\\\\\\\")\\\\n    has_hard_neg = sum(1 for s in samples if s.hard_negative_sent_ids)\\\\n    print(f\\\\\\\"Samples with hard negatives: {has_hard_neg} \\\\\\\"\\\\n          f\\\\\\\"({has_hard_neg / len(samples) * 100:.1f}%)\\\\\\\")\\\\n\\\\n    if samples:\\\\n        s = samples[0]\\\\n        print(f\\\\\\\"\\\\\\\\nExample: {s.head.name} --[{s.relation_name}]--> {s.tail.name}\\\\\\\")\\\\n        print(f\\\\\\\"  Evidence sents: {s.evidence_sent_ids}\\\\\\\")\\\\n        print(f\\\\\\\"  Hard negatives: {s.hard_negative_sent_ids}\\\\\\\")\\\\n\\\\n    if args.output:\\\\n        out_data = []\\\\n        for s in samples:\\\\n            out_data.append({\\\\n                \\\\\\\"doc_id\\\\\\\": s.doc_id,\\\\n                \\\\\\\"head\\\\\\\": s.head.name,\\\\n                \\\\\\\"tail\\\\\\\": s.tail.name,\\\\n                \\\\\\\"relation\\\\\\\": s.relation,\\\\n                \\\\\\\"relation_name\\\\\\\": s.relation_name,\\\\n                \\\\\\\"evidence_sent_ids\\\\\\\": s.evidence_sent_ids,\\\\n                \\\\\\\"hard_negative_sent_ids\\\\\\\": s.hard_negative_sent_ids,\\\\n            })\\\\n        with open(args.output, \\\\\\\"w\\\\\\\") as f:\\\\n            json.dump(out_data, f, ensure_ascii=False, indent=2)\\\\n        print(f\\\\\\\"Saved to {args.output}\\\\\\\")\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.31}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\\\"\\\"\\\"DocRED 数据预处理模块。\\n\\n加载 DocRED 数据集（train_annotated / dev / test），解析实体、关系、\\nevidence 标注，构建含 hard negatives 的训练样本。\\n\\n输入: DocRED JSON 文件目录或 HuggingFace dataset\\n输出: List[RelationSample]，每个样本包含 gold evidence 和 hard negative 句子\\n依赖: datasets (可选，用于 HF 加载)\\n\\\"\\\"\\\"\\n\\nimport json\\nimport logging\\nfrom dataclasses import dataclass, field\\nfrom pathlib import Path\\nfrom typing import Optional\\n\\nlogger = logging.getLogger(__name__)\\n\\nDOCRED_REL_INFO = {\\n    \\\"P6\\\": \\\"head of government\\\", \\\"P17\\\": \\\"country\\\", \\\"P19\\\": \\\"place of birth\\\",\\n    \\\"P20\\\": \\\"place of death\\\", \\\"P22\\\": \\\"father\\\", \\\"P25\\\": \\\"mother\\\",\\n    \\\"P26\\\": \\\"spouse\\\", \\\"P27\\\": \\\"country of citizenship\\\", \\\"P30\\\": \\\"continent\\\",\\n    \\\"P31\\\": \\\"instance of\\\", \\\"P35\\\": \\\"head of state\\\", \\\"P36\\\": \\\"capital\\\",\\n    \\\"P37\\\": \\\"official language\\\", \\\"P39\\\": \\\"position held\\\", \\\"P40\\\": \\\"child\\\",\\n    \\\"P50\\\": \\\"author\\\", \\\"P54\\\": \\\"member of sports team\\\", \\\"P57\\\": \\\"director\\\",\\n    \\\"P58\\\": \\\"screenwriter\\\", \\\"P69\\\": \\\"educated at\\\", \\\"P86\\\": \\\"composer\\\",\\n    \\\"P102\\\": \\\"member of political party\\\", \\\"P108\\\": \\\"employer\\\",\\n    \\\"P112\\\": \\\"founded by\\\", \\\"P118\\\": \\\"league\\\", \\\"P123\\\": \\\"publisher\\\",\\n    \\\"P127\\\": \\\"owned by\\\",\\n    \\\"P131\\\": \\\"located in the administrative territorial entity\\\",\\n    \\\"P136\\\": \\\"genre\\\", \\\"P137\\\": \\\"operator\\\", \\\"P140\\\": \\\"religion\\\",\\n    \\\"P150\\\": \\\"contains administrative territorial entity\\\",\\n    \\\"P155\\\": \\\"follows\\\", \\\"P156\\\": \\\"followed by\\\",\\n    \\\"P159\\\": \\\"headquarters location\\\", \\\"P161\\\": \\\"cast member\\\",\\n    \\\"P162\\\": \\\"producer\\\", \\\"P166\\\": \\\"award received\\\", \\\"P170\\\": \\\"creator\\\",\\n    \\\"P171\\\": \\\"parent taxon\\\", \\\"P172\\\": \\\"ethnic group\\\", \\\"P175\\\": \\\"performer\\\",\\n    \\\"P176\\\": \\\"manufacturer\\\", \\\"P178\\\": \\\"developer\\\", \\\"P179\\\": \\\"series\\\",\\n    \\\"P190\\\": \\\"sister city\\\", \\\"P194\\\": \\\"legislative body\\\",\\n    \\\"P205\\\": \\\"basin country\\\",\\n    \\\"P206\\\": \\\"located in or next to body of water\\\",\\n    \\\"P241\\\": \\\"military branch\\\", \\\"P264\\\": \\\"record label\\\",\\n    \\\"P272\\\": \\\"production company\\\", \\\"P276\\\": \\\"location\\\",\\n    \\\"P279\\\": \\\"subclass of\\\", \\\"P355\\\": \\\"subsidiary\\\", \\\"P361\\\": \\\"part of\\\",\\n    \\\"P364\\\": \\\"original language of work\\\", \\\"P400\\\": \\\"platform\\\",\\n    \\\"P403\\\": \\\"mouth of the watercourse\\\", \\\"P449\\\": \\\"original network\\\",\\n    \\\"P463\\\": \\\"member of\\\", \\\"P488\\\": \\\"chairperson\\\",\\n    \\\"P495\\\": \\\"country of origin\\\", \\\"P527\\\": \\\"has part\\\",\\n    \\\"P551\\\": \\\"residence\\\", \\\"P569\\\": \\\"date of birth\\\",\\n    \\\"P570\\\": \\\"date of death\\\", \\\"P571\\\": \\\"inception\\\",\\n    \\\"P576\\\": \\\"dissolved, abolished or demolished\\\",\\n    \\\"P577\\\": \\\"publication date\\\", \\\"P580\\\": \\\"start time\\\",\\n    \\\"P582\\\": \\\"end time\\\", \\\"P585\\\": \\\"point in time\\\", \\\"P607\\\": \\\"conflict\\\",\\n    \\\"P674\\\": \\\"characters\\\", \\\"P676\\\": \\\"lyrics by\\\",\\n    \\\"P706\\\": \\\"located on terrain feature\\\", \\\"P710\\\": \\\"participant\\\",\\n    \\\"P737\\\": \\\"influenced by\\\", \\\"P740\\\": \\\"location of formation\\\",\\n    \\\"P749\\\": \\\"parent organization\\\", \\\"P800\\\": \\\"notable work\\\",\\n    \\\"P807\\\": \\\"separated from\\\", \\\"P840\\\": \\\"narrative location\\\",\\n    \\\"P937\\\": \\\"work location\\\", \\\"P1001\\\": \\\"applies to jurisdiction\\\",\\n    \\\"P1056\\\": \\\"product or material produced\\\",\\n    \\\"P1198\\\": \\\"unemployment rate\\\", \\\"P1336\\\": \\\"territory claimed by\\\",\\n    \\\"P1344\\\": \\\"participant of\\\", \\\"P1365\\\": \\\"replaces\\\",\\n    \\\"P1366\\\": \\\"replaced by\\\", \\\"P1376\\\": \\\"capital of\\\",\\n    \\\"P1412\\\": \\\"languages spoken, written or signed\\\",\\n    \\\"P1441\\\": \\\"present in work\\\", \\\"P3373\\\": \\\"sibling\\\",\\n}\\n\\nSPLIT_FILENAMES = {\\n    \\\"train\\\": \\\"train_annotated.json\\\",\\n    \\\"train_annotated\\\": \\\"train_annotated.json\\\",\\n    \\\"train_distant\\\": \\\"train_distant.json\\\",\\n    \\\"dev\\\": \\\"dev.json\\\",\\n    \\\"test\\\": \\\"test.json\\\",\\n}\\n\\n\\n@dataclass\\nclass EntityMention:\\n    name: str\\n    sent_id: int\\n    pos: tuple[int, int]\\n    entity_type: str\\n\\n\\n@dataclass\\nclass Entity:\\n    entity_id: int\\n    mentions: list[EntityMention]\\n\\n    @property\\n    def name(self) -> str:\\n        return self.mentions[0].name\\n\\n    @property\\n    def sent_ids(self) -> set[int]:\\n        return {m.sent_id for m in self.mentions}\\n\\n\\n@dataclass\\nclass RelationSample:\\n    doc_id: str\\n    document: str\\n    sents: list[str]\\n    head: Entity\\n    tail: Entity\\n    relation: str\\n    relation_name: str\\n    evidence_sent_ids: list[int]\\n    hard_negative_sent_ids: list[int]\\n\\n\\nclass DocREDProcessor:\\n    \\\"\\\"\\\"DocRED 数据加载与预处理。\\\"\\\"\\\"\\n\\n    def __init__(self, data_dir: Optional[str] = None):\\n        self.data_dir\\n\\n... [截断: 输出过长，省略 4058 字符] ...\\n\\ntionSample]] = {}\\n        for s in samples:\\n            groups.setdefault(s.doc_id, []).append(s)\\n        return groups\\n\\n    def format_sft_sample(\\n        self, doc_samples: list[RelationSample]\\n    ) -> dict[str, str]:\\n        if not doc_samples:\\n            return {\\\"instruction\\\": \\\"\\\", \\\"input\\\": \\\"\\\", \\\"output\\\": \\\"\\\"}\\n\\n        ref = doc_samples[0]\\n        numbered_sents = \\\"\\\\n\\\".join(\\n            f\\\"[{i}] {s}\\\" for i, s in enumerate(ref.sents)\\n        )\\n\\n        entity_list = set()\\n        for s in doc_samples:\\n            entity_list.add(f\\\"{s.head.name} ({s.head.mentions[0].entity_type})\\\")\\n            entity_list.add(f\\\"{s.tail.name} ({s.tail.mentions[0].entity_type})\\\")\\n        entity_str = \\\", \\\".join(sorted(entity_list))\\n\\n        instruction = (\\n            \\\"Extract all relation triples from the document. \\\"\\n            \\\"For each triple, provide the head entity, relation, tail entity, \\\"\\n            \\\"and the sentence IDs that serve as evidence. \\\"\\n            \\\"Output as a JSON list.\\\"\\n        )\\n\\n        input_text = (\\n            f\\\"Document:\\\\n{numbered_sents}\\\\n\\\\n\\\"\\n            f\\\"Entities: {entity_str}\\\"\\n        )\\n\\n        triples = []\\n        for s in doc_samples:\\n            triples.append({\\n                \\\"head\\\": s.head.name,\\n                \\\"relation\\\": s.relation_name,\\n                \\\"tail\\\": s.tail.name,\\n                \\\"evidence\\\": s.evidence_sent_ids,\\n            })\\n        output_text = json.dumps(triples, ensure_ascii=False)\\n\\n        return {\\n            \\\"instruction\\\": instruction,\\n            \\\"input\\\": input_text,\\n            \\\"output\\\": output_text,\\n        }\\n\\n\\ndef download_docred(output_dir: str) -> Path:\\n    from datasets import load_dataset\\n\\n    out = Path(output_dir)\\n    out.mkdir(parents=True, exist_ok=True)\\n\\n    ds = load_dataset(\\\"thunlp/docred\\\", trust_remote_code=True)\\n    for split_name, split_ds in ds.items():\\n        fname = SPLIT_FILENAMES.get(split_name, f\\\"{split_name}.json\\\")\\n        path = out / fname\\n        data = [row for row in split_ds]\\n        with open(path, \\\"w\\\") as f:\\n            json.dump(data, f, ensure_ascii=False)\\n        logger.info(\\\"Saved %d documents to %s\\\", len(data), path)\\n\\n    return out\\n\\n\\nif __name__ == \\\"__main__\\\":\\n    import argparse\\n    import sys\\n\\n    logging.basicConfig(level=logging.INFO, format=\\\"%(levelname)s: %(message)s\\\")\\n\\n    parser = argparse.ArgumentParser(description=\\\"DocRED 数据预处理\\\")\\n    parser.add_argument(\\\"--data_dir\\\", type=str, default=None)\\n    parser.add_argument(\\\"--split\\\", type=str, default=\\\"dev\\\")\\n    parser.add_argument(\\\"--output\\\", type=str, default=None)\\n    parser.add_argument(\\\"--download\\\", action=\\\"store_true\\\")\\n    args = parser.parse_args()\\n\\n    if args.download:\\n        if not args.data_dir:\\n            print(\\\"--download requires --data_dir\\\", file=sys.stderr)\\n            sys.exit(1)\\n        download_docred(args.data_dir)\\n        sys.exit(0)\\n\\n    processor = DocREDProcessor(data_dir=args.data_dir)\\n    samples = processor.process(args.split)\\n\\n    print(f\\\"Total samples: {len(samples)}\\\")\\n    has_hard_neg = sum(1 for s in samples if s.hard_negative_sent_ids)\\n    print(f\\\"Samples with hard negatives: {has_hard_neg} \\\"\\n          f\\\"({has_hard_neg / len(samples) * 100:.1f}%)\\\")\\n\\n    if samples:\\n        s = samples[0]\\n        print(f\\\"\\\\nExample: {s.head.name} --[{s.relation_name}]--> {s.tail.name}\\\")\\n        print(f\\\"  Evidence sents: {s.evidence_sent_ids}\\\")\\n        print(f\\\"  Hard negatives: {s.hard_negative_sent_ids}\\\")\\n\\n    if args.output:\\n        out_data = []\\n        for s in samples:\\n            out_data.append({\\n                \\\"doc_id\\\": s.doc_id,\\n                \\\"head\\\": s.head.name,\\n                \\\"tail\\\": s.tail.name,\\n                \\\"relation\\\": s.relation,\\n                \\\"relation_name\\\": s.relation_name,\\n                \\\"evidence_sent_ids\\\": s.evidence_sent_ids,\\n                \\\"hard_negative_sent_ids\\\": s.hard_negative_sent_ids,\\n            })\\n        with open(args.output, \\\"w\\\") as f:\\n            json.dump(out_data, f, ensure_ascii=False, indent=2)\\n        print(f\\\"Saved to {args.output}\\\")\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.31}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 65_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01DDtpiUSbtTvnpcYu51fTJH`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "ls /root/autodl-tmp/data/docred/",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "12e4b261-5bc7-4e1f-92b2-42cdaa2d1d76",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GjJ37LZnUXzdRKjLBzvCsr",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5898,
      "cache_read_input_tokens": 59012,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5898
      },
      "output_tokens": 65,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 66 · 2026-05-15T02:28:06.447Z_

<details><summary>↩ Tool result · `toolu_01DDtpiUSbtTvnpcYu51fTJH`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"dev.json\\ntest.json\\ntrain_annotated.json\\ntrain_nli_cache.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "25c8cce5-f60c-4bc9-829c-40e6abf6c2ff",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"dev.json\\\\ntest.json\\\\ntrain_annotated.json\\\\ntrain_nli_cache.json\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.35}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"dev.json\\ntest.json\\ntrain_annotated.json\\ntrain_nli_cache.json\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.35}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 67_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the information I need. Let me summarize:

**DocRED data location**: `/root/autodl-tmp/data/docred/` (has dev.json, train_annotated.json, test.json)

**DocREDProcessor interface**:
- `DocREDProcessor(data_dir="/root/autodl-tmp/data/docred/")`
- `.process("dev")` → `List[RelationSample]`
- `.group_by_document(samples)` → `dict[str, List[RelationSample]]`


- `.format_sft_sample(doc_samples)` → `{"instruction": str, "input": str, "output": str}`

**Evaluator interface**:
- `DocREDEvaluator.from_train_file(train_path)` → evaluator with train triples for Ign-F1
- `evaluator.evaluate(predictions, gold)` → `{f1, ign_f1, evi_f1, evi_precision, evi_recall, edcr, ...}`
- `parse_model_output(doc_id, text)` → `list[dict` with extracted relations
- `gold_from_docred(docred_data)` → `list[dict]` with gold relations

Now I'm modifying the trainer script to add evaluation capabilities. I'll introduce new command-line arguments for the evaluation data directory, maximum documents to evaluate, and token generation limits. Then I'll create a function to prepare the evaluation dataset with prompts and gold labels, and a custom callback class that generates predictions at the end of each epoch, parses the outputs, and computes F1 and evidence-based metrics. Finally, I'll integrate this into the main training loop by instantiating the callback and configuring the trainer's evaluation strategy.

For the evaluation dataset itself, I'll format the dev set using the same chat template structure as the training data so the trainer can compute standard loss-based evaluation metrics alongside the task-specific metrics from the callback.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "82133a13-9d15-42bf-96e9-85012bd801dc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018gShKZ9vnZX8KYG462GMiN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4537,
      "cache_read_input_tokens": 64910,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4537
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Assistant

_source line 68_

Now I have the full picture. Let me write the modified rsft_trainer.py with task-level eval.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "e09b8453-d116-4a75-b6ac-b5d083361f15",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018gShKZ9vnZX8KYG462GMiN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4537,
      "cache_read_input_tokens": 64910,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4537
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 69_

<details open><summary>🔧 Tool call — Edit · `toolu_01GygUY9PSWwcwtbmPQzy2WN`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py",
  "old_string": "\"\"\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\n\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\n\n输入: JSONL，每行 {\"doc_id\": ..., \"input\": ..., \"output\": ..., \"ced_score\": ..., ...}\n输出: QLoRA adapter checkpoint\n依赖: transformers, trl, peft, bitsandbytes, datasets\n\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n\"\"\"\n\nimport argparse\nimport json\nimport logging\nimport os\n\nimport torch\nfrom datasets import Dataset\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\nfrom torch.utils.data import WeightedRandomSampler\nfrom transformers import (\n    AutoModelForCausalLM,\n    AutoTokenizer,\n    BitsAndBytesConfig,\n)\nfrom trl import SFTConfig, SFTTrainer\n\nfrom freige.training.sft_trainer import SYSTEM_PROMPT",
  "new_string": "\"\"\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\n\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\n\n输入: JSONL，每行 {\"doc_id\": ..., \"input\": ..., \"output\": ..., \"ced_score\": ..., ...}\n输出: QLoRA adapter checkpoint\n依赖: transformers, trl, peft, bitsandbytes, datasets\n\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n\"\"\"\n\nimport argparse\nimport json\nimport logging\nimport os\n\nimport torch\nfrom datasets import Dataset\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\nfrom torch.utils.data import WeightedRandomSampler\nfrom transformers import (\n    AutoModelForCausalLM,\n    AutoTokenizer,\n    BitsAndBytesConfig,\n    TrainerCallback,\n)\nfrom trl import SFTConfig, SFTTrainer\n\nfrom freige.training.sft_trainer import SYSTEM_PROMPT"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "a6228a59-59cd-4164-a6ec-5f970d22b1c7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018gShKZ9vnZX8KYG462GMiN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4537,
      "cache_read_input_tokens": 64910,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4537
      },
      "output_tokens": 8,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 70 · 2026-05-15T02:28:34.512Z_

<details><summary>↩ Tool result · `toolu_01GygUY9PSWwcwtbmPQzy2WN`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "52f91a2c-fc02-4097-ba60-3e5830c7670b",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py",
    "oldString": "\"\"\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\n\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\n\n输入: JSONL，每行 {\"doc_id\": ..., \"input\": ..., \"output\": ..., \"ced_score\": ..., ...}\n输出: QLoRA adapter checkpoint\n依赖: transformers, trl, peft, bitsandbytes, datasets\n\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n\"\"\"\n\nimport argparse\nimport json\nimport logging\nimport os\n\nimport torch\nfrom datasets import Dataset\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\nfrom torch.utils.data import WeightedRandomSampler\nfrom transformers import (\n    AutoModelForCausalLM,\n    AutoTokenizer,\n    BitsAndBytesConfig,\n)\nfrom trl import SFTConfig, SFTTrainer\n\nfrom freige.training.sft_trainer import SYSTEM_PROMPT",
    "newString": "\"\"\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\n\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\n\n输入: JSONL，每行 {\"doc_id\": ..., \"input\": ..., \"output\": ..., \"ced_score\": ..., ...}\n输出: QLoRA adapter checkpoint\n依赖: transformers, trl, peft, bitsandbytes, datasets\n\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n\"\"\"\n\nimport argparse\nimport json\nimport logging\nimport os\n\nimport torch\nfrom datasets import Dataset\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\nfrom torch.utils.data import WeightedRandomSampler\nfrom transformers import (\n    AutoModelForCausalLM,\n    AutoTokenizer,\n    BitsAndBytesConfig,\n    TrainerCallback,\n)\nfrom trl import SFTConfig, SFTTrainer\n\nfrom freige.training.sft_trainer import SYSTEM_PROMPT",
    "originalFile": "\"\"\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\n\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\n\n输入: JSONL，每行 {\"doc_id\": ..., \"input\": ..., \"output\": ..., \"ced_score\": ..., ...}\n输出: QLoRA adapter checkpoint\n依赖: transformers, trl, peft, bitsandbytes, datasets\n\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n\"\"\"\n\nimport argparse\nimport json\nimport logging\nimport os\n\nimport torch\nfrom datasets import Dataset\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\nfrom torch.utils.data import WeightedRandomSampler\nfrom transformers import (\n    AutoModelForCausalLM,\n    AutoTokenizer,\n    BitsAndBytesConfig,\n)\nfrom trl import SFTConfig, SFTTrainer\n\nfrom freige.training.sft_trainer import SYSTEM_PROMPT\n\nlogging.basicConfig(level=logging.INFO, format=\"%(asctime)s %(levelname)s %(message)s\")\nlogger = logging.getLogger(__name__)\n\nDEFAULT_BASE_MODEL = \"/root/autodl-tmp/models/Qwen3-4B\"\nDEFAULT_SFT_ADAPTER = \"/root/autodl-tmp/sft_output\"\n\n\ndef load_rsft_data(data_path: str, tokenizer, max_length: int = 2048):\n    \"\"\"加载 CED 筛选后的 RSFT 数据，格式化为 chat template 文本。\n\n    每行 JSONL 的 input 字段作为 user message，output 字段作为 assistant response，\n    经 apply_chat_template 拼接后用于 SFT 训练。超过 max_length 的样本被跳过\n    而非截断，避免训练在不完整 JSON 输出上。\n\n    Returns:\n        (Dataset, list[float]): 训练数据集和对应的 CED scores\n    \"\"\"\n    samples = []\n    with open(data_path) as f:\n        for line in f:\n            if line.strip():\n                samples.append(json.loads(line))\n\n    logger.info(\"Loaded %d RSFT samples from %s\", len(samples), data_path)\n\n    formatted = []\n    ced_scores = []\n    skipped = 0\n    for s in samples:\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": s[\"input\"]},\n            {\"role\": \"assistant\", \"content\": s[\"output\"]},\n        ]\n        text = tokenizer.apply_chat_template(\n            messages,\n            tokenize=False,\n            add_generation_prompt=False,\n            enable_thinking=False,\n        )\n        token_len = len(tokenizer.encode(text, add_special_tokens=False))\n        if token_len > max_length:\n            skipped += 1\n            continue\n        formatted.append({\"text\": text})\n        ced_scores.append(s.get(\"ced_score\", 1.0))\n\n    if skipped:\n        logger.warning(\"Skipped %d samples exceeding max_length=%d\", skipped, max_length)\n\n    if ced_scores:\n        logger.info(\n            \"Prepared %d RSFT samples (CED scores: min=%.3f, max=%.3f, mean=%.3f)\",\n            len(formatted), min(ced_scores), max(ced_scores),\n            sum(ced_scores) / len(ced_scores),\n        )\n    return Dataset.from_list(formatted), ced_scores\n\n\nclass WeightedSFTTrainer(SFTTrainer):\n    \"\"\"SFTTrainer with CED score-weighted sampling.\n\n    高 CED score 的样本被更频繁采样。使用 WeightedRandomSampler 实现，\n    适用于单机训练。多机 DDP 场景下 Accelerate 会替换 sampler，\n    此时 weighted_sampling 不生效，需改用数据集层面的过采样。\n    \"\"\"\n\n    def __init__(self, *args, sample_weights=None, **kwargs):\n        super().__init__(*args, **kwargs)\n        self.sample_weights = sample_weights\n\n    def _get_train_sampler(self, dataset=None):\n        if self.sample_weights is not None:\n            ds = dataset if dataset is not None else self.train_dataset\n            return WeightedRandomSampler(\n                weights=self.sample_weights,\n                num_samples=len(ds),\n                replacement=True,\n            )\n        return super()._get_train_sampler(dataset)\n\n\ndef main():\n    parser = argparse.ArgumentParser(description=\"FREIGE RSFT Training\")\n    parser.add_argument(\"--base_model\", type=str, default=DEFAULT_BASE_MODEL)\n    parser.add_argument(\"--sft_adapter\", type=str, default=DEFAULT_SFT_ADAPTER,\n                        help=\"SFT warmup adapter 路径 (merge 后训练新 LoRA)\")\n    parser.add_argument(\"--rsft_data_path\", type=str, required=True,\n                        help=\"CED 筛选后的 RSFT 训练数据 (JSONL)\")\n    parser.add_argument(\"--output_dir\", type=str, required=True)\n    parser.add_argument(\"--learning_rate\", type=float, default=2e-5)\n    parser.add_argument(\"--num_epochs\", type=int, default=3)\n    parser.add_argument(\"--per_device_batch_size\", type=int, default=4)\n    parser.add_argument(\"--gradient_accumulation_steps\", type=int, default=4)\n    parser.add_argument(\"--warmup_steps\", type=int, default=100)\n    parser.add_argument(\"--save_steps\", type=int, default=50)\n    parser.add_argument(\"--save_total_limit\", type=int, default=5)\n    parser.add_argument(\"--max_length\", type=int, default=2048)\n    parser.add_argument(\"--seed\", type=int, default=42)\n    parser.add_argument(\"--wandb_project\", type=str, default=\"freige-rsft\")\n    parser.add_argument(\"--wandb_run_name\", type=str, default=None)\n    parser.add_argument(\"--weighted_sampling\", action=\"store_true\",\n                        help=\"按 CED score 加权采样（高分样本更频繁）\")\n    parser.add_argument(\"--quantize\", action=\"store_true\",\n                        help=\"启用 4-bit QLoRA 量化\")\n    parser.add_argument(\"--lora_rank\", type=int, default=64)\n    parser.add_argument(\"--lora_alpha\", type=int, default=128)\n    parser.add_argument(\"--lora_dropout\", type=float, default=0.05)\n    parser.add_argument(\"--bf16\", action=\"store_true\", default=True)\n    parser.add_argument(\"--deepspeed\", type=str, default=None,\n                        help=\"DeepSpeed 配置文件路径\")\n    args = parser.parse_args()\n\n    # W&B\n    if args.wandb_project and \"WANDB_API_KEY\" in os.environ:\n        os.environ[\"WANDB_PROJECT\"] = args.wandb_project\n        if args.wandb_run_name:\n            os.environ[\"WANDB_NAME\"] = args.wandb_run_name\n\n    # Tokenizer\n    logger.info(\"Loading tokenizer: %s\", args.base_model)\n    tokenizer = AutoTokenizer.from_pretrained(\n        args.base_model, trust_remote_code=True, padding_side=\"right\",\n    )\n    if tokenizer.pad_token is None:\n        tokenizer.pad_token = tokenizer.eos_token\n\n    # Data\n    logger.info(\"Loading RSFT data: %s\", args.rsft_data_path)\n    train_dataset, ced_scores = load_rsft_data(\n        args.rsft_data_path, tokenizer, args.max_length,\n    )\n\n    # Model: base → merge SFT adapter → new LoRA\n    logger.info(\"Loading base model: %s\", args.base_model)\n    local_rank = int(os.environ.get(\"LOCAL_RANK\", 0))\n    model_kwargs = dict(\n        trust_remote_code=True,\n        attn_implementation=\"sdpa\",\n        device_map={\"\": local_rank},\n    )\n    if args.quantize:\n        logger.info(\"Using 4-bit QLoRA quantization\")\n        model_kwargs[\"quantization_config\"] = BitsAndBytesConfig(\n            load_in_4bit=True,\n            bnb_4bit_compute_dtype=torch.bfloat16,\n            bnb_4bit_quant_type=\"nf4\",\n            bnb_4bit_use_double_quant=True,\n        )\n    else:\n        model_kwargs[\"torch_dtype\"] = torch.bfloat16 if args.bf16 else torch.float16\n\n    model = AutoModelForCausalLM.from_pretrained(args.base_model, **model_kwargs)\n\n    if args.sft_adapter:\n        logger.info(\"Merging SFT adapter: %s\", args.sft_adapter)\n        model = PeftModel.from_pretrained(model, args.sft_adapter)\n        model = model.merge_and_unload()\n\n    model.config.use_cache = False\n    model.gradient_checkpointing_enable()\n\n    # Fresh LoRA for RSFT (与 SFT warmup 相同结构)\n    lora_config = LoraConfig(\n        task_type=TaskType.CAUSAL_LM,\n        r=args.lora_rank,\n        lora_alpha=args.lora_alpha,\n        lora_dropout=args.lora_dropout,\n        target_modules=[\"q_proj\", \"k_proj\", \"v_proj\", \"o_proj\",\n                         \"gate_proj\", \"up_proj\", \"down_proj\"],\n    )\n    model = get_peft_model(model, lora_config)\n    model.print_trainable_parameters()\n\n    # Training config\n    training_args = SFTConfig(\n        output_dir=args.output_dir,\n        num_train_epochs=args.num_epochs,\n        per_device_train_batch_size=args.per_device_batch_size,\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\n        learning_rate=args.learning_rate,\n        warmup_steps=args.warmup_steps,\n        bf16=args.bf16,\n        logging_steps=10,\n        save_strategy=\"steps\",\n        save_steps=args.save_steps,\n        save_total_limit=args.save_total_limit,\n        seed=args.seed,\n        max_length=args.max_length,\n        dataset_text_field=\"text\",\n        report_to=\"wandb\" if \"WANDB_API_KEY\" in os.environ else \"none\",\n        gradient_checkpointing=True,\n        gradient_checkpointing_kwargs={\"use_reentrant\": False},\n        deepspeed=args.deepspeed,\n    )\n\n    sample_weights = ced_scores if args.weighted_sampling else None\n\n    trainer = WeightedSFTTrainer(\n        model=model,\n        args=training_args,\n        train_dataset=train_dataset,\n        processing_class=tokenizer,\n        sample_weights=sample_weights,\n    )\n\n    logger.info(\n        \"Starting RSFT training (%d samples, weighted=%s)...\",\n        len(train_dataset), args.weighted_sampling,\n    )\n    trainer.train()\n\n    logger.info(\"Saving model to %s\", args.output_dir)\n    trainer.save_model(args.output_dir)\n    tokenizer.save_pretrained(args.output_dir)\n    logger.info(\"RSFT training complete.\")\n\n\nif __name__ == \"__main__\":\n    main()\n",
    "structuredPatch": [
      {
        "oldStart": 25,
        "oldLines": 6,
        "newStart": 25,
        "newLines": 7,
        "lines": [
          "     AutoModelForCausalLM,",
          "     AutoTokenizer,",
          "     BitsAndBytesConfig,",
          "+    TrainerCallback,",
          " )",
          " from trl import SFTConfig, SFTTrainer",
          " "
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 71_

Now add the `prepare_eval_data` function and `TaskEvalCallback` class after the `load_rsft_data` function:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "0c9096a3-b0e0-4c2b-94e7-cd59f70a25da",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011nxcbbv9zwB8rLd4iM5Jga",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1633,
      "cache_read_input_tokens": 69447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1633
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 72_

<details open><summary>🔧 Tool call — Edit · `toolu_01SM1854H6Zs8j45ihYXqSbv`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py",
  "old_string": "class WeightedSFTTrainer(SFTTrainer):",
  "new_string": "def prepare_eval_data(data_dir, tokenizer, max_docs=50):\n    \"\"\"Load DocRED dev set for task-level evaluation during training.\"\"\"\n    from freige.data.docred_processor import DocREDProcessor\n    from freige.eval.evaluator import gold_from_docred\n\n    processor = DocREDProcessor(data_dir=data_dir)\n    samples = processor.process(\"dev\")\n    groups = processor.group_by_document(samples)\n\n    eval_items = []\n    for doc_id, doc_samples in list(groups.items())[:max_docs]:\n        sft_sample = processor.format_sft_sample(doc_samples)\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": f\"{sft_sample['instruction']}\\n\\n{sft_sample['input']}\"},\n        ]\n        prompt = tokenizer.apply_chat_template(\n            messages, tokenize=False, add_generation_prompt=True, enable_thinking=False,\n        )\n        eval_items.append({\"doc_id\": doc_id, \"prompt\": prompt})\n\n    dev_path = os.path.join(data_dir, \"dev.json\")\n    with open(dev_path) as f:\n        dev_data = json.load(f)\n    gold = gold_from_docred(dev_data)\n\n    # Also build formatted eval dataset for loss-based eval\n    eval_formatted = []\n    for doc_id, doc_samples in groups.items():\n        sft_sample = processor.format_sft_sample(doc_samples)\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": f\"{sft_sample['instruction']}\\n\\n{sft_sample['input']}\"},\n            {\"role\": \"assistant\", \"content\": sft_sample[\"output\"]},\n        ]\n        text = tokenizer.apply_chat_template(\n            messages, tokenize=False, add_generation_prompt=False, enable_thinking=False,\n        )\n        eval_formatted.append({\"text\": text})\n    eval_dataset = Dataset.from_list(eval_formatted)\n\n    return eval_items, gold, eval_dataset\n\n\nclass TaskEvalCallback(TrainerCallback):\n    \"\"\"End-of-epoch task eval: generate on dev subset → compute F1 / Evi-F1 / EDCR.\"\"\"\n\n    def __init__(self, tokenizer, eval_items, gold, train_file, max_new_tokens=1024):\n        self.tokenizer = tokenizer\n        self.eval_items = eval_items\n        self.gold = gold\n        self.train_file = train_file\n        self.max_new_tokens = max_new_tokens\n        self._evaluator = None\n\n    @property\n    def evaluator(self):\n        if self._evaluator is None:\n            from freige.eval.evaluator import DocREDEvaluator\n            if self.train_file and os.path.exists(self.train_file):\n                self._evaluator = DocREDEvaluator.from_train_file(self.train_file)\n            else:\n                self._evaluator = DocREDEvaluator()\n        return self._evaluator\n\n    def on_epoch_end(self, args, state, control, model=None, **kwargs):\n        if not state.is_world_process_zero:\n            return\n        self._run_task_eval(model, state)\n\n    def _run_task_eval(self, model, state):\n        from freige.eval.evaluator import parse_model_output\n\n        model.eval()\n        model.config.use_cache = True\n        if hasattr(model, \"gradient_checkpointing_disable\"):\n            model.gradient_checkpointing_disable()\n\n        all_predictions = []\n        for item in self.eval_items:\n            inputs = self.tokenizer(\n                item[\"prompt\"], return_tensors=\"pt\", truncation=True, max_length=4096,\n            ).to(model.device)\n            with torch.no_grad():\n                outputs = model.generate(\n                    **inputs,\n                    max_new_tokens=self.max_new_tokens,\n                    do_sample=False,\n                    pad_token_id=self.tokenizer.pad_token_id,\n                )\n            generated = outputs[0][inputs[\"input_ids\"].shape[1]:]\n            text = self.tokenizer.decode(generated, skip_special_tokens=True)\n            triples = parse_model_output(item[\"doc_id\"], text)\n            all_predictions.extend(triples)\n\n        metrics = self.evaluator.evaluate(all_predictions, self.gold)\n\n        log_metrics = {\n            \"eval/rel_f1\": metrics[\"f1\"],\n            \"eval/ign_f1\": metrics[\"ign_f1\"],\n            \"eval/evi_f1\": metrics[\"evi_f1\"],\n            \"eval/evi_precision\": metrics[\"evi_precision\"],\n            \"eval/evi_recall\": metrics[\"evi_recall\"],\n            \"eval/edcr\": metrics.get(\"edcr\", 0),\n            \"eval/n_predictions\": len(all_predictions),\n        }\n        try:\n            import wandb\n            if wandb.run is not None:\n                wandb.log(log_metrics, step=state.global_step)\n        except ImportError:\n            pass\n\n        logger.info(\n            \"Task eval @ step %d: F1=%.4f, Ign-F1=%.4f, Evi-F1=%.4f, EDCR=%.4f (%d preds)\",\n            state.global_step, metrics[\"f1\"], metrics[\"ign_f1\"],\n            metrics[\"evi_f1\"], metrics.get(\"edcr\", 0), len(all_predictions),\n        )\n\n        model.config.use_cache = False\n        if hasattr(model, \"gradient_checkpointing_enable\"):\n            model.gradient_checkpointing_enable()\n        model.train()\n\n\nclass WeightedSFTTrainer(SFTTrainer):"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "9508efdc-df8d-4d82-861b-d6596d8fdd0e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011nxcbbv9zwB8rLd4iM5Jga",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1633,
      "cache_read_input_tokens": 69447,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1633
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 73 · 2026-05-15T02:28:55.567Z_

<details><summary>↩ Tool result · `toolu_01SM1854H6Zs8j45ihYXqSbv`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "3e71c671-15a8-4721-a2cd-f330c3c20a22",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py",
    "oldString": "class WeightedSFTTrainer(SFTTrainer):",
    "newString": "def prepare_eval_data(data_dir, tokenizer, max_docs=50):\n    \"\"\"Load DocRED dev set for task-level evaluation during training.\"\"\"\n    from freige.data.docred_processor import DocREDProcessor\n    from freige.eval.evaluator import gold_from_docred\n\n    processor = DocREDProcessor(data_dir=data_dir)\n    samples = processor.process(\"dev\")\n    groups = processor.group_by_document(samples)\n\n    eval_items = []\n    for doc_id, doc_samples in list(groups.items())[:max_docs]:\n        sft_sample = processor.format_sft_sample(doc_samples)\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": f\"{sft_sample['instruction']}\\n\\n{sft_sample['input']}\"},\n        ]\n        prompt = tokenizer.apply_chat_template(\n            messages, tokenize=False, add_generation_prompt=True, enable_thinking=False,\n        )\n        eval_items.append({\"doc_id\": doc_id, \"prompt\": prompt})\n\n    dev_path = os.path.join(data_dir, \"dev.json\")\n    with open(dev_path) as f:\n        dev_data = json.load(f)\n    gold = gold_from_docred(dev_data)\n\n    # Also build formatted eval dataset for loss-based eval\n    eval_formatted = []\n    for doc_id, doc_samples in groups.items():\n        sft_sample = processor.format_sft_sample(doc_samples)\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": f\"{sft_sample['instruction']}\\n\\n{sft_sample['input']}\"},\n            {\"role\": \"assistant\", \"content\": sft_sample[\"output\"]},\n        ]\n        text = tokenizer.apply_chat_template(\n            messages, tokenize=False, add_generation_prompt=False, enable_thinking=False,\n        )\n        eval_formatted.append({\"text\": text})\n    eval_dataset = Dataset.from_list(eval_formatted)\n\n    return eval_items, gold, eval_dataset\n\n\nclass TaskEvalCallback(TrainerCallback):\n    \"\"\"End-of-epoch task eval: generate on dev subset → compute F1 / Evi-F1 / EDCR.\"\"\"\n\n    def __init__(self, tokenizer, eval_items, gold, train_file, max_new_tokens=1024):\n        self.tokenizer = tokenizer\n        self.eval_items = eval_items\n        self.gold = gold\n        self.train_file = train_file\n        self.max_new_tokens = max_new_tokens\n        self._evaluator = None\n\n    @property\n    def evaluator(self):\n        if self._evaluator is None:\n            from freige.eval.evaluator import DocREDEvaluator\n            if self.train_file and os.path.exists(self.train_file):\n                self._evaluator = DocREDEvaluator.from_train_file(self.train_file)\n            else:\n                self._evaluator = DocREDEvaluator()\n        return self._evaluator\n\n    def on_epoch_end(self, args, state, control, model=None, **kwargs):\n        if not state.is_world_process_zero:\n            return\n        self._run_task_eval(model, state)\n\n    def _run_task_eval(self, model, state):\n        from freige.eval.evaluator import parse_model_output\n\n        model.eval()\n        model.config.use_cache = True\n        if hasattr(model, \"gradient_checkpointing_disable\"):\n            model.gradient_checkpointing_disable()\n\n        all_predictions = []\n        for item in self.eval_items:\n            inputs = self.tokenizer(\n                item[\"prompt\"], return_tensors=\"pt\", truncation=True, max_length=4096,\n            ).to(model.device)\n            with torch.no_grad():\n                outputs = model.generate(\n                    **inputs,\n                    max_new_tokens=self.max_new_tokens,\n                    do_sample=False,\n                    pad_token_id=self.tokenizer.pad_token_id,\n                )\n            generated = outputs[0][inputs[\"input_ids\"].shape[1]:]\n            text = self.tokenizer.decode(generated, skip_special_tokens=True)\n            triples = parse_model_output(item[\"doc_id\"], text)\n            all_predictions.extend(triples)\n\n        metrics = self.evaluator.evaluate(all_predictions, self.gold)\n\n        log_metrics = {\n            \"eval/rel_f1\": metrics[\"f1\"],\n            \"eval/ign_f1\": metrics[\"ign_f1\"],\n            \"eval/evi_f1\": metrics[\"evi_f1\"],\n            \"eval/evi_precision\": metrics[\"evi_precision\"],\n            \"eval/evi_recall\": metrics[\"evi_recall\"],\n            \"eval/edcr\": metrics.get(\"edcr\", 0),\n            \"eval/n_predictions\": len(all_predictions),\n        }\n        try:\n            import wandb\n            if wandb.run is not None:\n                wandb.log(log_metrics, step=state.global_step)\n        except ImportError:\n            pass\n\n        logger.info(\n            \"Task eval @ step %d: F1=%.4f, Ign-F1=%.4f, Evi-F1=%.4f, EDCR=%.4f (%d preds)\",\n            state.global_step, metrics[\"f1\"], metrics[\"ign_f1\"],\n            metrics[\"evi_f1\"], metrics.get(\"edcr\", 0), len(all_predictions),\n        )\n\n        model.config.use_cache = False\n        if hasattr(model, \"gradient_checkpointing_enable\"):\n            model.gradient_checkpointing_enable()\n        model.train()\n\n\nclass WeightedSFTTrainer(SFTTrainer):",
    "originalFile": "\"\"\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\n\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\n\n输入: JSONL，每行 {\"doc_id\": ..., \"input\": ..., \"output\": ..., \"ced_score\": ..., ...}\n输出: QLoRA adapter checkpoint\n依赖: transformers, trl, peft, bitsandbytes, datasets\n\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n\"\"\"\n\nimport argparse\nimport json\nimport logging\nimport os\n\nimport torch\nfrom datasets import Dataset\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\nfrom torch.utils.data import WeightedRandomSampler\nfrom transformers import (\n    AutoModelForCausalLM,\n    AutoTokenizer,\n    BitsAndBytesConfig,\n    TrainerCallback,\n)\nfrom trl import SFTConfig, SFTTrainer\n\nfrom freige.training.sft_trainer import SYSTEM_PROMPT\n\nlogging.basicConfig(level=logging.INFO, format=\"%(asctime)s %(levelname)s %(message)s\")\nlogger = logging.getLogger(__name__)\n\nDEFAULT_BASE_MODEL = \"/root/autodl-tmp/models/Qwen3-4B\"\nDEFAULT_SFT_ADAPTER = \"/root/autodl-tmp/sft_output\"\n\n\ndef load_rsft_data(data_path: str, tokenizer, max_length: int = 2048):\n    \"\"\"加载 CED 筛选后的 RSFT 数据，格式化为 chat template 文本。\n\n    每行 JSONL 的 input 字段作为 user message，output 字段作为 assistant response，\n    经 apply_chat_template 拼接后用于 SFT 训练。超过 max_length 的样本被跳过\n    而非截断，避免训练在不完整 JSON 输出上。\n\n    Returns:\n        (Dataset, list[float]): 训练数据集和对应的 CED scores\n    \"\"\"\n    samples = []\n    with open(data_path) as f:\n        for line in f:\n            if line.strip():\n                samples.append(json.loads(line))\n\n    logger.info(\"Loaded %d RSFT samples from %s\", len(samples), data_path)\n\n    formatted = []\n    ced_scores = []\n    skipped = 0\n    for s in samples:\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": s[\"input\"]},\n            {\"role\": \"assistant\", \"content\": s[\"output\"]},\n        ]\n        text = tokenizer.apply_chat_template(\n            messages,\n            tokenize=False,\n            add_generation_prompt=False,\n            enable_thinking=False,\n        )\n        token_len = len(tokenizer.encode(text, add_special_tokens=False))\n        if token_len > max_length:\n            skipped += 1\n            continue\n        formatted.append({\"text\": text})\n        ced_scores.append(s.get(\"ced_score\", 1.0))\n\n    if skipped:\n        logger.warning(\"Skipped %d samples exceeding max_length=%d\", skipped, max_length)\n\n    if ced_scores:\n        logger.info(\n            \"Prepared %d RSFT samples (CED scores: min=%.3f, max=%.3f, mean=%.3f)\",\n            len(formatted), min(ced_scores), max(ced_scores),\n            sum(ced_scores) / len(ced_scores),\n        )\n    return Dataset.from_list(formatted), ced_scores\n\n\nclass WeightedSFTTrainer(SFTTrainer):\n    \"\"\"SFTTrainer with CED score-weighted sampling.\n\n    高 CED score 的样本被更频繁采样。使用 WeightedRandomSampler 实现，\n    适用于单机训练。多机 DDP 场景下 Accelerate 会替换 sampler，\n    此时 weighted_sampling 不生效，需改用数据集层面的过采样。\n    \"\"\"\n\n    def __init__(self, *args, sample_weights=None, **kwargs):\n        super().__init__(*args, **kwargs)\n        self.sample_weights = sample_weights\n\n    def _get_train_sampler(self, dataset=None):\n        if self.sample_weights is not None:\n            ds = dataset if dataset is not None else self.train_dataset\n            return WeightedRandomSampler(\n                weights=self.sample_weights,\n                num_samples=len(ds),\n                replacement=True,\n            )\n        return super()._get_train_sampler(dataset)\n\n\ndef main():\n    parser = argparse.ArgumentParser(description=\"FREIGE RSFT Training\")\n    parser.add_argument(\"--base_model\", type=str, default=DEFAULT_BASE_MODEL)\n    parser.add_argument(\"--sft_adapter\", type=str, default=DEFAULT_SFT_ADAPTER,\n                        help=\"SFT warmup adapter 路径 (merge 后训练新 LoRA)\")\n    parser.add_argument(\"--rsft_data_path\", type=str, required=True,\n                        help=\"CED 筛选后的 RSFT 训练数据 (JSONL)\")\n    parser.add_argument(\"--output_dir\", type=str, required=True)\n    parser.add_argument(\"--learning_rate\", type=float, default=2e-5)\n    parser.add_argument(\"--num_epochs\", type=int, default=3)\n    parser.add_argument(\"--per_device_batch_size\", type=int, default=4)\n    parser.add_argument(\"--gradient_accumulation_steps\", type=int, default=4)\n    parser.add_argument(\"--warmup_steps\", type=int, default=100)\n    parser.add_argument(\"--save_steps\", type=int, default=50)\n    parser.add_argument(\"--save_total_limit\", type=int, default=5)\n    parser.add_argument(\"--max_length\", type=int, default=2048)\n    parser.add_argument(\"--seed\", type=int, default=42)\n    parser.add_argument(\"--wandb_project\", type=str, default=\"freige-rsft\")\n    parser.add_argument(\"--wandb_run_name\", type=str, default=None)\n    parser.add_argument(\"--weighted_sampling\", action=\"store_true\",\n                        help=\"按 CED score 加权采样（高分样本更频繁）\")\n    parser.add_argument(\"--quantize\", action=\"store_true\",\n                        help=\"启用 4-bit QLoRA 量化\")\n    parser.add_argument(\"--lora_rank\", type=int, default=64)\n    parser.add_argument(\"--lora_alpha\", type=int, default=128)\n    parser.add_argument(\"--lora_dropout\", type=float, default=0.05)\n    parser.add_argument(\"--bf16\", action=\"store_true\", default=True)\n    parser.add_argument(\"--deepspeed\", type=str, default=None,\n                        help=\"DeepSpeed 配置文件路径\")\n    args = parser.parse_args()\n\n    # W&B\n    if args.wandb_project and \"WANDB_API_KEY\" in os.environ:\n        os.environ[\"WANDB_PROJECT\"] = args.wandb_project\n        if args.wandb_run_name:\n            os.environ[\"WANDB_NAME\"] = args.wandb_run_name\n\n    # Tokenizer\n    logger.info(\"Loading tokenizer: %s\", args.base_model)\n    tokenizer = AutoTokenizer.from_pretrained(\n        args.base_model, trust_remote_code=True, padding_side=\"right\",\n    )\n    if tokenizer.pad_token is None:\n        tokenizer.pad_token = tokenizer.eos_token\n\n    # Data\n    logger.info(\"Loading RSFT data: %s\", args.rsft_data_path)\n    train_dataset, ced_scores = load_rsft_data(\n        args.rsft_data_path, tokenizer, args.max_length,\n    )\n\n    # Model: base → merge SFT adapter → new LoRA\n    logger.info(\"Loading base model: %s\", args.base_model)\n    local_rank = int(os.environ.get(\"LOCAL_RANK\", 0))\n    model_kwargs = dict(\n        trust_remote_code=True,\n        attn_implementation=\"sdpa\",\n        device_map={\"\": local_rank},\n    )\n    if args.quantize:\n        logger.info(\"Using 4-bit QLoRA quantization\")\n        model_kwargs[\"quantization_config\"] = BitsAndBytesConfig(\n            load_in_4bit=True,\n            bnb_4bit_compute_dtype=torch.bfloat16,\n            bnb_4bit_quant_type=\"nf4\",\n            bnb_4bit_use_double_quant=True,\n        )\n    else:\n        model_kwargs[\"torch_dtype\"] = torch.bfloat16 if args.bf16 else torch.float16\n\n    model = AutoModelForCausalLM.from_pretrained(args.base_model, **model_kwargs)\n\n    if args.sft_adapter:\n        logger.info(\"Merging SFT adapter: %s\", args.sft_adapter)\n        model = PeftModel.from_pretrained(model, args.sft_adapter)\n        model = model.merge_and_unload()\n\n    model.config.use_cache = False\n    model.gradient_checkpointing_enable()\n\n    # Fresh LoRA for RSFT (与 SFT warmup 相同结构)\n    lora_config = LoraConfig(\n        task_type=TaskType.CAUSAL_LM,\n        r=args.lora_rank,\n        lora_alpha=args.lora_alpha,\n        lora_dropout=args.lora_dropout,\n        target_modules=[\"q_proj\", \"k_proj\", \"v_proj\", \"o_proj\",\n                         \"gate_proj\", \"up_proj\", \"down_proj\"],\n    )\n    model = get_peft_model(model, lora_config)\n    model.print_trainable_parameters()\n\n    # Training config\n    training_args = SFTConfig(\n        output_dir=args.output_dir,\n        num_train_epochs=args.num_epochs,\n        per_device_train_batch_size=args.per_device_batch_size,\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\n        learning_rate=args.learning_rate,\n        warmup_steps=args.warmup_steps,\n        bf16=args.bf16,\n        logging_steps=10,\n        save_strategy=\"steps\",\n        save_steps=args.save_steps,\n        save_total_limit=args.save_total_limit,\n        seed=args.seed,\n        max_length=args.max_length,\n        dataset_text_field=\"text\",\n        report_to=\"wandb\" if \"WANDB_API_KEY\" in os.environ else \"none\",\n        gradient_checkpointing=True,\n        gradient_checkpointing_kwargs={\"use_reentrant\": False},\n        deepspeed=args.deepspeed,\n    )\n\n    sample_weights = ced_scores if args.weighted_sampling else None\n\n    trainer = WeightedSFTTrainer(\n        model=model,\n        args=training_args,\n        train_dataset=train_dataset,\n        processing_class=tokenizer,\n        sample_weights=sample_weights,\n    )\n\n    logger.info(\n        \"Starting RSFT training (%d samples, weighted=%s)...\",\n        len(train_dataset), args.weighted_sampling,\n    )\n    trainer.train()\n\n    logger.info(\"Saving model to %s\", args.output_dir)\n    trainer.save_model(args.output_dir)\n    tokenizer.save_pretrained(args.output_dir)\n    logger.info(\"RSFT training complete.\")\n\n\nif __name__ == \"__main__\":\n    main()\n",
    "structuredPatch": [
      {
        "oldStart": 90,
        "oldLines": 6,
        "newStart": 90,
        "newLines": 131,
        "lines": [
          "     return Dataset.from_list(formatted), ced_scores",
          " ",
          " ",
          "+def prepare_eval_data(data_dir, tokenizer, max_docs=50):",
          "+    \"\"\"Load DocRED dev set for task-level evaluation during training.\"\"\"",
          "+    from freige.data.docred_processor import DocREDProcessor",
          "+    from freige.eval.evaluator import gold_from_docred",
          "+",
          "+    processor = DocREDProcessor(data_dir=data_dir)",
          "+    samples = processor.process(\"dev\")",
          "+    groups = processor.group_by_document(samples)",
          "+",
          "+    eval_items = []",
          "+    for doc_id, doc_samples in list(groups.items())[:max_docs]:",
          "+        sft_sample = processor.format_sft_sample(doc_samples)",
          "+        messages = [",
          "+            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},",
          "+            {\"role\": \"user\", \"content\": f\"{sft_sample['instruction']}\\n\\n{sft_sample['input']}\"},",
          "+        ]",
          "+        prompt = tokenizer.apply_chat_template(",
          "+            messages, tokenize=False, add_generation_prompt=True, enable_thinking=False,",
          "+        )",
          "+        eval_items.append({\"doc_id\": doc_id, \"prompt\": prompt})",
          "+",
          "+    dev_path = os.path.join(data_dir, \"dev.json\")",
          "+    with open(dev_path) as f:",
          "+        dev_data = json.load(f)",
          "+    gold = gold_from_docred(dev_data)",
          "+",
          "+    # Also build formatted eval dataset for loss-based eval",
          "+    eval_formatted = []",
          "+    for doc_id, doc_samples in groups.items():",
          "+        sft_sample = processor.format_sft_sample(doc_samples)",
          "+        messages = [",
          "+            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},",
          "+            {\"role\": \"user\", \"content\": f\"{sft_sample['instruction']}\\n\\n{sft_sample['input']}\"},",
          "+            {\"role\": \"assistant\", \"content\": sft_sample[\"output\"]},",
          "+        ]",
          "+        text = tokenizer.apply_chat_template(",
          "+            messages, tokenize=False, add_generation_prompt=False, enable_thinking=False,",
          "+        )",
          "+        eval_formatted.append({\"text\": text})",
          "+    eval_dataset = Dataset.from_list(eval_formatted)",
          "+",
          "+    return eval_items, gold, eval_dataset",
          "+",
          "+",
          "+class TaskEvalCallback(TrainerCallback):",
          "+    \"\"\"End-of-epoch task eval: generate on dev subset → compute F1 / Evi-F1 / EDCR.\"\"\"",
          "+",
          "+    def __init__(self, tokenizer, eval_items, gold, train_file, max_new_tokens=1024):",
          "+        self.tokenizer = tokenizer",
          "+        self.eval_items = eval_items",
          "+        self.gold = gold",
          "+        self.train_file = train_file",
          "+        self.max_new_tokens = max_new_tokens",
          "+        self._evaluator = None",
          "+",
          "+    @property",
          "+    def evaluator(self):",
          "+        if self._evaluator is None:",
          "+            from freige.eval.evaluator import DocREDEvaluator",
          "+            if self.train_file and os.path.exists(self.train_file):",
          "+                self._evaluator = DocREDEvaluator.from_train_file(self.train_file)",
          "+            else:",
          "+                self._evaluator = DocREDEvaluator()",
          "+        return self._evaluator",
          "+",
          "+    def on_epoch_end(self, args, state, control, model=None, **kwargs):",
          "+        if not state.is_world_process_zero:",
          "+            return",
          "+        self._run_task_eval(model, state)",
          "+",
          "+    def _run_task_eval(self, model, state):",
          "+        from freige.eval.evaluator import parse_model_output",
          "+",
          "+        model.eval()",
          "+        model.config.use_cache = True",
          "+        if hasattr(model, \"gradient_checkpointing_disable\"):",
          "+            model.gradient_checkpointing_disable()",
          "+",
          "+        all_predictions = []",
          "+        for item in self.eval_items:",
          "+            inputs = self.tokenizer(",
          "+                item[\"prompt\"], return_tensors=\"pt\", truncation=True, max_length=4096,",
          "+            ).to(model.device)",
          "+            with torch.no_grad():",
          "+                outputs = model.generate(",
          "+                    **inputs,",
          "+                    max_new_tokens=self.max_new_tokens,",
          "+                    do_sample=False,",
          "+                    pad_token_id=self.tokenizer.pad_token_id,",
          "+                )",
          "+            generated = outputs[0][inputs[\"input_ids\"].shape[1]:]",
          "+            text = self.tokenizer.decode(generated, skip_special_tokens=True)",
          "+            triples = parse_model_output(item[\"doc_id\"], text)",
          "+            all_predictions.extend(triples)",
          "+",
          "+        metrics = self.evaluator.evaluate(all_predictions, self.gold)",
          "+",
          "+        log_metrics = {",
          "+            \"eval/rel_f1\": metrics[\"f1\"],",
          "+            \"eval/ign_f1\": metrics[\"ign_f1\"],",
          "+            \"eval/evi_f1\": metrics[\"evi_f1\"],",
          "+            \"eval/evi_precision\": metrics[\"evi_precision\"],",
          "+            \"eval/evi_recall\": metrics[\"evi_recall\"],",
          "+            \"eval/edcr\": metrics.get(\"edcr\", 0),",
          "+            \"eval/n_predictions\": len(all_predictions),",
          "+        }",
          "+        try:",
          "+            import wandb",
          "+            if wandb.run is not None:",
          "+                wandb.log(log_metrics, step=state.global_step)",
          "+        except ImportError:",
          "+            pass",
          "+",
          "+        logger.info(",
          "+            \"Task eval @ step %d: F1=%.4f, Ign-F1=%.4f, Evi-F1=%.4f, EDCR=%.4f (%d preds)\",",
          "+            state.global_step, metrics[\"f1\"], metrics[\"ign_f1\"],",
          "+            metrics[\"evi_f1\"], metrics.get(\"edcr\", 0), len(all_predictions),",
          "+        )",
          "+",
          "+        model.config.use_cache = False",
          "+        if hasattr(model, \"gradient_checkpointing_enable\"):",
          "+            model.gradient_checkpointing_enable()",
          "+        model.train()",
          "+",
          "+",
          " class WeightedSFTTrainer(SFTTrainer):",
          "     \"\"\"SFTTrainer with CED score-weighted sampling.",
          " "
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 74_

Now add the new CLI args and wire up eval in `main()`:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "d6720c9e-51f0-4e1e-b2e7-1f04a6c7b1a5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XDgBWdiojTvKSca445qEA2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1767,
      "cache_read_input_tokens": 71080,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1767
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 75_

<details open><summary>🔧 Tool call — Edit · `toolu_01G2Bo7a41rwhVeLRn2V5oGk`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py",
  "old_string": "    parser.add_argument(\"--bf16\", action=\"store_true\", default=True)\n    parser.add_argument(\"--deepspeed\", type=str, default=None,\n                        help=\"DeepSpeed 配置文件路径\")\n    args = parser.parse_args()",
  "new_string": "    parser.add_argument(\"--bf16\", action=\"store_true\", default=True)\n    parser.add_argument(\"--deepspeed\", type=str, default=None,\n                        help=\"DeepSpeed 配置文件路径\")\n    parser.add_argument(\"--eval_data_dir\", type=str, default=None,\n                        help=\"DocRED data dir (contains dev.json) for task-level eval\")\n    parser.add_argument(\"--eval_max_docs\", type=int, default=50,\n                        help=\"Max dev docs for task-level eval during training\")\n    parser.add_argument(\"--max_new_tokens\", type=int, default=1024)\n    args = parser.parse_args()"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "95f2fb43-f04c-45a9-bbf2-17bc6cb1c52c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XDgBWdiojTvKSca445qEA2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1767,
      "cache_read_input_tokens": 71080,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1767
      },
      "output_tokens": 4,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 76 · 2026-05-15T02:29:01.528Z_

<details><summary>↩ Tool result · `toolu_01G2Bo7a41rwhVeLRn2V5oGk`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "d1087cdc-6ee6-4f90-8d5b-4d3f9bd048d9",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py",
    "oldString": "    parser.add_argument(\"--bf16\", action=\"store_true\", default=True)\n    parser.add_argument(\"--deepspeed\", type=str, default=None,\n                        help=\"DeepSpeed 配置文件路径\")\n    args = parser.parse_args()",
    "newString": "    parser.add_argument(\"--bf16\", action=\"store_true\", default=True)\n    parser.add_argument(\"--deepspeed\", type=str, default=None,\n                        help=\"DeepSpeed 配置文件路径\")\n    parser.add_argument(\"--eval_data_dir\", type=str, default=None,\n                        help=\"DocRED data dir (contains dev.json) for task-level eval\")\n    parser.add_argument(\"--eval_max_docs\", type=int, default=50,\n                        help=\"Max dev docs for task-level eval during training\")\n    parser.add_argument(\"--max_new_tokens\", type=int, default=1024)\n    args = parser.parse_args()",
    "originalFile": "\"\"\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\n\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\n\n输入: JSONL，每行 {\"doc_id\": ..., \"input\": ..., \"output\": ..., \"ced_score\": ..., ...}\n输出: QLoRA adapter checkpoint\n依赖: transformers, trl, peft, bitsandbytes, datasets\n\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n\"\"\"\n\nimport argparse\nimport json\nimport logging\nimport os\n\nimport torch\nfrom datasets import Dataset\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\nfrom torch.utils.data import WeightedRandomSampler\nfrom transformers import (\n    AutoModelForCausalLM,\n    AutoTokenizer,\n    BitsAndBytesConfig,\n    TrainerCallback,\n)\nfrom trl import SFTConfig, SFTTrainer\n\nfrom freige.training.sft_trainer import SYSTEM_PROMPT\n\nlogging.basicConfig(level=logging.INFO, format=\"%(asctime)s %(levelname)s %(message)s\")\nlogger = logging.getLogger(__name__)\n\nDEFAULT_BASE_MODEL = \"/root/autodl-tmp/models/Qwen3-4B\"\nDEFAULT_SFT_ADAPTER = \"/root/autodl-tmp/sft_output\"\n\n\ndef load_rsft_data(data_path: str, tokenizer, max_length: int = 2048):\n    \"\"\"加载 CED 筛选后的 RSFT 数据，格式化为 chat template 文本。\n\n    每行 JSONL 的 input 字段作为 user message，output 字段作为 assistant response，\n    经 apply_chat_template 拼接后用于 SFT 训练。超过 max_length 的样本被跳过\n    而非截断，避免训练在不完整 JSON 输出上。\n\n    Returns:\n        (Dataset, list[float]): 训练数据集和对应的 CED scores\n    \"\"\"\n    samples = []\n    with open(data_path) as f:\n        for line in f:\n            if line.strip():\n                samples.append(json.loads(line))\n\n    logger.info(\"Loaded %d RSFT samples from %s\", len(samples), data_path)\n\n    formatted = []\n    ced_scores = []\n    skipped = 0\n    for s in samples:\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": s[\"input\"]},\n            {\"role\": \"assistant\", \"content\": s[\"output\"]},\n        ]\n        text = tokenizer.apply_chat_template(\n            messages,\n            tokenize=False,\n            add_generation_prompt=False,\n            enable_thinking=False,\n        )\n        token_len = len(tokenizer.encode(text, add_special_tokens=False))\n        if token_len > max_length:\n            skipped += 1\n            continue\n        formatted.append({\"text\": text})\n        ced_scores.append(s.get(\"ced_score\", 1.0))\n\n    if skipped:\n        logger.warning(\"Skipped %d samples exceeding max_length=%d\", skipped, max_length)\n\n    if ced_scores:\n        logger.info(\n            \"Prepared %d RSFT samples (CED scores: min=%.3f, max=%.3f, mean=%.3f)\",\n            len(formatted), min(ced_scores), max(ced_scores),\n            sum(ced_scores) / len(ced_scores),\n        )\n    return Dataset.from_list(formatted), ced_scores\n\n\ndef prepare_eval_data(data_dir, tokenizer, max_docs=50):\n    \"\"\"Load DocRED dev set for task-level evaluation during training.\"\"\"\n    from freige.data.docred_processor import DocREDProcessor\n    from freige.eval.evaluator import gold_from_docred\n\n    processor = DocREDProcessor(data_dir=data_dir)\n    samples = processor.process(\"dev\")\n    groups = processor.group_by_document(samples)\n\n    eval_items = []\n    for doc_id, doc_samples in list(groups.items())[:max_docs]:\n        sft_sample = processor.format_sft_sample(doc_samples)\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": f\"{sft_sample['instruction']}\\n\\n{sft_sample['input']}\"},\n        ]\n        prompt = tokenizer.apply_chat_template(\n            messages, tokenize=False, add_generation_prompt=True, enable_thinking=False,\n        )\n        eval_items.append({\"doc_id\": doc_id, \"prompt\": prompt})\n\n    dev_path = os.path.join(data_dir, \"dev.json\")\n    with open(dev_path) as f:\n        dev_data = json.load(f)\n    gold = gold_from_docred(dev_data)\n\n    # Also build formatted eval dataset for loss-based eval\n    eval_formatted = []\n    for doc_id, doc_samples in groups.items():\n        sft_sample = processor.format_sft_sample(doc_samples)\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": f\"{sft_sample['instruction']}\\n\\n{sft_sample['input']}\"},\n            {\"role\": \"assistant\", \"content\": sft_sample[\"output\"]},\n        ]\n        text = tokenizer.apply_chat_template(\n            messages, tokenize=False, add_generation_prompt=False, enable_thinking=False,\n        )\n        eval_formatted.append({\"text\": text})\n    eval_dataset = Dataset.from_list(eval_formatted)\n\n    return eval_items, gold, eval_dataset\n\n\nclass TaskEvalCallback(TrainerCallback):\n    \"\"\"End-of-epoch task eval: generate on dev subset → compute F1 / Evi-F1 / EDCR.\"\"\"\n\n    def __init__(self, tokenizer, eval_items, gold, train_file, max_new_tokens=1024):\n        self.tokenizer = tokenizer\n        self.eval_items = eval_items\n        self.gold = gold\n        self.train_file = train_file\n        self.max_new_tokens = max_new_tokens\n        self._evaluator = None\n\n    @property\n    def evaluator(self):\n        if self._evaluator is None:\n            from freige.eval.evaluator import DocREDEvaluator\n            if self.train_file and os.path.exists(self.train_file):\n                self._evaluator = DocREDEvaluator.from_train_file(self.train_file)\n            else:\n                self._evaluator = DocREDEvaluator()\n        return self._evaluator\n\n    def on_epoch_end(self, args, state, control, model=None, **kwargs):\n        if not state.is_world_process_zero:\n            return\n        self._run_task_eval(model, state)\n\n    def _run_task_eval(self, model, state):\n        from freige.eval.evaluator import parse_model_output\n\n        model.eval()\n        model.config.use_cache = True\n        if hasattr(model, \"gradient_checkpointing_disable\"):\n            model.gradient_checkpointing_disable()\n\n        all_predictions = []\n        for item in self.eval_items:\n            inputs = self.tokenizer(\n                item[\"prompt\"], return_tensors=\"pt\", truncation=True, max_length=4096,\n            ).to(model.device)\n            with torch.no_grad():\n                outputs = model.generate(\n                    **inputs,\n                    max_new_tokens=self.max_new_tokens,\n                    do_sample=False,\n                    pad_token_id=self.tokenizer.pad_token_id,\n                )\n            generated = outputs[0][inputs[\"input_ids\"].shape[1]:]\n            text = self.tokenizer.decode(generated, skip_special_tokens=True)\n            triples = parse_model_output(item[\"doc_id\"], text)\n            all_predictions.extend(triples)\n\n        metrics = self.evaluator.evaluate(all_predictions, self.gold)\n\n        log_metrics = {\n            \"eval/rel_f1\": metrics[\"f1\"],\n            \"eval/ign_f1\": metrics[\"ign_f1\"],\n            \"eval/evi_f1\": metrics[\"evi_f1\"],\n            \"eval/evi_precision\": metrics[\"evi_precision\"],\n            \"eval/evi_recall\": metrics[\"evi_recall\"],\n            \"eval/edcr\": metrics.get(\"edcr\", 0),\n            \"eval/n_predictions\": len(all_predictions),\n        }\n        try:\n            import wandb\n            if wandb.run is not None:\n                wandb.log(log_metrics, step=state.global_step)\n        except ImportError:\n            pass\n\n        logger.info(\n            \"Task eval @ step %d: F1=%.4f, Ign-F1=%.4f, Evi-F1=%.4f, EDCR=%.4f (%d preds)\",\n            state.global_step, metrics[\"f1\"], metrics[\"ign_f1\"],\n            metrics[\"evi_f1\"], metrics.get(\"edcr\", 0), len(all_predictions),\n        )\n\n        model.config.use_cache = False\n        if hasattr(model, \"gradient_checkpointing_enable\"):\n            model.gradient_checkpointing_enable()\n        model.train()\n\n\nclass WeightedSFTTrainer(SFTTrainer):\n    \"\"\"SFTTrainer with CED score-weighted sampling.\n\n    高 CED score 的样本被更频繁采样。使用 WeightedRandomSampler 实现，\n    适用于单机训练。多机 DDP 场景下 Accelerate 会替换 sampler，\n    此时 weighted_sampling 不生效，需改用数据集层面的过采样。\n    \"\"\"\n\n    def __init__(self, *args, sample_weights=None, **kwargs):\n        super().__init__(*args, **kwargs)\n        self.sample_weights = sample_weights\n\n    def _get_train_sampler(self, dataset=None):\n        if self.sample_weights is not None:\n            ds = dataset if dataset is not None else self.train_dataset\n            return WeightedRandomSampler(\n                weights=self.sample_weights,\n                num_samples=len(ds),\n                replacement=True,\n            )\n        return super()._get_train_sampler(dataset)\n\n\ndef main():\n    parser = argparse.ArgumentParser(description=\"FREIGE RSFT Training\")\n    parser.add_argument(\"--base_model\", type=str, default=DEFAULT_BASE_MODEL)\n    parser.add_argument(\"--sft_adapter\", type=str, default=DEFAULT_SFT_ADAPTER,\n                        help=\"SFT warmup adapter 路径 (merge 后训练新 LoRA)\")\n    parser.add_argument(\"--rsft_data_path\", type=str, required=True,\n                        help=\"CED 筛选后的 RSFT 训练数据 (JSONL)\")\n    parser.add_argument(\"--output_dir\", type=str, required=True)\n    parser.add_argument(\"--learning_rate\", type=float, default=2e-5)\n    parser.add_argument(\"--num_epochs\", type=int, default=3)\n    parser.add_argument(\"--per_device_batch_size\", type=int, default=4)\n    parser.add_argument(\"--gradient_accumulation_steps\", type=int, default=4)\n    parser.add_argument(\"--warmup_steps\", type=int, default=100)\n    parser.add_argument(\"--save_steps\", type=int, default=50)\n    parser.add_argument(\"--save_total_limit\", type=int, default=5)\n    parser.add_argument(\"--max_length\", type=int, default=2048)\n    parser.add_argument(\"--seed\", type=int, default=42)\n    parser.add_argument(\"--wandb_project\", type=str, default=\"freige-rsft\")\n    parser.add_argument(\"--wandb_run_name\", type=str, default=None)\n    parser.add_argument(\"--weighted_sampling\", action=\"store_true\",\n                        help=\"按 CED score 加权采样（高分样本更频繁）\")\n    parser.add_argument(\"--quantize\", action=\"store_true\",\n                        help=\"启用 4-bit QLoRA 量化\")\n    parser.add_argument(\"--lora_rank\", type=int, default=64)\n    parser.add_argument(\"--lora_alpha\", type=int, default=128)\n    parser.add_argument(\"--lora_dropout\", type=float, default=0.05)\n    parser.add_argument(\"--bf16\", action=\"store_true\", default=True)\n    parser.add_argument(\"--deepspeed\", type=str, default=None,\n                        help=\"DeepSpeed 配置文件路径\")\n    args = parser.parse_args()\n\n    # W&B\n    if args.wandb_project and \"WANDB_API_KEY\" in os.environ:\n        os.environ[\"WANDB_PROJECT\"] = args.wandb_project\n        if args.wandb_run_name:\n            os.environ[\"WANDB_NAME\"] = args.wandb_run_name\n\n    # Tokenizer\n    logger.info(\"Loading tokenizer: %s\", args.base_model)\n    tokenizer = AutoTokenizer.from_pretrained(\n        args.base_model, trust_remote_code=True, padding_side=\"right\",\n    )\n    if tokenizer.pad_token is None:\n        tokenizer.pad_token = tokenizer.eos_token\n\n    # Data\n    logger.info(\"Loading RSFT data: %s\", args.rsft_data_path)\n    train_dataset, ced_scores = load_rsft_data(\n        args.rsft_data_path, tokenizer, args.max_length,\n    )\n\n    # Model: base → merge SFT adapter → new LoRA\n    logger.info(\"Loading base model: %s\", args.base_model)\n    local_rank = int(os.environ.get(\"LOCAL_RANK\", 0))\n    model_kwargs = dict(\n        trust_remote_code=True,\n        attn_implementation=\"sdpa\",\n        device_map={\"\": local_rank},\n    )\n    if args.quantize:\n        logger.info(\"Using 4-bit QLoRA quantization\")\n        model_kwargs[\"quantization_config\"] = BitsAndBytesConfig(\n            load_in_4bit=True,\n            bnb_4bit_compute_dtype=torch.bfloat16,\n            bnb_4bit_quant_type=\"nf4\",\n            bnb_4bit_use_double_quant=True,\n        )\n    else:\n        model_kwargs[\"torch_dtype\"] = torch.bfloat16 if args.bf16 else torch.float16\n\n    model = AutoModelForCausalLM.from_pretrained(args.base_model, **model_kwargs)\n\n    if args.sft_adapter:\n        logger.info(\"Merging SFT adapter: %s\", args.sft_adapter)\n        model = PeftModel.from_pretrained(model, args.sft_adapter)\n        model = model.merge_and_unload()\n\n    model.config.use_cache = False\n    model.gradient_checkpointing_enable()\n\n    # Fresh LoRA for RSFT (与 SFT warmup 相同结构)\n    lora_config = LoraConfig(\n        task_type=TaskType.CAUSAL_LM,\n        r=args.lora_rank,\n        lora_alpha=args.lora_alpha,\n        lora_dropout=args.lora_dropout,\n        target_modules=[\"q_proj\", \"k_proj\", \"v_proj\", \"o_proj\",\n                         \"gate_proj\", \"up_proj\", \"down_proj\"],\n    )\n    model = get_peft_model(model, lora_config)\n    model.print_trainable_parameters()\n\n    # Training config\n    training_args = SFTConfig(\n        output_dir=args.output_dir,\n        num_train_epochs=args.num_epochs,\n        per_device_train_batch_size=args.per_device_batch_size,\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\n        learning_rate=args.learning_rate,\n        warmup_steps=args.warmup_steps,\n        bf16=args.bf16,\n        logging_steps=10,\n        save_strategy=\"steps\",\n        save_steps=args.save_steps,\n        save_total_limit=args.save_total_limit,\n        seed=args.seed,\n        max_length=args.max_length,\n        dataset_text_field=\"text\",\n        report_to=\"wandb\" if \"WANDB_API_KEY\" in os.environ else \"none\",\n        gradient_checkpointing=True,\n        gradient_checkpointing_kwargs={\"use_reentrant\": False},\n        deepspeed=args.deepspeed,\n    )\n\n    sample_weights = ced_scores if args.weighted_sampling else None\n\n    trainer = WeightedSFTTrainer(\n        model=model,\n        args=training_args,\n        train_dataset=train_dataset,\n        processing_class=tokenizer,\n        sample_weights=sample_weights,\n    )\n\n    logger.info(\n        \"Starting RSFT training (%d samples, weighted=%s)...\",\n        len(train_dataset), args.weighted_sampling,\n    )\n    trainer.train()\n\n    logger.info(\"Saving model to %s\", args.output_dir)\n    trainer.save_model(args.output_dir)\n    tokenizer.save_pretrained(args.output_dir)\n    logger.info(\"RSFT training complete.\")\n\n\nif __name__ == \"__main__\":\n    main()\n",
    "structuredPatch": [
      {
        "oldStart": 267,
        "oldLines": 6,
        "newStart": 267,
        "newLines": 11,
        "lines": [
          "     parser.add_argument(\"--bf16\", action=\"store_true\", default=True)",
          "     parser.add_argument(\"--deepspeed\", type=str, default=None,",
          "                         help=\"DeepSpeed 配置文件路径\")",
          "+    parser.add_argument(\"--eval_data_dir\", type=str, default=None,",
          "+                        help=\"DocRED data dir (contains dev.json) for task-level eval\")",
          "+    parser.add_argument(\"--eval_max_docs\", type=int, default=50,",
          "+                        help=\"Max dev docs for task-level eval during training\")",
          "+    parser.add_argument(\"--max_new_tokens\", type=int, default=1024)",
          "     args = parser.parse_args()",
          " ",
          "     # W&B"
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 77_

Now wire up the eval data and callback in the training section:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "8251ef19-fb41-41bc-8bdb-3c37e6db4bc2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UNNUNpB357LzuohtbrTVtP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 467,
      "cache_read_input_tokens": 72847,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 467
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 78_

<details open><summary>🔧 Tool call — Edit · `toolu_01GTqTMhje2a3G3Dm52Rhkew`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py",
  "old_string": "    # Training config\n    training_args = SFTConfig(\n        output_dir=args.output_dir,\n        num_train_epochs=args.num_epochs,\n        per_device_train_batch_size=args.per_device_batch_size,\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\n        learning_rate=args.learning_rate,\n        warmup_steps=args.warmup_steps,\n        bf16=args.bf16,\n        logging_steps=10,\n        save_strategy=\"steps\",\n        save_steps=args.save_steps,\n        save_total_limit=args.save_total_limit,\n        seed=args.seed,\n        max_length=args.max_length,\n        dataset_text_field=\"text\",\n        report_to=\"wandb\" if \"WANDB_API_KEY\" in os.environ else \"none\",\n        gradient_checkpointing=True,\n        gradient_checkpointing_kwargs={\"use_reentrant\": False},\n        deepspeed=args.deepspeed,\n    )\n\n    sample_weights = ced_scores if args.weighted_sampling else None\n\n    trainer = WeightedSFTTrainer(\n        model=model,\n        args=training_args,\n        train_dataset=train_dataset,\n        processing_class=tokenizer,\n        sample_weights=sample_weights,\n    )\n\n    logger.info(\n        \"Starting RSFT training (%d samples, weighted=%s)...\",\n        len(train_dataset), args.weighted_sampling,\n    )\n    trainer.train()",
  "new_string": "    # Eval data\n    eval_dataset = None\n    callbacks = []\n    if args.eval_data_dir:\n        logger.info(\"Loading eval data from %s (max %d docs for task eval)\",\n                     args.eval_data_dir, args.eval_max_docs)\n        eval_items, gold, eval_dataset = prepare_eval_data(\n            args.eval_data_dir, tokenizer, args.eval_max_docs,\n        )\n        train_file = os.path.join(args.eval_data_dir, \"train_annotated.json\")\n        callbacks.append(TaskEvalCallback(\n            tokenizer=tokenizer,\n            eval_items=eval_items,\n            gold=gold,\n            train_file=train_file,\n            max_new_tokens=args.max_new_tokens,\n        ))\n        logger.info(\"Task eval enabled: %d docs, %d gold triples\",\n                     len(eval_items), len(gold))\n\n    # Training config\n    training_args = SFTConfig(\n        output_dir=args.output_dir,\n        num_train_epochs=args.num_epochs,\n        per_device_train_batch_size=args.per_device_batch_size,\n        per_device_eval_batch_size=1,\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\n        learning_rate=args.learning_rate,\n        warmup_steps=args.warmup_steps,\n        bf16=args.bf16,\n        logging_steps=10,\n        eval_strategy=\"epoch\" if eval_dataset is not None else \"no\",\n        save_strategy=\"steps\",\n        save_steps=args.save_steps,\n        save_total_limit=args.save_total_limit,\n        seed=args.seed,\n        max_length=args.max_length,\n        dataset_text_field=\"text\",\n        report_to=\"wandb\" if \"WANDB_API_KEY\" in os.environ else \"none\",\n        gradient_checkpointing=True,\n        gradient_checkpointing_kwargs={\"use_reentrant\": False},\n        deepspeed=args.deepspeed,\n    )\n\n    sample_weights = ced_scores if args.weighted_sampling else None\n\n    trainer = WeightedSFTTrainer(\n        model=model,\n        args=training_args,\n        train_dataset=train_dataset,\n        eval_dataset=eval_dataset,\n        processing_class=tokenizer,\n        sample_weights=sample_weights,\n        callbacks=callbacks,\n    )\n\n    logger.info(\n        \"Starting RSFT training (%d samples, weighted=%s)...\",\n        len(train_dataset), args.weighted_sampling,\n    )\n    trainer.train()"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "52811911-7306-47fe-8c9f-9f83f2e9625a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01UNNUNpB357LzuohtbrTVtP",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 467,
      "cache_read_input_tokens": 72847,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 467
      },
      "output_tokens": 2,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 79 · 2026-05-15T02:29:16.225Z_

<details><summary>↩ Tool result · `toolu_01GTqTMhje2a3G3Dm52Rhkew`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "ccd7169d-0b31-4c98-b373-ff973a94c970",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py",
    "oldString": "    # Training config\n    training_args = SFTConfig(\n        output_dir=args.output_dir,\n        num_train_epochs=args.num_epochs,\n        per_device_train_batch_size=args.per_device_batch_size,\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\n        learning_rate=args.learning_rate,\n        warmup_steps=args.warmup_steps,\n        bf16=args.bf16,\n        logging_steps=10,\n        save_strategy=\"steps\",\n        save_steps=args.save_steps,\n        save_total_limit=args.save_total_limit,\n        seed=args.seed,\n        max_length=args.max_length,\n        dataset_text_field=\"text\",\n        report_to=\"wandb\" if \"WANDB_API_KEY\" in os.environ else \"none\",\n        gradient_checkpointing=True,\n        gradient_checkpointing_kwargs={\"use_reentrant\": False},\n        deepspeed=args.deepspeed,\n    )\n\n    sample_weights = ced_scores if args.weighted_sampling else None\n\n    trainer = WeightedSFTTrainer(\n        model=model,\n        args=training_args,\n        train_dataset=train_dataset,\n        processing_class=tokenizer,\n        sample_weights=sample_weights,\n    )\n\n    logger.info(\n        \"Starting RSFT training (%d samples, weighted=%s)...\",\n        len(train_dataset), args.weighted_sampling,\n    )\n    trainer.train()",
    "newString": "    # Eval data\n    eval_dataset = None\n    callbacks = []\n    if args.eval_data_dir:\n        logger.info(\"Loading eval data from %s (max %d docs for task eval)\",\n                     args.eval_data_dir, args.eval_max_docs)\n        eval_items, gold, eval_dataset = prepare_eval_data(\n            args.eval_data_dir, tokenizer, args.eval_max_docs,\n        )\n        train_file = os.path.join(args.eval_data_dir, \"train_annotated.json\")\n        callbacks.append(TaskEvalCallback(\n            tokenizer=tokenizer,\n            eval_items=eval_items,\n            gold=gold,\n            train_file=train_file,\n            max_new_tokens=args.max_new_tokens,\n        ))\n        logger.info(\"Task eval enabled: %d docs, %d gold triples\",\n                     len(eval_items), len(gold))\n\n    # Training config\n    training_args = SFTConfig(\n        output_dir=args.output_dir,\n        num_train_epochs=args.num_epochs,\n        per_device_train_batch_size=args.per_device_batch_size,\n        per_device_eval_batch_size=1,\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\n        learning_rate=args.learning_rate,\n        warmup_steps=args.warmup_steps,\n        bf16=args.bf16,\n        logging_steps=10,\n        eval_strategy=\"epoch\" if eval_dataset is not None else \"no\",\n        save_strategy=\"steps\",\n        save_steps=args.save_steps,\n        save_total_limit=args.save_total_limit,\n        seed=args.seed,\n        max_length=args.max_length,\n        dataset_text_field=\"text\",\n        report_to=\"wandb\" if \"WANDB_API_KEY\" in os.environ else \"none\",\n        gradient_checkpointing=True,\n        gradient_checkpointing_kwargs={\"use_reentrant\": False},\n        deepspeed=args.deepspeed,\n    )\n\n    sample_weights = ced_scores if args.weighted_sampling else None\n\n    trainer = WeightedSFTTrainer(\n        model=model,\n        args=training_args,\n        train_dataset=train_dataset,\n        eval_dataset=eval_dataset,\n        processing_class=tokenizer,\n        sample_weights=sample_weights,\n        callbacks=callbacks,\n    )\n\n    logger.info(\n        \"Starting RSFT training (%d samples, weighted=%s)...\",\n        len(train_dataset), args.weighted_sampling,\n    )\n    trainer.train()",
    "originalFile": "\"\"\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\n\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\n\n输入: JSONL，每行 {\"doc_id\": ..., \"input\": ..., \"output\": ..., \"ced_score\": ..., ...}\n输出: QLoRA adapter checkpoint\n依赖: transformers, trl, peft, bitsandbytes, datasets\n\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n\"\"\"\n\nimport argparse\nimport json\nimport logging\nimport os\n\nimport torch\nfrom datasets import Dataset\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\nfrom torch.utils.data import WeightedRandomSampler\nfrom transformers import (\n    AutoModelForCausalLM,\n    AutoTokenizer,\n    BitsAndBytesConfig,\n    TrainerCallback,\n)\nfrom trl import SFTConfig, SFTTrainer\n\nfrom freige.training.sft_trainer import SYSTEM_PROMPT\n\nlogging.basicConfig(level=logging.INFO, format=\"%(asctime)s %(levelname)s %(message)s\")\nlogger = logging.getLogger(__name__)\n\nDEFAULT_BASE_MODEL = \"/root/autodl-tmp/models/Qwen3-4B\"\nDEFAULT_SFT_ADAPTER = \"/root/autodl-tmp/sft_output\"\n\n\ndef load_rsft_data(data_path: str, tokenizer, max_length: int = 2048):\n    \"\"\"加载 CED 筛选后的 RSFT 数据，格式化为 chat template 文本。\n\n    每行 JSONL 的 input 字段作为 user message，output 字段作为 assistant response，\n    经 apply_chat_template 拼接后用于 SFT 训练。超过 max_length 的样本被跳过\n    而非截断，避免训练在不完整 JSON 输出上。\n\n    Returns:\n        (Dataset, list[float]): 训练数据集和对应的 CED scores\n    \"\"\"\n    samples = []\n    with open(data_path) as f:\n        for line in f:\n            if line.strip():\n                samples.append(json.loads(line))\n\n    logger.info(\"Loaded %d RSFT samples from %s\", len(samples), data_path)\n\n    formatted = []\n    ced_scores = []\n    skipped = 0\n    for s in samples:\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": s[\"input\"]},\n            {\"role\": \"assistant\", \"content\": s[\"output\"]},\n        ]\n        text = tokenizer.apply_chat_template(\n            messages,\n            tokenize=False,\n            add_generation_prompt=False,\n            enable_thinking=False,\n        )\n        token_len = len(tokenizer.encode(text, add_special_tokens=False))\n        if token_len > max_length:\n            skipped += 1\n            continue\n        formatted.append({\"text\": text})\n        ced_scores.append(s.get(\"ced_score\", 1.0))\n\n    if skipped:\n        logger.warning(\"Skipped %d samples exceeding max_length=%d\", skipped, max_length)\n\n    if ced_scores:\n        logger.info(\n            \"Prepared %d RSFT samples (CED scores: min=%.3f, max=%.3f, mean=%.3f)\",\n            len(formatted), min(ced_scores), max(ced_scores),\n            sum(ced_scores) / len(ced_scores),\n        )\n    return Dataset.from_list(formatted), ced_scores\n\n\ndef prepare_eval_data(data_dir, tokenizer, max_docs=50):\n    \"\"\"Load DocRED dev set for task-level evaluation during training.\"\"\"\n    from freige.data.docred_processor import DocREDProcessor\n    from freige.eval.evaluator import gold_from_docred\n\n    processor = DocREDProcessor(data_dir=data_dir)\n    samples = processor.process(\"dev\")\n    groups = processor.group_by_document(samples)\n\n    eval_items = []\n    for doc_id, doc_samples in list(groups.items())[:max_docs]:\n        sft_sample = processor.format_sft_sample(doc_samples)\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": f\"{sft_sample['instruction']}\\n\\n{sft_sample['input']}\"},\n        ]\n        prompt = tokenizer.apply_chat_template(\n            messages, tokenize=False, add_generation_prompt=True, enable_thinking=False,\n        )\n        eval_items.append({\"doc_id\": doc_id, \"prompt\": prompt})\n\n    dev_path = os.path.join(data_dir, \"dev.json\")\n    with open(dev_path) as f:\n        dev_data = json.load(f)\n    gold = gold_from_docred(dev_data)\n\n    # Also build formatted eval dataset for loss-based eval\n    eval_formatted = []\n    for doc_id, doc_samples in groups.items():\n        sft_sample = processor.format_sft_sample(doc_samples)\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": f\"{sft_sample['instruction']}\\n\\n{sft_sample['input']}\"},\n            {\"role\": \"assistant\", \"content\": sft_sample[\"output\"]},\n        ]\n        text = tokenizer.apply_chat_template(\n            messages, tokenize=False, add_generation_prompt=False, enable_thinking=False,\n        )\n        eval_formatted.append({\"text\": text})\n    eval_dataset = Dataset.from_list(eval_formatted)\n\n    return eval_items, gold, eval_dataset\n\n\nclass TaskEvalCallback(TrainerCallback):\n    \"\"\"End-of-epoch task eval: generate on dev subset → compute F1 / Evi-F1 / EDCR.\"\"\"\n\n    def __init__(self, tokenizer, eval_items, gold, train_file, max_new_tokens=1024):\n        self.tokenizer = tokenizer\n        self.eval_items = eval_items\n        self.gold = gold\n        self.train_file = train_file\n        self.max_new_tokens = max_new_tokens\n        self._evaluator = None\n\n    @property\n    def evaluator(self):\n        if self._evaluator is None:\n            from freige.eval.evaluator import DocREDEvaluator\n            if self.train_file and os.path.exists(self.train_file):\n                self._evaluator = DocREDEvaluator.from_train_file(self.train_file)\n            else:\n                self._evaluator = DocREDEvaluator()\n        return self._evaluator\n\n    def on_epoch_end(self, args, state, control, model=None, **kwargs):\n        if not state.is_world_process_zero:\n            return\n        self._run_task_eval(model, state)\n\n    def _run_task_eval(self, model, state):\n        from freige.eval.evaluator import parse_model_output\n\n        model.eval()\n        model.config.use_cache = True\n        if hasattr(model, \"gradient_checkpointing_disable\"):\n            model.gradient_checkpointing_disable()\n\n        all_predictions = []\n        for item in self.eval_items:\n            inputs = self.tokenizer(\n                item[\"prompt\"], return_tensors=\"pt\", truncation=True, max_length=4096,\n            ).to(model.device)\n            with torch.no_grad():\n                outputs = model.generate(\n                    **inputs,\n                    max_new_tokens=self.max_new_tokens,\n                    do_sample=False,\n                    pad_token_id=self.tokenizer.pad_token_id,\n                )\n            generated = outputs[0][inputs[\"input_ids\"].shape[1]:]\n            text = self.tokenizer.decode(generated, skip_special_tokens=True)\n            triples = parse_model_output(item[\"doc_id\"], text)\n            all_predictions.extend(triples)\n\n        metrics = self.evaluator.evaluate(all_predictions, self.gold)\n\n        log_metrics = {\n            \"eval/rel_f1\": metrics[\"f1\"],\n            \"eval/ign_f1\": metrics[\"ign_f1\"],\n            \"eval/evi_f1\": metrics[\"evi_f1\"],\n            \"eval/evi_precision\": metrics[\"evi_precision\"],\n            \"eval/evi_recall\": metrics[\"evi_recall\"],\n            \"eval/edcr\": metrics.get(\"edcr\", 0),\n            \"eval/n_predictions\": len(all_predictions),\n        }\n        try:\n            import wandb\n            if wandb.run is not None:\n                wandb.log(log_metrics, step=state.global_step)\n        except ImportError:\n            pass\n\n        logger.info(\n            \"Task eval @ step %d: F1=%.4f, Ign-F1=%.4f, Evi-F1=%.4f, EDCR=%.4f (%d preds)\",\n            state.global_step, metrics[\"f1\"], metrics[\"ign_f1\"],\n            metrics[\"evi_f1\"], metrics.get(\"edcr\", 0), len(all_predictions),\n        )\n\n        model.config.use_cache = False\n        if hasattr(model, \"gradient_checkpointing_enable\"):\n            model.gradient_checkpointing_enable()\n        model.train()\n\n\nclass WeightedSFTTrainer(SFTTrainer):\n    \"\"\"SFTTrainer with CED score-weighted sampling.\n\n    高 CED score 的样本被更频繁采样。使用 WeightedRandomSampler 实现，\n    适用于单机训练。多机 DDP 场景下 Accelerate 会替换 sampler，\n    此时 weighted_sampling 不生效，需改用数据集层面的过采样。\n    \"\"\"\n\n    def __init__(self, *args, sample_weights=None, **kwargs):\n        super().__init__(*args, **kwargs)\n        self.sample_weights = sample_weights\n\n    def _get_train_sampler(self, dataset=None):\n        if self.sample_weights is not None:\n            ds = dataset if dataset is not None else self.train_dataset\n            return WeightedRandomSampler(\n                weights=self.sample_weights,\n                num_samples=len(ds),\n                replacement=True,\n            )\n        return super()._get_train_sampler(dataset)\n\n\ndef main():\n    parser = argparse.ArgumentParser(description=\"FREIGE RSFT Training\")\n    parser.add_argument(\"--base_model\", type=str, default=DEFAULT_BASE_MODEL)\n    parser.add_argument(\"--sft_adapter\", type=str, default=DEFAULT_SFT_ADAPTER,\n                        help=\"SFT warmup adapter 路径 (merge 后训练新 LoRA)\")\n    parser.add_argument(\"--rsft_data_path\", type=str, required=True,\n                        help=\"CED 筛选后的 RSFT 训练数据 (JSONL)\")\n    parser.add_argument(\"--output_dir\", type=str, required=True)\n    parser.add_argument(\"--learning_rate\", type=float, default=2e-5)\n    parser.add_argument(\"--num_epochs\", type=int, default=3)\n    parser.add_argument(\"--per_device_batch_size\", type=int, default=4)\n    parser.add_argument(\"--gradient_accumulation_steps\", type=int, default=4)\n    parser.add_argument(\"--warmup_steps\", type=int, default=100)\n    parser.add_argument(\"--save_steps\", type=int, default=50)\n    parser.add_argument(\"--save_total_limit\", type=int, default=5)\n    parser.add_argument(\"--max_length\", type=int, default=2048)\n    parser.add_argument(\"--seed\", type=int, default=42)\n    parser.add_argument(\"--wandb_project\", type=str, default=\"freige-rsft\")\n    parser.add_argument(\"--wandb_run_name\", type=str, default=None)\n    parser.add_argument(\"--weighted_sampling\", action=\"store_true\",\n                        help=\"按 CED score 加权采样（高分样本更频繁）\")\n    parser.add_argument(\"--quantize\", action=\"store_true\",\n                        help=\"启用 4-bit QLoRA 量化\")\n    parser.add_argument(\"--lora_rank\", type=int, default=64)\n    parser.add_argument(\"--lora_alpha\", type=int, default=128)\n    parser.add_argument(\"--lora_dropout\", type=float, default=0.05)\n    parser.add_argument(\"--bf16\", action=\"store_true\", default=True)\n    parser.add_argument(\"--deepspeed\", type=str, default=None,\n                        help=\"DeepSpeed 配置文件路径\")\n    parser.add_argument(\"--eval_data_dir\", type=str, default=None,\n                        help=\"DocRED data dir (contains dev.json) for task-level eval\")\n    parser.add_argument(\"--eval_max_docs\", type=int, default=50,\n                        help=\"Max dev docs for task-level eval during training\")\n    parser.add_argument(\"--max_new_tokens\", type=int, default=1024)\n    args = parser.parse_args()\n\n    # W&B\n    if args.wandb_project and \"WANDB_API_KEY\" in os.environ:\n        os.environ[\"WANDB_PROJECT\"] = args.wandb_project\n        if args.wandb_run_name:\n            os.environ[\"WANDB_NAME\"] = args.wandb_run_name\n\n    # Tokenizer\n    logger.info(\"Loading tokenizer: %s\", args.base_model)\n    tokenizer = AutoTokenizer.from_pretrained(\n        args.base_model, trust_remote_code=True, padding_side=\"right\",\n    )\n    if tokenizer.pad_token is None:\n        tokenizer.pad_token = tokenizer.eos_token\n\n    # Data\n    logger.info(\"Loading RSFT data: %s\", args.rsft_data_path)\n    train_dataset, ced_scores = load_rsft_data(\n        args.rsft_data_path, tokenizer, args.max_length,\n    )\n\n    # Model: base → merge SFT adapter → new LoRA\n    logger.info(\"Loading base model: %s\", args.base_model)\n    local_rank = int(os.environ.get(\"LOCAL_RANK\", 0))\n    model_kwargs = dict(\n        trust_remote_code=True,\n        attn_implementation=\"sdpa\",\n        device_map={\"\": local_rank},\n    )\n    if args.quantize:\n        logger.info(\"Using 4-bit QLoRA quantization\")\n        model_kwargs[\"quantization_config\"] = BitsAndBytesConfig(\n            load_in_4bit=True,\n            bnb_4bit_compute_dtype=torch.bfloat16,\n            bnb_4bit_quant_type=\"nf4\",\n            bnb_4bit_use_double_quant=True,\n        )\n    else:\n        model_kwargs[\"torch_dtype\"] = torch.bfloat16 if args.bf16 else torch.float16\n\n    model = AutoModelForCausalLM.from_pretrained(args.base_model, **model_kwargs)\n\n    if args.sft_adapter:\n        logger.info(\"Merging SFT adapter: %s\", args.sft_adapter)\n        model = PeftModel.from_pretrained(model, args.sft_adapter)\n        model = model.merge_and_unload()\n\n    model.config.use_cache = False\n    model.gradient_checkpointing_enable()\n\n    # Fresh LoRA for RSFT (与 SFT warmup 相同结构)\n    lora_config = LoraConfig(\n        task_type=TaskType.CAUSAL_LM,\n        r=args.lora_rank,\n        lora_alpha=args.lora_alpha,\n        lora_dropout=args.lora_dropout,\n        target_modules=[\"q_proj\", \"k_proj\", \"v_proj\", \"o_proj\",\n                         \"gate_proj\", \"up_proj\", \"down_proj\"],\n    )\n    model = get_peft_model(model, lora_config)\n    model.print_trainable_parameters()\n\n    # Training config\n    training_args = SFTConfig(\n        output_dir=args.output_dir,\n        num_train_epochs=args.num_epochs,\n        per_device_train_batch_size=args.per_device_batch_size,\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\n        learning_rate=args.learning_rate,\n        warmup_steps=args.warmup_steps,\n        bf16=args.bf16,\n        logging_steps=10,\n        save_strategy=\"steps\",\n        save_steps=args.save_steps,\n        save_total_limit=args.save_total_limit,\n        seed=args.seed,\n        max_length=args.max_length,\n        dataset_text_field=\"text\",\n        report_to=\"wandb\" if \"WANDB_API_KEY\" in os.environ else \"none\",\n        gradient_checkpointing=True,\n        gradient_checkpointing_kwargs={\"use_reentrant\": False},\n        deepspeed=args.deepspeed,\n    )\n\n    sample_weights = ced_scores if args.weighted_sampling else None\n\n    trainer = WeightedSFTTrainer(\n        model=model,\n        args=training_args,\n        train_dataset=train_dataset,\n        processing_class=tokenizer,\n        sample_weights=sample_weights,\n    )\n\n    logger.info(\n        \"Starting RSFT training (%d samples, weighted=%s)...\",\n        len(train_dataset), args.weighted_sampling,\n    )\n    trainer.train()\n\n    logger.info(\"Saving model to %s\", args.output_dir)\n    trainer.save_model(args.output_dir)\n    tokenizer.save_pretrained(args.output_dir)\n    logger.info(\"RSFT training complete.\")\n\n\nif __name__ == \"__main__\":\n    main()\n",
    "structuredPatch": [
      {
        "oldStart": 335,
        "oldLines": 16,
        "newStart": 335,
        "newLines": 38,
        "lines": [
          "     model = get_peft_model(model, lora_config)",
          "     model.print_trainable_parameters()",
          " ",
          "+    # Eval data",
          "+    eval_dataset = None",
          "+    callbacks = []",
          "+    if args.eval_data_dir:",
          "+        logger.info(\"Loading eval data from %s (max %d docs for task eval)\",",
          "+                     args.eval_data_dir, args.eval_max_docs)",
          "+        eval_items, gold, eval_dataset = prepare_eval_data(",
          "+            args.eval_data_dir, tokenizer, args.eval_max_docs,",
          "+        )",
          "+        train_file = os.path.join(args.eval_data_dir, \"train_annotated.json\")",
          "+        callbacks.append(TaskEvalCallback(",
          "+            tokenizer=tokenizer,",
          "+            eval_items=eval_items,",
          "+            gold=gold,",
          "+            train_file=train_file,",
          "+            max_new_tokens=args.max_new_tokens,",
          "+        ))",
          "+        logger.info(\"Task eval enabled: %d docs, %d gold triples\",",
          "+                     len(eval_items), len(gold))",
          "+",
          "     # Training config",
          "     training_args = SFTConfig(",
          "         output_dir=args.output_dir,",
          "         num_train_epochs=args.num_epochs,",
          "         per_device_train_batch_size=args.per_device_batch_size,",
          "+        per_device_eval_batch_size=1,",
          "         gradient_accumulation_steps=args.gradient_accumulation_steps,",
          "         learning_rate=args.learning_rate,",
          "         warmup_steps=args.warmup_steps,",
          "         bf16=args.bf16,",
          "         logging_steps=10,",
          "+        eval_strategy=\"epoch\" if eval_dataset is not None else \"no\",",
          "         save_strategy=\"steps\",",
          "         save_steps=args.save_steps,",
          "         save_total_limit=args.save_total_limit,"
        ]
      },
      {
        "oldStart": 363,
        "oldLines": 8,
        "newStart": 385,
        "newLines": 10,
        "lines": [
          "         model=model,",
          "         args=training_args,",
          "         train_dataset=train_dataset,",
          "+        eval_dataset=eval_dataset,",
          "         processing_class=tokenizer,",
          "         sample_weights=sample_weights,",
          "+        callbacks=callbacks,",
          "     )",
          " ",
          "     logger.info("
        ]
      }
    ],
    "userModified": false,
    "replaceAll": false
  }
}
```

</details>

---

### Assistant

_source line 80_

Let me verify the final file:

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "419db276-b482-43bb-81ec-12133e97e35e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H3N4oBzhr6ghLmR8D5dph6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1280,
      "cache_read_input_tokens": 73314,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1280
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 81_

<details open><summary>🔧 Tool call — Read · `toolu_01KvR8edeD1yKgPCw5gYtajc`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "5150283c-eaaa-4e27-ae6c-8bbec4bd287c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01H3N4oBzhr6ghLmR8D5dph6",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1280,
      "cache_read_input_tokens": 73314,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1280
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 82 · 2026-05-15T02:29:18.781Z_

<details><summary>↩ Tool result · `toolu_01KvR8edeD1yKgPCw5gYtajc`</summary>

```text
1	"""RSFT (Rejection Sampling Fine-Tuning) 训练脚本。
2	
3	从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。
4	流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。
5	
6	输入: JSONL，每行 {"doc_id": ..., "input": ..., "output": ..., "ced_score": ..., ...}
7	输出: QLoRA adapter checkpoint
8	依赖: transformers, trl, peft, bitsandbytes, datasets
9	
10	单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output
11	多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \
12	            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output
13	"""
14	
15	import argparse
16	import json
17	import logging
18	import os
19	
20	import torch
21	from datasets import Dataset
22	from peft import LoraConfig, PeftModel, TaskType, get_peft_model
23	from torch.utils.data import WeightedRandomSampler
24	from transformers import (
25	    AutoModelForCausalLM,
26	    AutoTokenizer,
27	    BitsAndBytesConfig,
28	    TrainerCallback,
29	)
30	from trl import SFTConfig, SFTTrainer
31	
32	from freige.training.sft_trainer import SYSTEM_PROMPT
33	
34	logging.basicConfig(level=logging.INFO, format="%(asctime)s %(levelname)s %(message)s")
35	logger = logging.getLogger(__name__)
36	
37	DEFAULT_BASE_MODEL = "/root/autodl-tmp/models/Qwen3-4B"
38	DEFAULT_SFT_ADAPTER = "/root/autodl-tmp/sft_output"
39	
40	
41	def load_rsft_data(data_path: str, tokenizer, max_length: int = 2048):
42	    """加载 CED 筛选后的 RSFT 数据，格式化为 chat template 文本。
43	
44	    每行 JSONL 的 input 字段作为 user message，output 字段作为 assistant response，
45	    经 apply_chat_template 拼接后用于 SFT 训练。超过 max_length 的样本被跳过
46	    而非截断，避免训练在不完整 JSON 输出上。
47	
48	    Returns:
49	        (Dataset, list[float]): 训练数据集和对应的 CED scores
50	    """
51	    samples = []
52	    with open(data_path) as f:
53	        for line in f:
54	            if line.strip():
55	                samples.append(json.loads(line))
56	
57	    logger.info("Loaded %d RSFT samples from %s", len(samples), data_path)
58	
59	    formatted = []
60	    ced_scores = []
61	    skipped = 0
62	    for s in samples:
63	        messages = [
64	            {"role": "system", "content": SYSTEM_PROMPT},
65	            {"role": "user", "content": s["input"]},
66	            {"role": "assistant", "content": s["output"]},
67	        ]
68	        text = tokenizer.apply_chat_template(
69	            messages,
70	            tokenize=False,
71	            add_generation_prompt=False,
72	            enable_thinking=False,
73	        )
74	        token_len = len(tokenizer.encode(text, add_special_tokens=False))
75	        if token_len > max_length:
76	            skipped += 1
77	            continue
78	        formatted.append({"text": text})
79	        ced_scores.append(s.get("ced_score", 1.0))
80	
81	    if skipped:
82	        logger.warning("Skipped %d samples exceeding max_length=%d", skipped, max_length)
83	
84	    if ced_scores:
85	        logger.info(
86	            "Prepared %d RSFT samples (CED scores: min=%.3f, max=%.3f, mean=%.3f)",
87	            len(formatted), min(ced_scores), max(ced_scores),
88	            sum(ced_scores) / len(ced_scores),
89	        )
90	    return Dataset.from_list(formatted), ced_scores
91	
92	
93	def prepare_eval_data(data_dir, tokenizer, max_docs=50):
94	    """Load DocRED dev set for task-level evaluation during training."""
95	    from freige.data.docred_processor import DocREDProcessor
96	    from freige.eval.evaluator import gold_from_docred
97	
98	    processor = DocREDProcessor(data_dir=data_dir)
99	    samples = processor.process("dev")
100	    groups = processor.group_by_document(samples)
101	
102	    eval_items = []
103	    for doc_id, doc_samples in list(groups.items())[:max_docs]:
104	        sft_sample = processor.format_sft_sample(doc_samples)
105	        messages = [
106	            {"role": "system", "content": SYSTEM_PROMPT},
107	            {"role": "user", "content": f"{sft_sample['instruction']}\n\n{sft_sample['input']}"},
108	        ]
109	        prompt = tokenizer.apply_chat_template(
110	            messages, tokenize=False, add_generation_prompt=True, enable_thinking=False,
111	        )
112	        eval_items.append({"doc_id": doc_id, "prompt": prompt})
113	
114	    dev_path = os.path.join(data_dir, "dev.json")
115	    with open(dev_path) as f:
116	        dev_data = json.load(f)
117	    gold = gold_from_docred(dev_data)
118	
119	    # Also build formatted eval dataset for loss-based eval
120	    eval_formatted = []
121	    for doc_id, doc_samples in groups.items():
122	        sft_sample = processor.format_sft_sample(doc_samples)
123	        messages = [
124	            {"role": "system", "content": SYSTEM_PROMPT},
125	            {"role": "user", "content": f"{sft_sample['instruction']}\n\n{sft_sample['input']}"},
126	            {"role": "assistant", "content": sft_sample["output"]},
127	        ]
128	        text = tokenizer.apply_chat_template(
129	            messages, tokenize=False, add_generation_prompt=False, enable_thinking=False,
130	        )
131	        eval_formatted.append({"text": text})
132	    eval_dataset = Dataset.from_list(eval_formatted)
133	
134	    return eval_items, gold, eval_dataset
135	
136	
137	class TaskEvalCallback(TrainerCallback):
138	    """End-of-epoch task eval: generate on dev subset → compute F1 / Evi-F1 / EDCR."""
139	
140	    def __init__(self, tokenizer, eval_items, gold, train_file, max_new_tokens=1024):
141	        self.tokenizer = tokenizer
142	        self.eval_items = eval_items
143	        self.gold = gold
144	        self.train_file = train_file
145	        self.max_new_tokens = max_new_tokens
146	        self._evaluator = None
147	
148	    @property
149	    def evaluator(self):
150	        if self._evaluator is None:
151	            from freige.eval.evaluator import DocREDEvaluator
152	            if self.train_file and os.path.exists(self.train_file):
153	                self._evaluator = DocREDEvaluator.from_train_file(self.train_file)
154	            else:
155	                self._evaluator = DocREDEvaluator()
156	        return self._evaluator
157	
158	    def on_epoch_end(self, args, state, control, model=None, **kwargs):
159	        if not state.is_world_process_zero:
160	            return
161	        self._run_task_eval(model, state)
162	
163	    def _run_task_eval(self, model, state):
164	        from freige.eval.evaluator import parse_model_output
165	
166	        model.eval()
167	        model.config.use_cache = True
168	        if hasattr(model, "gradient_checkpointing_disable"):
169	            model.gradient_checkpointing_disable()
170	
171	        all_predictions = []
172	        for item in self.eval_items:
173	            inputs = self.tokenizer(
174	                item["prompt"], return_tensors="pt", truncation=True, max_length=4096,
175	            ).to(model.device)
176	            with torch.no_grad():
177	                outputs = model.generate(
178	                    **inputs,
179	                    max_new_tokens=self.max_new_tokens,
180	                    do_sample=False,
181	                    pad_token_id=self.tokenizer.pad_token_id,
182	                )
183	            generated = outputs[0][inputs["input_ids"].shape[1]:]
184	            text = self.tokenizer.decode(generated, skip_special_tokens=True)
185	            triples = parse_model_output(item["doc_id"], text)
186	            all_predictions.extend(triples)
187	
188	        metrics = self.evaluator.evaluate(all_predictions, self.gold)
189	
190	        log_metrics = {
191	            "eval/rel_f1": metrics["f1"],
192	            "eval/ign_f1": metrics["ign_f1"],
193	            "eval/evi_f1": metrics["evi_f1"],
194	            "eval/evi_precision": metrics["evi_precision"],
195	            "eval/evi_recall": metrics["evi_recall"],
196	            "eval/edcr": metrics.get("edcr", 0),
197	            "eval/n_predictions": len(all_predictions),
198	        }
199	        try:
200	            import wandb
201	            if wandb.run is not None:
202	                wandb.log(log_metrics, step=state.global_step)
203	        except ImportError:
204	            pass
205	
206	        logger.info(
207	            "Task eval @ step %d: F1=%.4f, Ign-F1=%.4f, Evi-F1=%.4f, EDCR=%.4f (%d preds)",
208	            state.global_step, metrics["f1"], metrics["ign_f1"],
209	            metrics["evi_f1"], metrics.get("edcr", 0), len(all_predictions),
210	        )
211	
212	        model.config.use_cache = False
213	        if hasattr(model, "gradient_checkpointing_enable"):
214	            model.gradient_checkpointing_enable()
215	        model.train()
216	
217	
218	class WeightedSFTTrainer(SFTTrainer):
219	    """SFTTrainer with CED score-weighted sampling.
220	
221	    高 CED score 的样本被更频繁采样。使用 WeightedRandomSampler 实现，
222	    适用于单机训练。多机 DDP 场景下 Accelerate 会替换 sampler，
223	    此时 weighted_sampling 不生效，需改用数据集层面的过采样。
224	    """
225	
226	    def __init__(self, *args, sample_weights=None, **kwargs):
227	        super().__init__(*args, **kwargs)
228	        self.sample_weights = sample_weights
229	
230	    def _get_train_sampler(self, dataset=None):
231	        if self.sample_weights is not None:
232	            ds = dataset if dataset is not None else self.train_dataset
233	            return WeightedRandomSampler(
234	                weights=self.sample_weights,
235	                num_samples=len(ds),
236	                replacement=True,
237	            )
238	        return super()._get_train_sampler(dataset)
239	
240	
241	def main():
242	    parser = argparse.ArgumentParser(description="FREIGE RSFT Training")
243	    parser.add_argument("--base_model", type=str, default=DEFAULT_BASE_MODEL)
244	    parser.add_argument("--sft_adapter", type=str, default=DEFAULT_SFT_ADAPTER,
245	                        help="SFT warmup adapter 路径 (merge 后训练新 LoRA)")
246	    parser.add_argument("--rsft_data_path", type=str, required=True,
247	                        help="CED 筛选后的 RSFT 训练数据 (JSONL)")
248	    parser.add_argument("--output_dir", type=str, required=True)
249	    parser.add_argument("--learning_rate", type=float, default=2e-5)
250	    parser.add_argument("--num_epochs", type=int, default=3)
251	    parser.add_argument("--per_device_batch_size", type=int, default=4)
252	    parser.add_argument("--gradient_accumulation_steps", type=int, default=4)
253	    parser.add_argument("--warmup_steps", type=int, default=100)
254	    parser.add_argument("--save_steps", type=int, default=50)
255	    parser.add_argument("--save_total_limit", type=int, default=5)
256	    parser.add_argument("--max_length", type=int, default=2048)
257	    parser.add_argument("--seed", type=int, default=42)
258	    parser.add_argument("--wandb_project", type=str, default="freige-rsft")
259	    parser.add_argument("--wandb_run_name", type=str, default=None)
260	    parser.add_argument("--weighted_sampling", action="store_true",
261	                        help="按 CED score 加权采样（高分样本更频繁）")
262	    parser.add_argument("--quantize", action="store_true",
263	                        help="启用 4-bit QLoRA 量化")
264	    parser.add_argument("--lora_rank", type=int, default=64)
265	    parser.add_argument("--lora_alpha", type=int, default=128)
266	    parser.add_argument("--lora_dropout", type=float, default=0.05)
267	    parser.add_argument("--bf16", action="store_true", default=True)
268	    parser.add_argument("--deepspeed", type=str, default=None,
269	                        help="DeepSpeed 配置文件路径")
270	    parser.add_argument("--eval_data_dir", type=str, default=None,
271	                        help="DocRED data dir (contains dev.json) for task-level eval")
272	    parser.add_argument("--eval_max_docs", type=int, default=50,
273	                        help="Max dev docs for task-level eval during training")
274	    parser.add_argument("--max_new_tokens", type=int, default=1024)
275	    args = parser.parse_args()
276	
277	    # W&B
278	    if args.wandb_project and "WANDB_API_KEY" in os.environ:
279	        os.environ["WANDB_PROJECT"] = args.wandb_project
280	        if args.wandb_run_name:
281	            os.environ["WANDB_NAME"] = args.wandb_run_name
282	
283	    # Tokenizer
284	    logger.info("Loading tokenizer: %s", args.base_model)
285	    tokenizer = AutoTokenizer.from_pretrained(
286	        args.base_model, trust_remote_code=True, padding_side="right",
287	    )
288	    if tokenizer.pad_token is None:
289	        tokenizer.pad_token = tokenizer.eos_token
290	
291	    # Data
292	    logger.info("Loading RSFT data: %s", args.rsft_data_path)
293	    train_dataset, ced_scores = load_rsft_data(
294	        args.rsft_data_path, tokenizer, args.max_length,
295	    )
296	
297	    # Model: base → merge SFT adapter → new LoRA
298	    logger.info("Loading base model: %s", args.base_model)
299	    local_rank = int(os.environ.get("LOCAL_RANK", 0))
300	    model_kwargs = dict(
301	        trust_remote_code=True,
302	        attn_implementation="sdpa",
303	        device_map={"": local_rank},
304	    )
305	    if args.quantize:
306	        logger.info("Using 4-bit QLoRA quantization")
307	        model_kwargs["quantization_config"] = BitsAndBytesConfig(
308	            load_in_4bit=True,
309	            bnb_4bit_compute_dtype=torch.bfloat16,
310	            bnb_4bit_quant_type="nf4",
311	            bnb_4bit_use_double_quant=True,
312	        )
313	    else:
314	        model_kwargs["torch_dtype"] = torch.bfloat16 if args.bf16 else torch.float16
315	
316	    model = AutoModelForCausalLM.from_pretrained(args.base_model, **model_kwargs)
317	
318	    if args.sft_adapter:
319	        logger.info("Merging SFT adapter: %s", args.sft_adapter)
320	        model = PeftModel.from_pretrained(model, args.sft_adapter)
321	        model = model.merge_and_unload()
322	
323	    model.config.use_cache = False
324	    model.gradient_checkpointing_enable()
325	
326	    # Fresh LoRA for RSFT (与 SFT warmup 相同结构)
327	    lora_config = LoraConfig(
328	        task_type=TaskType.CAUSAL_LM,
329	        r=args.lora_rank,
330	        lora_alpha=args.lora_alpha,
331	        lora_dropout=args.lora_dropout,
332	        target_modules=["q_proj", "k_proj", "v_proj", "o_proj",
333	                         "gate_proj", "up_proj", "down_proj"],
334	    )
335	    model = get_peft_model(model, lora_config)
336	    model.print_trainable_parameters()
337	
338	    # Eval data
339	    eval_dataset = None
340	    callbacks = []
341	    if args.eval_data_dir:
342	        logger.info("Loading eval data from %s (max %d docs for task eval)",
343	                     args.eval_data_dir, args.eval_max_docs)
344	        eval_items, gold, eval_dataset = prepare_eval_data(
345	            args.eval_data_dir, tokenizer, args.eval_max_docs,
346	        )
347	        train_file = os.path.join(args.eval_data_dir, "train_annotated.json")
348	        callbacks.append(TaskEvalCallback(
349	            tokenizer=tokenizer,
350	            eval_items=eval_items,
351	            gold=gold,
352	            train_file=train_file,
353	            max_new_tokens=args.max_new_tokens,
354	        ))
355	        logger.info("Task eval enabled: %d docs, %d gold triples",
356	                     len(eval_items), len(gold))
357	
358	    # Training config
359	    training_args = SFTConfig(
360	        output_dir=args.output_dir,
361	        num_train_epochs=args.num_epochs,
362	        per_device_train_batch_size=args.per_device_batch_size,
363	        per_device_eval_batch_size=1,
364	        gradient_accumulation_steps=args.gradient_accumulation_steps,
365	        learning_rate=args.learning_rate,
366	        warmup_steps=args.warmup_steps,
367	        bf16=args.bf16,
368	        logging_steps=10,
369	        eval_strategy="epoch" if eval_dataset is not None else "no",
370	        save_strategy="steps",
371	        save_steps=args.save_steps,
372	        save_total_limit=args.save_total_limit,
373	        seed=args.seed,
374	        max_length=args.max_length,
375	        dataset_text_field="text",
376	        report_to="wandb" if "WANDB_API_KEY" in os.environ else "none",
377	        gradient_checkpointing=True,
378	        gradient_checkpointing_kwargs={"use_reentrant": False},
379	        deepspeed=args.deepspeed,
380	    )
381	
382	    sample_weights = ced_scores if args.weighted_sampling else None
383	
384	    trainer = WeightedSFTTrainer(
385	        model=model,
386	        args=training_args,
387	        train_dataset=train_dataset,
388	        eval_dataset=eval_dataset,
389	        processing_class=tokenizer,
390	        sample_weights=sample_weights,
391	        callbacks=callbacks,
392	    )
393	
394	    logger.info(
395	        "Starting RSFT training (%d samples, weighted=%s)...",
396	        len(train_dataset), args.weighted_sampling,
397	    )
398	    trainer.train()
399	
400	    logger.info("Saving model to %s", args.output_dir)
401	    trainer.save_model(args.output_dir)
402	    tokenizer.save_pretrained(args.output_dir)
403	    logger.info("RSFT training complete.")
404	
405	
406	if __name__ == "__main__":
407	    main()
408	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "52016d4a-68ee-4906-8917-d128bbc5da48",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/artifacts/freige/training/rsft_trainer.py",
      "content": "\"\"\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\n\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\n\n输入: JSONL，每行 {\"doc_id\": ..., \"input\": ..., \"output\": ..., \"ced_score\": ..., ...}\n输出: QLoRA adapter checkpoint\n依赖: transformers, trl, peft, bitsandbytes, datasets\n\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n\"\"\"\n\nimport argparse\nimport json\nimport logging\nimport os\n\nimport torch\nfrom datasets import Dataset\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\nfrom torch.utils.data import WeightedRandomSampler\nfrom transformers import (\n    AutoModelForCausalLM,\n    AutoTokenizer,\n    BitsAndBytesConfig,\n    TrainerCallback,\n)\nfrom trl import SFTConfig, SFTTrainer\n\nfrom freige.training.sft_trainer import SYSTEM_PROMPT\n\nlogging.basicConfig(level=logging.INFO, format=\"%(asctime)s %(levelname)s %(message)s\")\nlogger = logging.getLogger(__name__)\n\nDEFAULT_BASE_MODEL = \"/root/autodl-tmp/models/Qwen3-4B\"\nDEFAULT_SFT_ADAPTER = \"/root/autodl-tmp/sft_output\"\n\n\ndef load_rsft_data(data_path: str, tokenizer, max_length: int = 2048):\n    \"\"\"加载 CED 筛选后的 RSFT 数据，格式化为 chat template 文本。\n\n    每行 JSONL 的 input 字段作为 user message，output 字段作为 assistant response，\n    经 apply_chat_template 拼接后用于 SFT 训练。超过 max_length 的样本被跳过\n    而非截断，避免训练在不完整 JSON 输出上。\n\n    Returns:\n        (Dataset, list[float]): 训练数据集和对应的 CED scores\n    \"\"\"\n    samples = []\n    with open(data_path) as f:\n        for line in f:\n            if line.strip():\n                samples.append(json.loads(line))\n\n    logger.info(\"Loaded %d RSFT samples from %s\", len(samples), data_path)\n\n    formatted = []\n    ced_scores = []\n    skipped = 0\n    for s in samples:\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": s[\"input\"]},\n            {\"role\": \"assistant\", \"content\": s[\"output\"]},\n        ]\n        text = tokenizer.apply_chat_template(\n            messages,\n            tokenize=False,\n            add_generation_prompt=False,\n            enable_thinking=False,\n        )\n        token_len = len(tokenizer.encode(text, add_special_tokens=False))\n        if token_len > max_length:\n            skipped += 1\n            continue\n        formatted.append({\"text\": text})\n        ced_scores.append(s.get(\"ced_score\", 1.0))\n\n    if skipped:\n        logger.warning(\"Skipped %d samples exceeding max_length=%d\", skipped, max_length)\n\n    if ced_scores:\n        logger.info(\n            \"Prepared %d RSFT samples (CED scores: min=%.3f, max=%.3f, mean=%.3f)\",\n            len(formatted), min(ced_scores), max(ced_scores),\n            sum(ced_scores) / len(ced_scores),\n        )\n    return Dataset.from_list(formatted), ced_scores\n\n\ndef prepare_eval_data(data_dir, tokenizer, max_docs=50):\n    \"\"\"Load DocRED dev set for task-level evaluation during training.\"\"\"\n    from freige.data.docred_processor import DocREDProcessor\n    from freige.eval.evaluator import gold_from_docred\n\n    processor = DocREDProcessor(data_dir=data_dir)\n    samples = processor.process(\"dev\")\n    groups = processor.group_by_document(samples)\n\n    eval_items = []\n    for doc_id, doc_samples in list(groups.items())[:max_docs]:\n        sft_sample = processor.format_sft_sample(doc_samples)\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": f\"{sft_sample['instruction']}\\n\\n{sft_sample['input']}\"},\n        ]\n        prompt = tokenizer.apply_chat_template(\n            messages, tokenize=False, add_generation_prompt=True, enable_thinking=False,\n        )\n        eval_items.append({\"doc_id\": doc_id, \"prompt\": prompt})\n\n    dev_path = os.path.join(data_dir, \"dev.json\")\n    with open(dev_path) as f:\n        dev_data = json.load(f)\n    gold = gold_from_docred(dev_data)\n\n    # Also build formatted eval dataset for loss-based eval\n    eval_formatted = []\n    for doc_id, doc_samples in groups.items():\n        sft_sample = processor.format_sft_sample(doc_samples)\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": f\"{sft_sample['instruction']}\\n\\n{sft_sample['input']}\"},\n            {\"role\": \"assistant\", \"content\": sft_sample[\"output\"]},\n        ]\n        text = tokenizer.apply_chat_template(\n            messages, tokenize=False, add_generation_prompt=False, enable_thinking=False,\n        )\n        eval_formatted.append({\"text\": text})\n    eval_dataset = Dataset.from_list(eval_formatted)\n\n    return eval_items, gold, eval_dataset\n\n\nclass TaskEvalCallback(TrainerCallback):\n    \"\"\"End-of-epoch task eval: generate on dev subset → compute F1 / Evi-F1 / EDCR.\"\"\"\n\n    def __init__(self, tokenizer, eval_items, gold, train_file, max_new_tokens=1024):\n        self.tokenizer = tokenizer\n        self.eval_items = eval_items\n        self.gold = gold\n        self.train_file = train_file\n        self.max_new_tokens = max_new_tokens\n        self._evaluator = None\n\n    @property\n    def evaluator(self):\n        if self._evaluator is None:\n            from freige.eval.evaluator import DocREDEvaluator\n            if self.train_file and os.path.exists(self.train_file):\n                self._evaluator = DocREDEvaluator.from_train_file(self.train_file)\n            else:\n                self._evaluator = DocREDEvaluator()\n        return self._evaluator\n\n    def on_epoch_end(self, args, state, control, model=None, **kwargs):\n        if not state.is_world_process_zero:\n            return\n        self._run_task_eval(model, state)\n\n    def _run_task_eval(self, model, state):\n        from freige.eval.evaluator import parse_model_output\n\n        model.eval()\n        model.config.use_cache = True\n        if hasattr(model, \"gradient_checkpointing_disable\"):\n            model.gradient_checkpointing_disable()\n\n        all_predictions = []\n        for item in self.eval_items:\n            inputs = self.tokenizer(\n                item[\"prompt\"], return_tensors=\"pt\", truncation=True, max_length=4096,\n            ).to(model.device)\n            with torch.no_grad():\n                outputs = model.generate(\n                    **inputs,\n                    max_new_tokens=self.max_new_tokens,\n                    do_sample=False,\n                    pad_token_id=self.tokenizer.pad_token_id,\n                )\n            generated = outputs[0][inputs[\"input_ids\"].shape[1]:]\n            text = self.tokenizer.decode(generated, skip_special_tokens=True)\n            triples = parse_model_output(item[\"doc_id\"], text)\n            all_predictions.extend(triples)\n\n        metrics = self.evaluator.evaluate(all_predictions, self.gold)\n\n        log_metrics = {\n            \"eval/rel_f1\": metrics[\"f1\"],\n            \"eval/ign_f1\": metrics[\"ign_f1\"],\n            \"eval/evi_f1\": metrics[\"evi_f1\"],\n            \"eval/evi_precision\": metrics[\"evi_precision\"],\n            \"eval/evi_recall\": metrics[\"evi_recall\"],\n            \"eval/edcr\": metrics.get(\"edcr\", 0),\n            \"eval/n_predictions\": len(all_predictions),\n        }\n        try:\n            import wandb\n            if wandb.run is not None:\n                wandb.log(log_metrics, step=state.global_step)\n        except ImportError:\n            pass\n\n        logger.info(\n            \"Task eval @ step %d: F1=%.4f, Ign-F1=%.4f, Evi-F1=%.4f, EDCR=%.4f (%d preds)\",\n            state.global_step, metrics[\"f1\"], metrics[\"ign_f1\"],\n            metrics[\"evi_f1\"], metrics.get(\"edcr\", 0), len(all_predictions),\n        )\n\n        model.config.use_cache = False\n        if hasattr(model, \"gradient_checkpointing_enable\"):\n            model.gradient_checkpointing_enable()\n        model.train()\n\n\nclass WeightedSFTTrainer(SFTTrainer):\n    \"\"\"SFTTrainer with CED score-weighted sampling.\n\n    高 CED score 的样本被更频繁采样。使用 WeightedRandomSampler 实现，\n    适用于单机训练。多机 DDP 场景下 Accelerate 会替换 sampler，\n    此时 weighted_sampling 不生效，需改用数据集层面的过采样。\n    \"\"\"\n\n    def __init__(self, *args, sample_weights=None, **kwargs):\n        super().__init__(*args, **kwargs)\n        self.sample_weights = sample_weights\n\n    def _get_train_sampler(self, dataset=None):\n        if self.sample_weights is not None:\n            ds = dataset if dataset is not None else self.train_dataset\n            return WeightedRandomSampler(\n                weights=self.sample_weights,\n                num_samples=len(ds),\n                replacement=True,\n            )\n        return super()._get_train_sampler(dataset)\n\n\ndef main():\n    parser = argparse.ArgumentParser(description=\"FREIGE RSFT Training\")\n    parser.add_argument(\"--base_model\", type=str, default=DEFAULT_BASE_MODEL)\n    parser.add_argument(\"--sft_adapter\", type=str, default=DEFAULT_SFT_ADAPTER,\n                        help=\"SFT warmup adapter 路径 (merge 后训练新 LoRA)\")\n    parser.add_argument(\"--rsft_data_path\", type=str, required=True,\n                        help=\"CED 筛选后的 RSFT 训练数据 (JSONL)\")\n    parser.add_argument(\"--output_dir\", type=str, required=True)\n    parser.add_argument(\"--learning_rate\", type=float, default=2e-5)\n    parser.add_argument(\"--num_epochs\", type=int, default=3)\n    parser.add_argument(\"--per_device_batch_size\", type=int, default=4)\n    parser.add_argument(\"--gradient_accumulation_steps\", type=int, default=4)\n    parser.add_argument(\"--warmup_steps\", type=int, default=100)\n    parser.add_argument(\"--save_steps\", type=int, default=50)\n    parser.add_argument(\"--save_total_limit\", type=int, default=5)\n    parser.add_argument(\"--max_length\", type=int, default=2048)\n    parser.add_argument(\"--seed\", type=int, default=42)\n    parser.add_argument(\"--wandb_project\", type=str, default=\"freige-rsft\")\n    parser.add_argument(\"--wandb_run_name\", type=str, default=None)\n    parser.add_argument(\"--weighted_sampling\", action=\"store_true\",\n                        help=\"按 CED score 加权采样（高分样本更频繁）\")\n    parser.add_argument(\"--quantize\", action=\"store_true\",\n                        help=\"启用 4-bit QLoRA 量化\")\n    parser.add_argument(\"--lora_rank\", type=int, default=64)\n    parser.add_argument(\"--lora_alpha\", type=int, default=128)\n    parser.add_argument(\"--lora_dropout\", type=float, default=0.05)\n    parser.add_argument(\"--bf16\", action=\"store_true\", default=True)\n    parser.add_argument(\"--deepspeed\", type=str, default=None,\n                        help=\"DeepSpeed 配置文件路径\")\n    parser.add_argument(\"--eval_data_dir\", type=str, default=None,\n                        help=\"DocRED data dir (contains dev.json) for task-level eval\")\n    parser.add_argument(\"--eval_max_docs\", type=int, default=50,\n                        help=\"Max dev docs for task-level eval during training\")\n    parser.add_argument(\"--max_new_tokens\", type=int, default=1024)\n    args = parser.parse_args()\n\n    # W&B\n    if args.wandb_project and \"WANDB_API_KEY\" in os.environ:\n        os.environ[\"WANDB_PROJECT\"] = args.wandb_project\n        if args.wandb_run_name:\n            os.environ[\"WANDB_NAME\"] = args.wandb_run_name\n\n    # Tokenizer\n    logger.info(\"Loading tokenizer: %s\", args.base_model)\n    tokenizer = AutoTokenizer.from_pretrained(\n        args.base_model, trust_remote_code=True, padding_side=\"right\",\n    )\n    if tokenizer.pad_token is None:\n        tokenizer.pad_token = tokenizer.eos_token\n\n    # Data\n    logger.info(\"Loading RSFT data: %s\", args.rsft_data_path)\n    train_dataset, ced_scores = load_rsft_data(\n        args.rsft_data_path, tokenizer, args.max_length,\n    )\n\n    # Model: base → merge SFT adapter → new LoRA\n    logger.info(\"Loading base model: %s\", args.base_model)\n    local_rank = int(os.environ.get(\"LOCAL_RANK\", 0))\n    model_kwargs = dict(\n        trust_remote_code=True,\n        attn_implementation=\"sdpa\",\n        device_map={\"\": local_rank},\n    )\n    if args.quantize:\n        logger.info(\"Using 4-bit QLoRA quantization\")\n        model_kwargs[\"quantization_config\"] = BitsAndBytesConfig(\n            load_in_4bit=True,\n            bnb_4bit_compute_dtype=torch.bfloat16,\n            bnb_4bit_quant_type=\"nf4\",\n            bnb_4bit_use_double_quant=True,\n        )\n    else:\n        model_kwargs[\"torch_dtype\"] = torch.bfloat16 if args.bf16 else torch.float16\n\n    model = AutoModelForCausalLM.from_pretrained(args.base_model, **model_kwargs)\n\n    if args.sft_adapter:\n        logger.info(\"Merging SFT adapter: %s\", args.sft_adapter)\n        model = PeftModel.from_pretrained(model, args.sft_adapter)\n        model = model.merge_and_unload()\n\n    model.config.use_cache = False\n    model.gradient_checkpointing_enable()\n\n    # Fresh LoRA for RSFT (与 SFT warmup 相同结构)\n    lora_config = LoraConfig(\n        task_type=TaskType.CAUSAL_LM,\n        r=args.lora_rank,\n        lora_alpha=args.lora_alpha,\n        lora_dropout=args.lora_dropout,\n        target_modules=[\"q_proj\", \"k_proj\", \"v_proj\", \"o_proj\",\n                         \"gate_proj\", \"up_proj\", \"down_proj\"],\n    )\n    model = get_peft_model(model, lora_config)\n    model.print_trainable_parameters()\n\n    # Eval data\n    eval_dataset = None\n    callbacks = []\n    if args.eval_data_dir:\n        logger.info(\"Loading eval data from %s (max %d docs for task eval)\",\n                     args.eval_data_dir, args.eval_max_docs)\n        eval_items, gold, eval_dataset = prepare_eval_data(\n            args.eval_data_dir, tokenizer, args.eval_max_docs,\n        )\n        train_file = os.path.join(args.eval_data_dir, \"train_annotated.json\")\n        callbacks.append(TaskEvalCallback(\n            tokenizer=tokenizer,\n            eval_items=eval_items,\n            gold=gold,\n            train_file=train_file,\n            max_new_tokens=args.max_new_tokens,\n        ))\n        logger.info(\"Task eval enabled: %d docs, %d gold triples\",\n                     len(eval_items), len(gold))\n\n    # Training config\n    training_args = SFTConfig(\n        output_dir=args.output_dir,\n        num_train_epochs=args.num_epochs,\n        per_device_train_batch_size=args.per_device_batch_size,\n        per_device_eval_batch_size=1,\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\n        learning_rate=args.learning_rate,\n        warmup_steps=args.warmup_steps,\n        bf16=args.bf16,\n        logging_steps=10,\n        eval_strategy=\"epoch\" if eval_dataset is not None else \"no\",\n        save_strategy=\"steps\",\n        save_steps=args.save_steps,\n        save_total_limit=args.save_total_limit,\n        seed=args.seed,\n        max_length=args.max_length,\n        dataset_text_field=\"text\",\n        report_to=\"wandb\" if \"WANDB_API_KEY\" in os.environ else \"none\",\n        gradient_checkpointing=True,\n        gradient_checkpointing_kwargs={\"use_reentrant\": False},\n        deepspeed=args.deepspeed,\n    )\n\n    sample_weights = ced_scores if args.weighted_sampling else None\n\n    trainer = WeightedSFTTrainer(\n        model=model,\n        args=training_args,\n        train_dataset=train_dataset,\n        eval_dataset=eval_dataset,\n        processing_class=tokenizer,\n        sample_weights=sample_weights,\n        callbacks=callbacks,\n    )\n\n    logger.info(\n        \"Starting RSFT training (%d samples, weighted=%s)...\",\n        len(train_dataset), args.weighted_sampling,\n    )\n    trainer.train()\n\n    logger.info(\"Saving model to %s\", args.output_dir)\n    trainer.save_model(args.output_dir)\n    tokenizer.save_pretrained(args.output_dir)\n    logger.info(\"RSFT training complete.\")\n\n\nif __name__ == \"__main__\":\n    main()\n",
      "numLines": 408,
      "startLine": 1,
      "totalLines": 408
    }
  }
}
```

</details>

---

### Assistant

_source line 83_

文件完整且正确。现在同步到服务器并验证。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "36e8a7f1-4966-4fb2-a263-45b59b5e5b7f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U5tkHyAC7GjkXtZtFk4m26",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6211,
      "cache_read_input_tokens": 74594,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6211
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 84_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_execute · `toolu_014VRxs5HSPdiv5koH4VQwcX`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "cat > /root/autodl-tmp/freige/training/rsft_trainer.py << 'RSFT_EOF'\n\"\"\"RSFT (Rejection Sampling Fine-Tuning) 训练脚本。\n\n从 SFT warmup checkpoint 继续训练，使用经 CED 打分筛选的高质量生成数据。\n流程: base model → merge SFT adapter → 新 QLoRA → 在 RSFT 数据上训练。\n\n输入: JSONL，每行 {\"doc_id\": ..., \"input\": ..., \"output\": ..., \"ced_score\": ..., ...}\n输出: QLoRA adapter checkpoint\n依赖: transformers, trl, peft, bitsandbytes, datasets\n\n单卡:   python -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n多卡:   accelerate launch --config_file configs/accelerate_4gpu.yaml \\\n            -m freige.training.rsft_trainer --rsft_data_path data.jsonl --output_dir ./rsft_output\n\"\"\"\n\nimport argparse\nimport json\nimport logging\nimport os\n\nimport torch\nfrom datasets import Dataset\nfrom peft import LoraConfig, PeftModel, TaskType, get_peft_model\nfrom torch.utils.data import WeightedRandomSampler\nfrom transformers import (\n    AutoModelForCausalLM,\n    AutoTokenizer,\n    BitsAndBytesConfig,\n    TrainerCallback,\n)\nfrom trl import SFTConfig, SFTTrainer\n\nfrom freige.training.sft_trainer import SYSTEM_PROMPT\n\nlogging.basicConfig(level=logging.INFO, format=\"%(asctime)s %(levelname)s %(message)s\")\nlogger = logging.getLogger(__name__)\n\nDEFAULT_BASE_MODEL = \"/root/autodl-tmp/models/Qwen3-4B\"\nDEFAULT_SFT_ADAPTER = \"/root/autodl-tmp/sft_output\"\n\n\ndef load_rsft_data(data_path: str, tokenizer, max_length: int = 2048):\n    \"\"\"加载 CED 筛选后的 RSFT 数据，格式化为 chat template 文本。\n\n    每行 JSONL 的 input 字段作为 user message，output 字段作为 assistant response，\n    经 apply_chat_template 拼接后用于 SFT 训练。超过 max_length 的样本被跳过\n    而非截断，避免训练在不完整 JSON 输出上。\n\n    Returns:\n        (Dataset, list[float]): 训练数据集和对应的 CED scores\n    \"\"\"\n    samples = []\n    with open(data_path) as f:\n        for line in f:\n            if line.strip():\n                samples.append(json.loads(line))\n\n    logger.info(\"Loaded %d RSFT samples from %s\", len(samples), data_path)\n\n    formatted = []\n    ced_scores = []\n    skipped = 0\n    for s in samples:\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": s[\"input\"]},\n            {\"role\": \"assistant\", \"content\": s[\"output\"]},\n        ]\n        text = tokenizer.apply_chat_template(\n            messages,\n            tokenize=False,\n            add_generation_prompt=False,\n            enable_thinking=False,\n        )\n        token_len = len(tokenizer.encode(text, add_special_tokens=False))\n        if token_len > max_length:\n            skipped += 1\n            continue\n        formatted.append({\"text\": text})\n        ced_scores.append(s.get(\"ced_score\", 1.0))\n\n    if skipped:\n        logger.warning(\"Skipped %d samples exceeding max_length=%d\", skipped, max_length)\n\n    if ced_scores:\n        logger.info(\n            \"Prepared %d RSFT samples (CED scores: min=%.3f, max=%.3f, mean=%.3f)\",\n            len(formatted), min(ced_scores), max(ced_scores),\n            sum(ced_scores) / len(ced_scores),\n        )\n    return Dataset.from_list(formatted), ced_scores\n\n\ndef prepare_eval_data(data_dir, tokenizer, max_docs=50):\n    \"\"\"Load DocRED dev set for task-level evaluation during training.\"\"\"\n    from freige.data.docred_processor import DocREDProcessor\n    from freige.eval.evaluator import gold_from_docred\n\n    processor = DocREDProcessor(data_dir=data_dir)\n    samples = processor.process(\"dev\")\n    groups = processor.group_by_document(samples)\n\n    eval_items = []\n    for doc_id, doc_samples in list(groups.items())[:max_docs]:\n        sft_sample = processor.format_sft_sample(doc_samples)\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": f\"{sft_sample['instruction']}\\n\\n{sft_sample['input']}\"},\n        ]\n        prompt = tokenizer.apply_chat_template(\n            messages, tokenize=False, add_generation_prompt=True, enable_thinking=False,\n        )\n        eval_items.append({\"doc_id\": doc_id, \"prompt\": prompt})\n\n    dev_path = os.path.join(data_dir, \"dev.json\")\n    with open(dev_path) as f:\n        dev_data = json.load(f)\n    gold = gold_from_docred(dev_data)\n\n    # Also build formatted eval dataset for loss-based eval\n    eval_formatted = []\n    for doc_id, doc_samples in groups.items():\n        sft_sample = processor.format_sft_sample(doc_samples)\n        messages = [\n            {\"role\": \"system\", \"content\": SYSTEM_PROMPT},\n            {\"role\": \"user\", \"content\": f\"{sft_sample['instruction']}\\n\\n{sft_sample['input']}\"},\n            {\"role\": \"assistant\", \"content\": sft_sample[\"output\"]},\n        ]\n        text = tokenizer.apply_chat_template(\n            messages, tokenize=False, add_generation_prompt=False, enable_thinking=False,\n        )\n        eval_formatted.append({\"text\": text})\n    eval_dataset = Dataset.from_list(eval_formatted)\n\n    return eval_items, gold, eval_dataset\n\n\nclass TaskEvalCallback(TrainerCallback):\n    \"\"\"End-of-epoch task eval: generate on dev subset -> compute F1 / Evi-F1 / EDCR.\"\"\"\n\n    def __init__(self, tokenizer, eval_items, gold, train_file, max_new_tokens=1024):\n        self.tokenizer = tokenizer\n        self.eval_items = eval_items\n        self.gold = gold\n        self.train_file = train_file\n        self.max_new_tokens = max_new_tokens\n        self._evaluator = None\n\n    @property\n    def evaluator(self):\n        if self._evaluator is None:\n            from freige.eval.evaluator import DocREDEvaluator\n            if self.train_file and os.path.exists(self.train_file):\n                self._evaluator = DocREDEvaluator.from_train_file(self.train_file)\n            else:\n                self._evaluator = DocREDEvaluator()\n        return self._evaluator\n\n    def on_epoch_end(self, args, state, control, model=None, **kwargs):\n        if not state.is_world_process_zero:\n            return\n        self._run_task_eval(model, state)\n\n    def _run_task_eval(self, model, state):\n        from freige.eval.evaluator import parse_model_output\n\n        model.eval()\n        model.config.use_cache = True\n        if hasattr(model, \"gradient_checkpointing_disable\"):\n            model.gradient_checkpointing_disable()\n\n        all_predictions = []\n        for item in self.eval_items:\n            inputs = self.tokenizer(\n                item[\"prompt\"], return_tensors=\"pt\", truncation=True, max_length=4096,\n            ).to(model.device)\n            with torch.no_grad():\n                outputs = model.generate(\n                    **inputs,\n                    max_new_tokens=self.max_new_tokens,\n                    do_sample=False,\n                    pad_token_id=self.tokenizer.pad_token_id,\n                )\n            generated = outputs[0][inputs[\"input_ids\"].shape[1]:]\n            text = self.tokenizer.decode(generated, skip_special_tokens=True)\n            triples = parse_model_output(item[\"doc_id\"], text)\n            all_predictions.extend(triples)\n\n        metrics = self.evaluator.evaluate(all_predictions, self.gold)\n\n        log_metrics = {\n            \"eval/rel_f1\": metrics[\"f1\"],\n            \"eval/ign_f1\": metrics[\"ign_f1\"],\n            \"eval/evi_f1\": metrics[\"evi_f1\"],\n            \"eval/evi_precision\": metrics[\"evi_precision\"],\n            \"eval/evi_recall\": metrics[\"evi_recall\"],\n            \"eval/edcr\": metrics.get(\"edcr\", 0),\n            \"eval/n_predictions\": len(all_predictions),\n        }\n        try:\n            import wandb\n            if wandb.run is not None:\n                wandb.log(log_metrics, step=state.global_step)\n        except ImportError:\n            pass\n\n        logger.info(\n            \"Task eval @ step %d: F1=%.4f, Ign-F1=%.4f, Evi-F1=%.4f, EDCR=%.4f (%d preds)\",\n            state.global_step, metrics[\"f1\"], metrics[\"ign_f1\"],\n            metrics[\"evi_f1\"], metrics.get(\"edcr\", 0), len(all_predictions),\n        )\n\n        model.config.use_cache = False\n        if hasattr(model, \"gradient_checkpointing_enable\"):\n            model.gradient_checkpointing_enable()\n        model.train()\n\n\nclass WeightedSFTTrainer(SFTTrainer):\n    \"\"\"SFTTrainer with CED score-weighted sampling.\n\n    高 CED score 的样本被更频繁采样。使用 WeightedRandomSampler 实现，\n    适用于单机训练。多机 DDP 场景下 Accelerate 会替换 sampler，\n    此时 weighted_sampling 不生效，需改用数据集层面的过采样。\n    \"\"\"\n\n    def __init__(self, *args, sample_weights=None, **kwargs):\n        super().__init__(*args, **kwargs)\n        self.sample_weights = sample_weights\n\n    def _get_train_sampler(self, dataset=None):\n        if self.sample_weights is not None:\n            ds = dataset if dataset is not None else self.train_dataset\n            return WeightedRandomSampler(\n                weights=self.sample_weights,\n                num_samples=len(ds),\n                replacement=True,\n            )\n        return super()._get_train_sampler(dataset)\n\n\ndef main():\n    parser = argparse.ArgumentParser(description=\"FREIGE RSFT Training\")\n    parser.add_argument(\"--base_model\", type=str, default=DEFAULT_BASE_MODEL)\n    parser.add_argument(\"--sft_adapter\", type=str, default=DEFAULT_SFT_ADAPTER,\n                        help=\"SFT warmup adapter 路径 (merge 后训练新 LoRA)\")\n    parser.add_argument(\"--rsft_data_path\", type=str, required=True,\n                        help=\"CED 筛选后的 RSFT 训练数据 (JSONL)\")\n    parser.add_argument(\"--output_dir\", type=str, required=True)\n    parser.add_argument(\"--learning_rate\", type=float, default=2e-5)\n    parser.add_argument(\"--num_epochs\", type=int, default=3)\n    parser.add_argument(\"--per_device_batch_size\", type=int, default=4)\n    parser.add_argument(\"--gradient_accumulation_steps\", type=int, default=4)\n    parser.add_argument(\"--warmup_steps\", type=int, default=100)\n    parser.add_argument(\"--save_steps\", type=int, default=50)\n    parser.add_argument(\"--save_total_limit\", type=int, default=5)\n    parser.add_argument(\"--max_length\", type=int, default=2048)\n    parser.add_argument(\"--seed\", type=int, default=42)\n    parser.add_argument(\"--wandb_project\", type=str, default=\"freige-rsft\")\n    parser.add_argument(\"--wandb_run_name\", type=str, default=None)\n    parser.add_argument(\"--weighted_sampling\", action=\"store_true\",\n                        help=\"按 CED score 加权采样（高分样本更频繁）\")\n    parser.add_argument(\"--quantize\", action=\"store_true\",\n                        help=\"启用 4-bit QLoRA 量化\")\n    parser.add_argument(\"--lora_rank\", type=int, default=64)\n    parser.add_argument(\"--lora_alpha\", type=int, default=128)\n    parser.add_argument(\"--lora_dropout\", type=float, default=0.05)\n    parser.add_argument(\"--bf16\", action=\"store_true\", default=True)\n    parser.add_argument(\"--deepspeed\", type=str, default=None,\n                        help=\"DeepSpeed 配置文件路径\")\n    parser.add_argument(\"--eval_data_dir\", type=str, default=None,\n                        help=\"DocRED data dir (contains dev.json) for task-level eval\")\n    parser.add_argument(\"--eval_max_docs\", type=int, default=50,\n                        help=\"Max dev docs for task-level eval during training\")\n    parser.add_argument(\"--max_new_tokens\", type=int, default=1024)\n    args = parser.parse_args()\n\n    # W&B\n    if args.wandb_project and \"WANDB_API_KEY\" in os.environ:\n        os.environ[\"WANDB_PROJECT\"] = args.wandb_project\n        if args.wandb_run_name:\n            os.environ[\"WANDB_NAME\"] = args.wandb_run_name\n\n    # Tokenizer\n    logger.info(\"Loading tokenizer: %s\", args.base_model)\n    tokenizer = AutoTokenizer.from_pretrained(\n        args.base_model, trust_remote_code=True, padding_side=\"right\",\n    )\n    if tokenizer.pad_token is None:\n        tokenizer.pad_token = tokenizer.eos_token\n\n    # Data\n    logger.info(\"Loading RSFT data: %s\", args.rsft_data_path)\n    train_dataset, ced_scores = load_rsft_data(\n        args.rsft_data_path, tokenizer, args.max_length,\n    )\n\n    # Model: base -> merge SFT adapter -> new LoRA\n    logger.info(\"Loading base model: %s\", args.base_model)\n    local_rank = int(os.environ.get(\"LOCAL_RANK\", 0))\n    model_kwargs = dict(\n        trust_remote_code=True,\n        attn_implementation=\"sdpa\",\n        device_map={\"\": local_rank},\n    )\n    if args.quantize:\n        logger.info(\"Using 4-bit QLoRA quantization\")\n        model_kwargs[\"quantization_config\"] = BitsAndBytesConfig(\n            load_in_4bit=True,\n            bnb_4bit_compute_dtype=torch.bfloat16,\n            bnb_4bit_quant_type=\"nf4\",\n            bnb_4bit_use_double_quant=True,\n        )\n    else:\n        model_kwargs[\"torch_dtype\"] = torch.bfloat16 if args.bf16 else torch.float16\n\n    model = AutoModelForCausalLM.from_pretrained(args.base_model, **model_kwargs)\n\n    if args.sft_adapter:\n        logger.info(\"Merging SFT adapter: %s\", args.sft_adapter)\n        model = PeftModel.from_pretrained(model, args.sft_adapter)\n        model = model.merge_and_unload()\n\n    model.config.use_cache = False\n    model.gradient_checkpointing_enable()\n\n    # Fresh LoRA for RSFT\n    lora_config = LoraConfig(\n        task_type=TaskType.CAUSAL_LM,\n        r=args.lora_rank,\n        lora_alpha=args.lora_alpha,\n        lora_dropout=args.lora_dropout,\n        target_modules=[\"q_proj\", \"k_proj\", \"v_proj\", \"o_proj\",\n                         \"gate_proj\", \"up_proj\", \"down_proj\"],\n    )\n    model = get_peft_model(model, lora_config)\n    model.print_trainable_parameters()\n\n    # Eval data\n    eval_dataset = None\n    callbacks = []\n    if args.eval_data_dir:\n        logger.info(\"Loading eval data from %s (max %d docs for task eval)\",\n                     args.eval_data_dir, args.eval_max_docs)\n        eval_items, gold, eval_dataset = prepare_eval_data(\n            args.eval_data_dir, tokenizer, args.eval_max_docs,\n        )\n        train_file = os.path.join(args.eval_data_dir, \"train_annotated.json\")\n        callbacks.append(TaskEvalCallback(\n            tokenizer=tokenizer,\n            eval_items=eval_items,\n            gold=gold,\n            train_file=train_file,\n            max_new_tokens=args.max_new_tokens,\n        ))\n        logger.info(\"Task eval enabled: %d docs, %d gold triples\",\n                     len(eval_items), len(gold))\n\n    # Training config\n    training_args = SFTConfig(\n        output_dir=args.output_dir,\n        num_train_epochs=args.num_epochs,\n        per_device_train_batch_size=args.per_device_batch_size,\n        per_device_eval_batch_size=1,\n        gradient_accumulation_steps=args.gradient_accumulation_steps,\n        learning_rate=args.learning_rate,\n        warmup_steps=args.warmup_steps,\n        bf16=args.bf16,\n        logging_steps=10,\n        eval_strategy=\"epoch\" if eval_dataset is not None else \"no\",\n        save_strategy=\"steps\",\n        save_steps=args.save_steps,\n        save_total_limit=args.save_total_limit,\n        seed=args.seed,\n        max_length=args.max_length,\n        dataset_text_field=\"text\",\n        report_to=\"wandb\" if \"WANDB_API_KEY\" in os.environ else \"none\",\n        gradient_checkpointing=True,\n        gradient_checkpointing_kwargs={\"use_reentrant\": False},\n        deepspeed=args.deepspeed,\n    )\n\n    sample_weights = ced_scores if args.weighted_sampling else None\n\n    trainer = WeightedSFTTrainer(\n        model=model,\n        args=training_args,\n        train_dataset=train_dataset,\n        eval_dataset=eval_dataset,\n        processing_class=tokenizer,\n        sample_weights=sample_weights,\n        callbacks=callbacks,\n    )\n\n    logger.info(\n        \"Starting RSFT training (%d samples, weighted=%s)...\",\n        len(train_dataset), args.weighted_sampling,\n    )\n    trainer.train()\n\n    logger.info(\"Saving model to %s\", args.output_dir)\n    trainer.save_model(args.output_dir)\n    tokenizer.save_pretrained(args.output_dir)\n    logger.info(\"RSFT training complete.\")\n\n\nif __name__ == \"__main__\":\n    main()\nRSFT_EOF",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "cd156caa-1454-4461-b04e-83c9339af270",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01U5tkHyAC7GjkXtZtFk4m26",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6211,
      "cache_read_input_tokens": 74594,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6211
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 85 · 2026-05-15T02:30:14.084Z_

<details><summary>↩ Tool result · `toolu_014VRxs5HSPdiv5koH4VQwcX`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.38}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "fd306b77-5159-4d42-88ea-7f3855ae1fbc",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.38}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.38}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 86_

验证语法和导入：

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "61cf51ae-22c8-454b-aa9b-d96efb440a7f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YSwanmTjDCPqXV191CUvs8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5339,
      "cache_read_input_tokens": 80805,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5339
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool call

_source line 87_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_execute · `toolu_01KMyMXiwstbwJ8342gP5HCo`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 python -c \"import ast; ast.parse(open('freige/training/rsft_trainer.py').read()); print('SYNTAX_OK')\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "0ef0890c-a10b-46d7-82e5-15a92b227c86",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01YSwanmTjDCPqXV191CUvs8",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5339,
      "cache_read_input_tokens": 80805,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5339
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 88 · 2026-05-15T02:30:20.004Z_

<details><summary>↩ Tool result · `toolu_01KMyMXiwstbwJ8342gP5HCo`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"SYNTAX_OK\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "c0c2335e-2588-4219-aaf8-40c4eab96a9c",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"SYNTAX_OK\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.45}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"SYNTAX_OK\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.45}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 89_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_execute · `toolu_0184F15gfkd5ZMtnoHHWrvvF`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp && HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 python -c \"from freige.training.rsft_trainer import TaskEvalCallback, prepare_eval_data, WeightedSFTTrainer; print('IMPORT_OK')\"",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "5863e10f-a23e-42c2-8945-54241fefa182",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PpbbBFXHnULpNafxS4jaqa",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 285,
      "cache_read_input_tokens": 86144,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 285
      },
      "output_tokens": 72,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 90 · 2026-05-15T02:30:30.607Z_

<details><summary>↩ Tool result · `toolu_0184F15gfkd5ZMtnoHHWrvvF`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"IMPORT_OK\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 6.88}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "ba98101a-22d0-4a50-ae98-0cff38b11a5a",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"IMPORT_OK\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 6.88}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"IMPORT_OK\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 6.88}}"
    }
  }
}
```

</details>

---

### Tool call

_source line 91_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__ssh_read_only · `toolu_01MKhG1x9u6zb34u7TWRkQqA`</summary>

```json
{
  "server": "rtx5090-4x",
  "command": "wc -l /root/autodl-tmp/freige/training/rsft_trainer.py",
  "account": "root"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "3c6d9c02-7066-4f0c-a46b-026b8d3a4855",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ReXgkd42chuNHxavD3BMnh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 283,
      "cache_read_input_tokens": 86429,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 283
      },
      "output_tokens": 54,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Tool result

_source line 92 · 2026-05-15T02:30:33.979Z_

<details><summary>↩ Tool result · `toolu_01MKhG1x9u6zb34u7TWRkQqA`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"stdout\": \"407 /root/autodl-tmp/freige/training/rsft_trainer.py\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.32}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "edcf8889-526d-4e1e-9c24-1600785cb581",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"stdout\\\": \\\"407 /root/autodl-tmp/freige/training/rsft_trainer.py\\\\n\\\", \\\"stderr\\\": \\\"\\\", \\\"return_code\\\": 0}, \\\"error\\\": null, \\\"metadata\\\": {\\\"elapsed_seconds\\\": 0.32}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"stdout\": \"407 /root/autodl-tmp/freige/training/rsft_trainer.py\\n\", \"stderr\": \"\", \"return_code\": 0}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.32}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 93_

语法和导入均通过。下面是汇总结果。

---

## 验证结果

### 已满足项

| 项目 | 状态 |
|------|------|
| SFT 训练框架复用 | ✅ 相同 SFTConfig/SFTTrainer, chat template, SYSTEM_PROMPT |
| LoRA 结构一致 | ✅ r=64, alpha=128, dropout=0.05, 7 target modules 完全一致 |
| SFT adapter merge | ✅ base → PeftModel.from_pretrained → merge_and_unload → 新 LoRA |
| CED 数据加载 | ✅ JSONL 格式，ced_score 加权采样 |
| 多 GPU 支持 | ✅ accelerate_4gpu.yaml + deepspeed_zero2.json 已配置，`--deepspeed` 参数已有 |
| bf16 / gradient checkpointing | ✅ |

### 新增修改

| 修改 | 内容 |
|------|------|
| `TrainerCallback` import | 新增 |
| `prepare_eval_data()` | 加载 DocRED dev set，构建 task eval prompts + gold + loss-based eval dataset |
| `TaskEvalCallback` | 每个 epoch 结束时：generate on dev subset → parse → 计算 F1/Ign-F1/Evi-F1/EDCR → log to W&B |
| eval_loss 支持 | `eval_strategy="epoch"`, `eval_dataset` 传入 trainer |
| 新 CLI 参数 | `--eval_data_dir`, `--eval_max_docs`(50), `--max_new_tokens`(1024) |

### SFT vs RSFT 超参对比

| 参数 | SFT warmup | RSFT 默认 | 说明 |
|------|-----------|----------|------|
| learning_rate | 2e-4 | **2e-5** | 10x 低，合理——从 warmup checkpoint 继续 |
| per_device_batch_size | 1 | **4** | RSFT 样本更短 (max_length=2048 vs 4096) |
| gradient_accumulation | 16 | **4** | effective bs: SFT=16, RSFT=16 (4×4) |
| warmup | ratio=0.05 | **steps=100** | |
| max_length | 4096 | **2048** | RSFT 生成数据一般更短 |
| epochs | 3 | 3 | 相同 |

### 显存估算 (单卡 RTX 5090 32GB)

- Qwen3-4B bf16: ~8GB
- LoRA trainable: ~250MB
- Optimizer (AdamW): ~500MB
- Activations (bs=4, seq=2048, grad ckpt): ~8-10GB
- 总计: ~17-19GB → **单卡可行**，4 GPU 更从容

### 完整训练命令

**单卡：**
```bash
cd /root/autodl-tmp && \
HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 \
python -m freige.training.rsft_trainer \
    --base_model /root/autodl-tmp/models/Qwen3-4B \
    --sft_adapter /root/autodl-tmp/sft_output \
    --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl \
    --output_dir /root/autodl-tmp/rsft_output \
    --learning_rate 2e-5 \
    --num_epochs 3 \
    --per_device_batch_size 4 \
    --gradient_accumulation_steps 4 \
    --lora_rank 64 --lora_alpha 128 \
    --weighted_sampling \
    --eval_data_dir /root/autodl-tmp/data/docred \
    --eval_max_docs 50 \
    --wandb_run_name rsft-ced-r1 \
    --seed 42
```

**4 GPU (accelerate + DeepSpeed ZeRO-2)：**
```bash
cd /root/autodl-tmp && \
HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 \
accelerate launch --config_file freige/configs/accelerate_4gpu.yaml \
    -m freige.training.rsft_trainer \
    --base_model /root/autodl-tmp/models/Qwen3-4B \
    --sft_adapter /root/autodl-tmp/sft_output \
    --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl \
    --output_dir /root/autodl-tmp/rsft_output \
    --learning_rate 2e-5 \
    --num_epochs 3 \
    --per_device_batch_size 4 \
    --gradient_accumulation_steps 1 \
    --lora_rank 64 --lora_alpha 128 \
    --weighted_sampling \
    --eval_data_dir /root/autodl-tmp/data/docred \
    --eval_max_docs 50 \
    --deepspeed freige/configs/deepspeed_zero2.json \
    --wandb_run_name rsft-ced-r1-4gpu \
    --seed 42
```

注意：4 GPU 时 `gradient_accumulation_steps=1`（effective bs = 4×4=16，与单卡一致）。WeightedRandomSampler 在 DDP 下不生效，Accelerate 会替换 sampler。

### 预估训练时间

假设 ~3000 RSFT 样本，effective bs=16:
- ~188 steps/epoch × 3 epochs = ~564 steps
- 单卡 RTX 5090: ~2-3 min/epoch → **~10 min total**
- 4 GPU: ~1 min/epoch → **~5 min total**
- Task eval (50 docs generate): ~3-5 min/epoch

### 待完成前置

`/root/autodl-tmp/rsft_filtered/rsft_train.jsonl` 尚不存在，需先完成 CED score → filter 流程生成训练数据。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "uuid": "8da14558-d605-4a6f-ae6c-0413a62f239f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014ioDkujB8W4ua26zaTBPcV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 222,
      "cache_read_input_tokens": 86712,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 222
      },
      "output_tokens": 1,
      "service_tier": "standard",
      "inference_geo": "not_available"
    },
    "diagnostics": null,
    "context_management": null
  }
}
```

</details>

---

### Task result

_source line 94_

语法和导入均通过。下面是汇总结果。

---

## 验证结果

### 已满足项

| 项目 | 状态 |
|------|------|
| SFT 训练框架复用 | ✅ 相同 SFTConfig/SFTTrainer, chat template, SYSTEM_PROMPT |
| LoRA 结构一致 | ✅ r=64, alpha=128, dropout=0.05, 7 target modules 完全一致 |
| SFT adapter merge | ✅ base → PeftModel.from_pretrained → merge_and_unload → 新 LoRA |
| CED 数据加载 | ✅ JSONL 格式，ced_score 加权采样 |
| 多 GPU 支持 | ✅ accelerate_4gpu.yaml + deepspeed_zero2.json 已配置，`--deepspeed` 参数已有 |
| bf16 / gradient checkpointing | ✅ |

### 新增修改

| 修改 | 内容 |
|------|------|
| `TrainerCallback` import | 新增 |
| `prepare_eval_data()` | 加载 DocRED dev set，构建 task eval prompts + gold + loss-based eval dataset |
| `TaskEvalCallback` | 每个 epoch 结束时：generate on dev subset → parse → 计算 F1/Ign-F1/Evi-F1/EDCR → log to W&B |
| eval_loss 支持 | `eval_strategy="epoch"`, `eval_dataset` 传入 trainer |
| 新 CLI 参数 | `--eval_data_dir`, `--eval_max_docs`(50), `--max_new_tokens`(1024) |

### SFT vs RSFT 超参对比

| 参数 | SFT warmup | RSFT 默认 | 说明 |
|------|-----------|----------|------|
| learning_rate | 2e-4 | **2e-5** | 10x 低，合理——从 warmup checkpoint 继续 |
| per_device_batch_size | 1 | **4** | RSFT 样本更短 (max_length=2048 vs 4096) |
| gradient_accumulation | 16 | **4** | effective bs: SFT=16, RSFT=16 (4×4) |
| warmup | ratio=0.05 | **steps=100** | |
| max_length | 4096 | **2048** | RSFT 生成数据一般更短 |
| epochs | 3 | 3 | 相同 |

### 显存估算 (单卡 RTX 5090 32GB)

- Qwen3-4B bf16: ~8GB
- LoRA trainable: ~250MB
- Optimizer (AdamW): ~500MB
- Activations (bs=4, seq=2048, grad ckpt): ~8-10GB
- 总计: ~17-19GB → **单卡可行**，4 GPU 更从容

### 完整训练命令

**单卡：**
```bash
cd /root/autodl-tmp && \
HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 \
python -m freige.training.rsft_trainer \
    --base_model /root/autodl-tmp/models/Qwen3-4B \
    --sft_adapter /root/autodl-tmp/sft_output \
    --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl \
    --output_dir /root/autodl-tmp/rsft_output \
    --learning_rate 2e-5 \
    --num_epochs 3 \
    --per_device_batch_size 4 \
    --gradient_accumulation_steps 4 \
    --lora_rank 64 --lora_alpha 128 \
    --weighted_sampling \
    --eval_data_dir /root/autodl-tmp/data/docred \
    --eval_max_docs 50 \
    --wandb_run_name rsft-ced-r1 \
    --seed 42
```

**4 GPU (accelerate + DeepSpeed ZeRO-2)：**
```bash
cd /root/autodl-tmp && \
HF_HOME=/root/autodl-tmp/.hf_cache HF_HUB_OFFLINE=1 TRANSFORMERS_OFFLINE=1 \
accelerate launch --config_file freige/configs/accelerate_4gpu.yaml \
    -m freige.training.rsft_trainer \
    --base_model /root/autodl-tmp/models/Qwen3-4B \
    --sft_adapter /root/autodl-tmp/sft_output \
    --rsft_data_path /root/autodl-tmp/rsft_filtered/rsft_train.jsonl \
    --output_dir /root/autodl-tmp/rsft_output \
    --learning_rate 2e-5 \
    --num_epochs 3 \
    --per_device_batch_size 4 \
    --gradient_accumulation_steps 1 \
    --lora_rank 64 --lora_alpha 128 \
    --weighted_sampling \
    --eval_data_dir /root/autodl-tmp/data/docred \
    --eval_max_docs 50 \
    --deepspeed freige/configs/deepspeed_zero2.json \
    --wandb_run_name rsft-ced-r1-4gpu \
    --seed 42
```

注意：4 GPU 时 `gradient_accumulation_steps=1`（effective bs = 4×4=16，与单卡一致）。WeightedRandomSampler 在 DDP 下不生效，Accelerate 会替换 sampler。

### 预估训练时间

假设 ~3000 RSFT 样本，effective bs=16:
- ~188 steps/epoch × 3 epochs = ~564 steps
- 单卡 RTX 5090: ~2-3 min/epoch → **~10 min total**
- 4 GPU: ~1 min/epoch → **~5 min total**
- Task eval (50 docs generate): ~3-5 min/epoch

### 待完成前置

`/root/autodl-tmp/rsft_filtered/rsft_train.jsonl` 尚不存在，需先完成 CED score → filter 流程生成训练数据。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 369775,
  "duration_api_ms": 363893,
  "num_turns": 35,
  "stop_reason": "end_turn",
  "session_id": "a8193610-3695-4682-abff-bb921c22ef73",
  "total_cost_usd": 1.6427647500000002,
  "usage": {
    "input_tokens": 24,
    "cache_creation_input_tokens": 75093,
    "cache_read_input_tokens": 1200885,
    "output_tokens": 22828,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 75093,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 1737,
        "cache_read_input_tokens": 86712,
        "cache_creation_input_tokens": 222,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 222
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 2086,
      "outputTokens": 17,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.002171,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 24,
      "outputTokens": 22828,
      "cacheReadInputTokens": 1200885,
      "cacheCreationInputTokens": 75093,
      "webSearchRequests": 0,
      "costUSD": 1.64059375,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "4a203698-fda7-452e-ab7c-fcd63c02d900"
}
```

</details>

---
