# analysis claim audit — Part 1 of 2

**When Self-Consistency Fails for NER: Degeneracy, Signal Collapse, and the Correlation-Selection Gap** · Worker execution logs

[Transcript overview](../analysis-claim-audit.md) · [Part 2 →](part-002.md) · [Structured JSON](../../../sessions/1b/1b9b5d4c25dd42d866f7.json)

## Before a recorded user message

## Before a recorded user message

120 recorded events


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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie",
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
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
    "mcp__agent-ml-research__append_idea",
    "mcp__agent-ml-research__read_project_file",
    "mcp__agent-ml-research__read_registry",
    "mcp__agent-ml-research__register_artifact",
    "mcp__agent-ml-research__save_project_file",
    "mcp__agent-ml-research__update_registry"
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
  "uuid": "df3feafc-d2c5-496c-8265-51f3ebeb45c1",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/memory/"
  },
  "fast_mode_state": "off"
}
```

---


### Runtime record

_source line 3_

```json
{
  "type": "rate_limit_event",
  "rate_limit_info": {
    "status": "allowed",
    "resetsAt": 1779207000,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "f11e6a96-106d-48bf-8add-08e17a19729b",
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8"
}
```

---


### Assistant

_source line 4_

<details><summary>Logged reasoning block</summary>

```text
The task is to perform a quantitative claim audit across the entire paper for the project `struct_self_consist_ie`. I need to:

1. Read all paper sections
2. Read the experiment registry
3. Cross-reference all quantitative claims with actual experimental data
4. Produce an audit report

Let me start by reading the paper sections and the registry in parallel. I'll use the MCP tools to read project files and the registry.

Let me first load the MCP tool schemas.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "e9787634-3b50-44ab-90d2-f924a1d04f95",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NCLbwB8Fg7gK3ABUSE2VcB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12210,
      "cache_read_input_tokens": 11701,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12210
      },
      "output_tokens": 23,
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

_source line 5_

开始论文定量声明审计。先加载工具并读取论文各章节和实验数据。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "6729e8f6-ae83-4256-8204-deae66a2eb5b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NCLbwB8Fg7gK3ABUSE2VcB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12210,
      "cache_read_input_tokens": 11701,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12210
      },
      "output_tokens": 23,
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

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01P8cozeXNhzZBTHFUR7LEyQ`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__read_registry,mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__register_artifact",
  "max_results": 4
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "d08f915a-58c2-495b-9ae2-91af8e19bbff",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NCLbwB8Fg7gK3ABUSE2VcB",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 12210,
      "cache_read_input_tokens": 11701,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12210
      },
      "output_tokens": 23,
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

_source line 7 · 2026-05-19T13:33:29.306Z_

<details><summary>↩ Tool result · `toolu_01P8cozeXNhzZBTHFUR7LEyQ`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_project_file"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__read_registry"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__save_project_file"
}
```

```json
{
  "type": "tool_reference",
  "tool_name": "mcp__agent-ml-research__register_artifact"
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
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "9816f6cf-7626-4f47-a316-420ca3ab0e2f",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__read_project_file",
      "mcp__agent-ml-research__read_registry",
      "mcp__agent-ml-research__save_project_file",
      "mcp__agent-ml-research__register_artifact"
    ],
    "query": "select:mcp__agent-ml-research__read_project_file,mcp__agent-ml-research__read_registry,mcp__agent-ml-research__save_project_file,mcp__agent-ml-research__register_artifact",
    "total_deferred_tools": 25
  }
}
```

</details>

---


### Assistant

_source line 8_

<details><summary>Logged reasoning block</summary>

```text
Now let me read the paper sections and the registry in parallel. I'll try reading various paper files and the registry simultaneously.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "513d9dd9-2230-4de0-b014-6aa681ce946a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012oRWrC1xpgk7rVew6w8JjZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1811,
      "cache_read_input_tokens": 23911,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1811
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

_source line 9_

并行读取论文各章节、paper_framing 和实验 registry。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "686cddcd-a0f6-47f3-baf9-177f711f6485",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012oRWrC1xpgk7rVew6w8JjZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1811,
      "cache_read_input_tokens": 23911,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1811
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

_source line 10_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_project_file · `toolu_01LyChb16PBXnvWQwmB6iJyt`</summary>

```json
{
  "project": "struct_self_consist_ie",
  "file": "paper_framing.md",
  "max_chars": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "e5453951-8508-4e7f-9463-0cc482bb0776",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012oRWrC1xpgk7rVew6w8JjZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1811,
      "cache_read_input_tokens": 23911,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1811
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

_source line 11 · 2026-05-19T13:33:34.766Z_

<details><summary>↩ Tool result · `toolu_01LyChb16PBXnvWQwmB6iJyt`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/paper_framing.md\", \"content\": \"# Paper Framing — struct_self_consist_ie\\n\\n> Updated 2026-05-19 — D157+D160 TRIPLE CONTRIBUTION + SCALE UPGRADE. Title: \\\"Strong Predictors, Weak Selectors: Addressing the Correlation-Selection Gap in Self-Consistency for Named Entity Recognition\\\". Entity construction θ=2/N (+1.02pp SciERC, +1.40pp FewNERD, multi-seed N=8 mean). **72B zero-shot confirms gap is fundamental**: LP ρ=-0.002 (CoNLL) / 0.081 (SciERC); LP-weighted construction +1.53pp (SciERC ZS); θ=2/N fails in zero-shot (-0.52pp SciERC, -0.92pp CoNLL). Gating bootstrap CI: τ=0.3 stable in [0.2,0.4]. D162: Decomposition formula deleted (R²=-8.53). Scale: 7B→14B→32B→72B Qwen2.5 + 8B cross-family (Qwen3+LLaMA). 14B/32B training in progress.\\n\\n## Target Venue\\n- Primary: EMNLP 2026 **Main Conference** (via ARR May 2026)\\n- Deadline: ARR May cycle, 2026-05-25\\n\\n## Core Claims (D157 updated — TRIPLE CONTRIBUTION: QE + diagnostic + prescriptive)\\n\\n### Claim 1 (PRIMARY — Dual Contribution: QE Framework + Selection Diagnostic)\\n**Positive contribution (A)**: Confidence signals reliably predict structured IE output quality at the population level (AUROC up to 0.82, ρ up to 0.45), enabling practical QE/selective prediction.\\n**Diagnostic contribution (B)** (D154 revised): Selection viability depends on LP signal quality and dataset characteristics, not degeneracy alone:\\n- **Degeneracy as headroom predictor**: High degeneracy eliminates selection headroom (CoNLL 47.4% degen → 0 net gain). Within fixed dataset-model settings, degeneracy causally modulates LP effectiveness (SciERC epoch ablation: −1.18/+0.74/+0.99pp at 3/5/10 epochs; per-entity-type within Few-NERD ρ=−0.881). But across datasets, degeneracy alone does NOT predict LP selection direction (23-point cross-configuration ρ=0.052, p=0.81).\\n- **LP-quality alignment as primary predictor**: LP must track entity-level F1 within instances. Few-NERD within-instance ρ(LP,F1) ≈ 0.5-0.66 → LP selection +1.36pp (p<0.05). SciERC ρ(LP,F1) ≈ 0.18-0.24 → LP fails despite similar degeneracy (17.8% vs 13.8%). This is the primary determinant of LP selection success across datasets.\\n- **Structural signals (SJ/FK/EM/VC)**: universally fail regardless — instance-level aggregates cannot rank candidates by construction.\\n- **Multi-causal diagnosis (D154)**: (1) degeneracy modulates headroom within settings; (2) LP-quality alignment determines cross-dataset selection success; (3) LoRA rank=8 reduces degeneracy (7.2% vs 17.8%) AND improves LP spread (0.057 vs 0.041 nats) but SciERC's weak LP-F1 alignment (ρ~0.24) still prevents selection success → LP alignment is the binding constraint, degeneracy is a within-setting modulator.\\n\\nThe framing is NOT \\\"selection fails\\\" (pure negative) but \\\"we characterize WHEN LP works (strong LP-F1 alignment), WHY it fails elsewhere (weak alignment + compression), and WHAT distinguishes LP from structural signals\\\" (empirical characterization with diagnostic implications).\\n\\n**Three-layer argument + Capability-diversity tension**:\\n- Layer A (design property, noted not discovered): 4/5 signals are instance-level aggregates → cannot rank candidates by construction. This is a conceptual clarification — the \\\"methodological premise\\\" — not an empirical finding.\\n- Layer B (empirical — instance degeneracy): 21-58% of instances produce identical F1 across all N samples, eliminating selection headroom. Within-instance ρ=0.524 (SciERC) and 0.994 (CoNLL) — signals ARE correlated within instances, but degeneracy makes this irrelevant. Non-degenerate instances show MBR closing 23-41% of oracle gap. Selection recovers T=1.0 sampling degradation (LP 0.647 vs Random 0.610, +3.7pp) but only matches T=0 greedy (0.645 macro) at 8× inference cost — zero marginal gain.\\n- Layer C (empirical — LP-quality alignment, revised D123): LP selection requires adequate within-instance correlation with task quality. Few-NERD ρ(LP,F1)≈0.5-0.66 → selection succeeds (+1.36pp). SciERC ρ(LP,F1)≈0.18-0.24 → selection fails even when LP range is adequate (rank=8: 0.057 nats). LP compression (median range 0.041 nats on SciERC full-rank) is a contributing factor but NOT the sole explanation — rank=8 expands LP range to 0.057 yet still fails. Entity-token LP shows 4× variance but WORSE selection (-2.0pp). Free-form ablation confirms compression is model/task intrinsic for NER (std ratio 0.97).\\n- **Capability-diversity tension** (unifying insight, D111): Model capability → output convergence → instance degeneracy → vanishing selection headroom. Evidence: CoNLL (91% F1) → 58% degeneracy, SciERC (66% F1) → 21%, WNUT (48% F1) → ~0%. Scale dimension: 8B → 21% degen vs 4B → 10.4% on SciERC. This is NOT an \\\"artifact\\\" — it is a **consequence of capability**, a structural inevitability. The better the model, the less test-time scaling can help via unsupervised selection.\\n\\n**Distinction from MBR literature**: Eikema et al.'s MBR failure = utility function misalignment. Our failure = utility IS aligned (within-instance ρ=0.524) but headroom eliminated by degeneracy — qualitatively novel mechanism.\\n\\n**Key evidence (score compression)**:\\n- Non-tied subset (40%): logprob selection +2.9pp vs greedy (p=0.01), within-instance ρ: 0.08→0.39\\n- Full set: logprob +0.6pp, bootstrap p=0.39, Cohen's d=0.038 (negligible), 95% CI [-3.0, +4.2]pp\\n- Oracle headroom: NER +13pp, RE +18pp → information exists but signals can't access it\\n\\n**Key evidence (free-form ablation)** [DONE — exp_freeform_ablation, NEGATIVE]:\\n- LP distribution: constrained std=0.0206, free-form std=0.0199 (ratio 0.97, virtually unchanged)\\n- Tied fraction: 59.7% → 57.7% (-2.0pp, negligible)\\n- NER selection: +0.59pp → +0.18pp (both negligible vs greedy)\\n- RE selection: -0.68pp → +1.69pp (flipped positive — secondary finding)\\n- NER VC rho: 0.379 → 0.409 (slight QE improvement, selection still fails)\\n- Parse rate: 99.95% (fine-tuned model retains JSON format without grammar)\\n- **Conclusion**: Score compression is model/task intrinsic. The gap is universal.\\n\\n**Key evidence (scale ablation)** [DONE — 2×2 matrix: {CoNLL, SciERC} × {Qwen3-8B, Qwen3-4B}]:\\n- CoNLL NER: 4B greedy_f1=0.9234 (>8B 0.9123, +1.11pp), SJ_ρ=0.4217 (≈8B 0.4357, −1.4pp), FK_ρ=0.4181 (>8B 0.3998, +1.83pp)\\n- SciERC NER: 4B SJ_ρ=0.4221 (>8B 0.3825, +3.96pp), FK_ρ=0.3258 (>8B 0.2590, +6.68pp)\\n- SciERC RE: 4B SJ_ρ=0.2673 (>8B 0.2441, +2.32pp), FK_ρ=0.3593 (>8B 0.2782, +8.11pp); struct>surface ✗ at both scales\\n- **Conclusion**: Correlation strength maintained or improved at 4B across all 4 cells. The gap originates from within-instance signal misalignment, not model capacity. Task difficulty (SciERC RE zero-F1 rate) remains the primary driver, consistent across scales.\\n- CoNLL 4B headroom: 1.70pp (vs 8B 4.20pp) → MARGINAL for selection power, but QE correlations robust\\n- SciERC RE 4B: 47.6% zero-F1, RE LP_ρ_cond=0.1135 (p=0.074, n.s.) → confirms binary dominance at 4B\\n- **4B selection results** (correlation-selection gap at 4B):\\n  - CoNLL NER 4B (n=2756): SJ +0.07pp, FK +0.03pp, LP +0.09pp vs greedy 0.9213. All ≤0.1pp — MARGINAL (headroom 1.70pp)\\n  - SciERC NER 4B (n=529): SJ **-1.49pp**, FK -1.56pp, LP -2.23pp vs greedy 0.6622. Oracle 0.7925 (+13.02pp). **All signals WORSE than greedy despite 13pp oracle headroom — gap confirmed at 4B**\\n  - SciERC NER 4B gap demonstration: SJ-FK ρ gap = +0.096 (strong correlation advantage), SJ-FK selection F1 gap = +0.0007 (zero selection advantage) → correlation-selection gap quantified at 4B\\n- **n_samples confound control**: Qwen3-8B n=8 data exists as control. CoNLL SJ: n8 ρ=0.4389 → n16 ρ=0.4496 (Δ=0.011, CI crosses zero). SciERC SJ: n8→n16 Δ=0.066, CI=[0.004, 0.128] weak effect. n_samples not a confound for 4B-8B comparison.\\n- **Paper framing**: \\\"Scale ablation shows the gap is not an artifact of a particular model size; correlation strength is maintained at 4B, confirming that the gap originates from within-instance signal misalignment rather than model capacity.\\\"\\n\\n**exp-019 supervised verifier**: IN PROGRESS (D116 Dream feedback — all 3 tiers flagged as critical gap). Simplified to logistic regression on 5 signals (scikit-learn, CPU, ~30min). If supervised verifier partially closes oracle gap → proves gap IS closable, signals carry information but unsupervised heuristics are too weak. Grounds the \\\"what would be needed\\\" part of Contribution B.\\n\\n**exp-023 LoRA rank=8 ablation** [DONE]: rank=8 vs rank=32 on SciERC. Degeneracy: 7.2% vs 21% (3× reduction). Oracle headroom: 16.0pp vs 13.3pp. But ALL selection methods still fail to beat greedy (LP -0.5pp, SJ -0.9pp). QE correlation preserved (VC ρ=0.394, SJ ρ=0.365). **Key insight**: Reducing degeneracy is NECESSARY but NOT SUFFICIENT — signals themselves lack the discriminative power to exploit increased headroom. Strengthens multi-causal argument and points to trained verifiers as the path forward. Dream 三档公认最强实验。\\n\\n**exp-021 Few-NERD Full** [DONE — Scenario B: LP works, structural fails]:\\n- Dataset: Few-NERD INTRA coarse 8-type, 131k train, 32,565 test (gold-filtered)\\n- Degeneracy: 10.0% (vs SciERC 21%, CoNLL 58%) — lowest in our study\\n- LP selection: +1.36pp vs greedy (95% CI [+1.02, +1.34], p<0.05, bootstrap B=10000). **First dataset where LP significantly improves selection.**\\n- Structural signals: SJ -0.42pp, FK -0.55pp, EM -0.31pp, VC -0.18pp — ALL fail\\n- QE correlation (unified pipeline): LP ρ=0.22 (global), SJ ρ=0.38, FK ρ=0.35 — QE preserved; within-instance LP ρ≈0.5-0.7\\n- Oracle headroom: 13.8pp — ample room for selection\\n- **Key insight**: LP succeeds where LP-F1 alignment is strong; structural signals fail regardless. Within Few-NERD, per-entity-type analysis shows ρ=−0.881 between degeneracy and LP delta (within-dataset causal effect). But cross-dataset, the gradient CoNLL→SciERC→Few-NERD does NOT monotonically predict LP effectiveness (D154: ρ=0.052 at 23 points).\\n\\n**Bonus finding (parse rate)**: Free-form parse rate 99.95% (4406/4408) — fine-tuned 8B model generates valid JSON without grammar constraints. Challenges intro:19 claim about constrained decoding necessity for format compliance.\\n\\n**Implications**: Not just \\\"signals don't work\\\" but \\\"here's WHY they don't work (intrinsic score compression), here's proof it's universal (controlled ablation via elimination), and here's the forward direction (breaking LP compression requires fundamentally different approaches — trained verifiers, multi-round refinement — not simply relaxing decoding constraints).\\\"\\n\\n### Claim 2 (METHODOLOGY — QE Evaluation Framework)\\nSystematic evaluation of 5 confidence signals across 4 families for structured IE quality estimation. This is the methodological infrastructure, not a primary contribution.\\n\\n**Key results**:\\n- NER: EM AUROC 0.749, voting_conf ρ=0.379, SJ ρ=0.360 — all >> logprob (AUROC 0.578, ρ=0.205). 3-seed consistent: SJ > FK delta=0.093~0.122\\n- RE (3-seed confirmed): **LP > SJ > FK** (mean ρ: LP 0.302, SJ 0.265, FK 0.254). Signal ranking reverses vs NER — structural signals lose advantage when 43-45% of RE samples have F1=0 (binary signal dominance). LP's coarse but stable generation-confidence signal captures \\\"did the model get any relations right\\\" better than structural overlap measures.\\n- Difficulty-dependent signal ranking: WNUT-17 conditional collapse (ρ significant → n.s.) + logprob ρ=−0.410 (non-obvious: overconfidence on OOD)\\n- Temperature robustness: SJ Δρ=±0.01 vs FK Δρ=±0.06-0.09. T=0.7: LP full ρ improves 0.205→0.249, LP cond ρ 0.154→0.185; FK 0.267→0.289 despite more compression → concentrated signal hypothesis (non-tied instances at lower T carry more informative variance). **Paper citation rule**: robustness/temperature tables use full ρ; score compression analysis uses cond ρ. Always annotate which variant.\\n- **Task-dependent signal effectiveness** (new finding from RE 3-seed): The optimal signal family depends on task structure. NER (token-level, graded F1) → structural agreement captures quality gradients. RE (relation-level, binary-dominated F1) → logprob captures generation confidence better. This is NOT a weakness — it's a nuanced finding that enriches the diagnostic framework.\\n\\n**Evidence preserved from original Claim 1** (SciERC, N=8, T=1.0, exp_012_rerun_1024):\\n- NER full (n=529): ρ — voting_conf 0.379, SJ 0.360, EM 0.295, FK 0.267, logprob 0.205; AUROC — EM 0.749, SJ 0.692, voting_conf 0.684, FK 0.629, logprob 0.578\\n- RE full (n=397): AUROC — EM 0.706, voting_conf 0.694, SJ 0.670, FK 0.609, logprob 0.601\\n- ECE (NER): EM 0.353, voting 0.381, SJ 0.453, FK 0.451, logprob 0.706\\n\\n### Claim 2b (Selection evidence)\\n**exp_016_rerun_1024 evidence** (SciERC 8B, N=8, T=1.0):\\n- NER best-of-N (n=529): logprob 0.6501 > sj 0.6450 = ensemble 0.6450 > greedy 0.6439 > voting 0.6337 > random 0.6077 (oracle 0.7758)\\n- RE best-of-N (n=397): greedy 0.4042 > logprob 0.3948 > sj 0.3855 = ensemble 0.3855 > voting 0.3592 > random 0.3544 (oracle 0.5850)\\n\\n**4B selection evidence** (N=8, T=1.0):\\n- CoNLL NER 4B (n=2756): greedy 0.9213, SJ 0.9220 (+0.07pp), FK 0.9215, LP 0.9221 (+0.09pp), oracle 0.9382. Headroom 1.70pp → selection indistinguishable\\n- SciERC NER 4B (n=529): greedy 0.6622, SJ 0.6473 (-1.49pp), FK 0.6466 (-1.56pp), LP 0.6399 (-2.23pp), oracle 0.7925 (+13.02pp). **All signals worse than greedy** → correlation-selection gap at 4B confirmed\\n\\n**exp_016_rerun_1024_bootstrap evidence** (3-seed bootstrap, 1000 iterations):\\n- NER logprob vs greedy: bootstrap 95% CI [−0.030, +0.042], permutation p=0.39\\n- Effect size: Cohen's d=0.038 (negligible), sign test win rate=0.466\\n\\n### Claim 3 (Diagnostic — task-complexity boundary + task-dependent signal effectiveness)\\nThe effectiveness of consistency-based confidence is governed by task structural complexity: compound error propagation in relational tasks degrades the consistency-accuracy correlation on the full instance set, but the signal remains valid within the model's capability range. This boundary applies across all confidence signals tested.\\n\\n**RE 3-seed mechanism** (D073, confirmed at 4B): 43-47% of RE samples have F1=0 (8B: 43-45%, 4B: 47.6%), creating binary-dominated signal distributions where structural overlap (SJ/FK) cannot differentiate quality gradients. Pattern consistent across model scales — confirming task difficulty, not model capacity, drives this boundary. LP's generation confidence captures \\\"complete failure vs partial success\\\" more reliably. 3-seed RE QE: LP ρ=0.302 > SJ 0.265 > FK 0.254. **Definitive binary dominance evidence**: RE LP full ρ=0.266 but cond ρ=0.011 (p=0.86, completely n.s.) — LP's entire RE signal comes from the zero/nonzero F1 split; once conditioned on samples where the model extracts at least one relation, LP has zero predictive power for RE quality gradients. In contrast, NER LP cond ρ remains informative (0.154–0.185). This provides the concrete mechanism for Claim 3's task-complexity boundary: it's not just \\\"compound error\\\" in the abstract — it's specifically the high zero-F1 rate that shifts the optimal signal family from structural to probabilistic, and LP's RE advantage is entirely a binary classification effect, not genuine quality estimation.\\n\\n**MVP evidence**: RE full vs cond AUROC lift — EM: 0.706→0.752 (+4.6pp), SJ: 0.670→0.646 (−2.4pp, 待确认), voting_conf: 0.694→0.642 (−5.2pp, 待确认). Component decomposition shows all RE components equally weak (head_sj rho=0.210). T=0.7 naturally separates knowledge-gap vs uncertainty errors.\\n\\n**exp-005 evidence**: Conditional filtering dwarfs temperature tuning — RE SJ cond lift +0.07~0.14 vs temperature effect ±0.01. T=1.0 preserves more oracle headroom (RE: 0.167 vs 0.131) and diversity (1-SJ: 0.389 vs 0.313). Recommendation: T=1.0 + conditional filtering, not temperature optimization.\\n\\n**exp-001 N-scaling evidence** (SciERC, n=200 subset, ⚠️ needs full-set confirmation):\\n- RE N=16: voting_conf ρ=0.448 (vs N=8 0.340, +0.108), SJ ρ=0.333 (vs 0.244, +0.089), all signals improve +0.07~0.10\\n- NER N=16: flat (already saturated at N=8) — voting_conf 0.401 vs 0.392\\n- **Key insight**: The task-complexity boundary is partially a SAMPLE BUDGET boundary. Compound error propagation increases per-instance variance, requiring more samples (N=16 vs N=8) to average out noise. This makes Claim 2 more nuanced: RE consistency fails at N=8 not because the signal is absent, but because it's noisier and needs more samples to manifest.\\n- ⚠️ Caveat: exp-001 ran on 200/529 instances. Full-set replication needed before claiming in paper.\\n\\n### Claim 4 (D154: Empirical Characterization of Selection Boundaries)\\n**Contribution C (Selection Boundary Characterization)**: Empirical analysis of when and why LP selection succeeds or fails, with DGS as exploratory heuristic (not validated framework).\\n- **Core finding (D154)**: Selection viability depends on LP signal quality (within-instance ρ(LP,F1)) and dataset characteristics. Cross-dataset degeneracy-LP correlation is ρ=0.052 (23 points, p=0.81) — degeneracy alone does not predict selection direction. Within fixed settings, degeneracy causally modulates LP effectiveness (epoch ablation, temperature ablation, per-entity-type analysis).\\n- **DGS as explored heuristic** (demoted from \\\"validated framework\\\"): Mixed results across dataset×model:\\n  - Few-NERD Qwen: +0.92pp (significant) — strong LP alignment (ρ~0.5)\\n  - SciERC Qwen: +0.71pp (not significant) — weak alignment (ρ~0.2)\\n  - CoNLL Qwen: -0.81pp (significant negative) — high degen + weak alignment\\n  - CoNLL LLaMA: +0.14pp (significant positive) — LP-quality alignment adequate\\n  - Cross-model sign reversal on CoNLL illustrates LP alignment's role, but DGS does not constitute a reliable prescriptive method\\n- **MBR**: Uniformly negative, excluded. Exception: SciERC T=1.2 +1.8pp under high-diversity conditions.\\n- **Status**: D154 reframing complete. DGS is ablation evidence, not core contribution.\\n\\n## Story Spine (D157 — Triple Contribution: QE + Diagnostic + Prescriptive, Main Conference)\\n\\n**Problem**: Test-time scaling via multi-sample generation improves LLM reasoning, but its effectiveness for structured information extraction is unclear. Practitioners need to know: (1) can confidence signals estimate output quality? (2) can they select better outputs? (3) if not, what SHOULD they do instead?\\n\\n**Existing approaches & gaps**: Self-consistency (Wang et al. 2023) succeeds for discrete-answer reasoning via majority vote on discrete answers. MBR decoding succeeds for MT. But structured IE outputs (entity sets, relation triples) present a fundamentally different challenge — prior work applies instance-level selection (pick one of N complete outputs), which is the wrong analogy for set-structured outputs. We show the correct analogy is entity-level construction (aggregate across outputs).\\n\\n**Our framing (D157 — TRIPLE CONTRIBUTION)**:\\n\\n**Contribution A (Positive — QE Framework)**: Five confidence signals across four families reliably predict structured IE output quality (AUROC 0.82, ρ 0.45). Signal ranking is task-dependent: structural > probabilistic for NER, reversed for RE. QE enables selective prediction: filtering 20% low-confidence instances yields +5-8pp F1 gain (AUPRC 0.70-0.92, VC strongest signal).\\n\\n**Contribution B (Diagnostic — Why Instance-Level Selection Fails)**:\\n1. **Design property**: 4/5 signals are instance-level aggregates → cannot rank candidates by construction.\\n2. **Instance Degeneracy**: 21-58% of instances produce identical F1 across all N samples, eliminating selection headroom.\\n3. **LP Compression**: Logprob within-instance range compressed (0.041 nats). Free-form ablation confirms intrinsic (std ratio 0.97).\\n4. **Multi-causal**: LoRA rank=8 reduces degeneracy 3× (7.2% vs 21%) and increases oracle headroom (+2.7pp), but ALL selection methods still fail to beat greedy → low degeneracy is NECESSARY but NOT SUFFICIENT.\\n5. **Capability-diversity tension**: Higher capability → more convergence → more degeneracy. CoNLL 91% F1→58% degen, SciERC 66%→21%.\\n6. **LP alignment as primary predictor**: LP selection viability depends on within-instance ρ(LP,F1). Few-NERD (ρ~0.5-0.7) → LP +1.38pp (p<0.05). SciERC (ρ~0.2) → LP fails despite similar degeneracy. Cross-dataset degeneracy ρ=0.052 (23 configs, p=0.81).\\n\\n**Contribution C (Prescriptive — Entity-Level Construction + Practitioner Protocol, D157)**:\\nThe correct self-consistency analogy for structured IE is NOT instance-level selection but entity-level construction: aggregate entities across N samples via majority vote, constructing a new output from parts.\\n- **Entity construction (multi-seed N=8 mean)**: SciERC +1.02pp, FewNERD +1.40pp, CoNLL +0.10pp (n.s.). Mechanism: recall gain by aggregating low-frequency correct entities across samples.\\n- **72B zero-shot construction**: LP-weighted construction SciERC ZS +1.53pp (stronger than fine-tuned!), CoNLL ZS -0.37pp (headroom-limited). **θ=2/N fails in zero-shot** (SciERC -0.52pp, CoNLL -0.92pp) → LP-weighting is necessary in zero-shot regime.\\n- **Construction effectiveness is headroom-dependent**: Works when oracle headroom is sufficient (SciERC 15pp → +1.53pp), fails when near ceiling (CoNLL 5.3pp → -0.37pp). This is consistent across fine-tuned and zero-shot regimes.\\n- **LP-alignment gating (preliminary diagnostic)**: Probe 50 instances on validation set to compute adjusted alignment score → automatically select construction vs LP selection. 3/3 datasets correct gating. Bootstrap CI: τ=0.3 at center of [0.25, 0.35] stable plateau, routing decisions stable across τ∈[0.2, 0.4] (stability ≥95%).\\n- **Selective prediction**: QE-driven human-in-the-loop — retain 80% high-confidence instances, F1 +5-8pp. VC is strongest signal across all datasets.\\n\\n**QE-vs-Selection Decoupling** (Dream-identified most novel insight): QE correlation (SJ ρ) is stable across LoRA rank configurations (0.360→0.378) while selection gap changes dramatically. Signals are ALWAYS useful for flagging uncertain instances, even when they cannot improve selection.\\n\\n**Headline**: \\\"We present a triple contribution for structured IE test-time scaling: (1) a QE framework showing confidence signals reliably predict output quality and enable selective prediction (+5-8pp @80% coverage); (2) a diagnostic revealing that the correlation-selection gap is fundamental — persisting from 4B to 72B and from fine-tuned to zero-shot regimes — driven by degeneracy, LP compression, and LP-alignment misalignment; and (3) entity-level construction as a diagnostic-motivated mitigation that significantly improves over greedy decoding (+1.02pp SciERC, +1.40pp FewNERD fine-tuned; +1.53pp SciERC zero-shot via LP-weighting), with effectiveness governed by oracle headroom.\\\"\\n\\n**Title candidates**:\\n- \\\"Don't Select, Construct: Diagnosing and Fixing Test-Time Scaling for Structured Information Extraction\\\"\\n- \\\"Strong Predictors, Weak Selectors: From Diagnosis to Entity-Level Construction for Structured IE\\\"\\n- \\\"Beyond Selection: Entity-Level Construction as the Correct Self-Consistency for Structured IE\\\"\\n\\n## Anticipated Reviewer Concerns\\n\\n### R1: \\\"Only one NER dataset — generalization unclear\\\"\\n- **Status**: ✅ RESOLVED. 3 NER datasets (SciERC + CoNLL-2003 + Few-NERD INTRA) × 2 models (Qwen3-8B + LLaMA-3.1-8B) + scale ablation (Qwen3-4B). Few-NERD adds 32,565 instances with distinct degeneracy profile (10% vs 21-58%). Cross-dataset comparison revealing LP alignment as primary selection predictor (D154) is the paper's strongest empirical contribution.\\n- **Priority**: P0, RESOLVED\\n\\n### R2: \\\"Only one model family (Qwen3-8B)\\\"\\n- **Mitigation**: LLaMA-3.1-8B shows model-agnostic effect. ⚠️ **exp-007 数据被污染 (test data leakage)**，LLaMA SciERC 正确值来自 exp_018 (clean rerun)。unified_rho_full.json 的 LLaMA SciERC 条目必须替换为 exp_018 数据。正确 LLaMA SciERC N=8 3-seed mean: SJ 0.325, FK 0.256, VC 0.384, EM 0.279, LP 0.162。\\n- **Priority**: P0\\n\\n### R3: \\\"FK is a strawman baseline — what about log-prob, USC, exact-match?\\\"\\n- **Mitigation**: exp-012 (log-prob), exp-013 (exact-match), exp-014 (entity voting) provide comprehensive baseline comparison. Results: structural consistency family (EM+SJ+voting) >> log-prob >> FK. USC discussed in related work (LLM-as-judge, orthogonal approach).\\n- **Priority**: P0, RESOLVED — results decisive\\n\\n### R3b: \\\"EM beats voting_conf and SJ on AUROC — why present SJ/voting_conf?\\\"\\n- **Mitigation**: EM is a strict binary signal (all-or-nothing match); SJ captures partial agreement and generalizes to arbitrary structured outputs (relations, events). Voting_conf provides granular entity-level scores. NER full AUROC: EM 0.749 > SJ 0.692 > voting_conf 0.684, but ρ: voting_conf 0.379 > SJ 0.360 > EM 0.295. EM excels at binary discrimination but underperforms on rank ordering. SJ is also more temperature-robust (Δρ=±0.01). Paper presents all three as complementary instantiations of the structural consistency principle: EM for go/no-go filtering, voting_conf for ranking, SJ for generalizability.\\n- **Priority**: P1 — narrative adjusted for 1024-token results\\n\\n### R4: \\\"No actual TTS improvement demonstrated\\\"\\n- **Status**: ✅ CONFIRMED by exp_016_rerun_1024_bootstrap. No signal significantly outperforms greedy on either task. NER logprob +0.6pp not significant (bootstrap p=0.39, 95% CI [−0.030, +0.042], Cohen's d=0.038). RE: greedy > all signals.\\n- **Mitigation**: Paper PIVOTS to \\\"confidence estimation + correlation-selection gap analysis.\\\" exp-006 redesigned as diagnostic: show selection curves to visualize the gap (F1 vs N per signal + oracle ceiling). The gap itself is a contribution, not a failure.\\n- **Priority**: P0 — narrative pivot complete, bootstrap confirms\\n\\n### R5: \\\"Sample size N=8 may be too small for reliable SJ estimation\\\"\\n- **Mitigation**: exp-001 (N=16) with multi-seed robustness\\n- **Priority**: P0\\n\\n### R6: \\\"Conditional analysis cherry-picks favorable instances\\\"\\n- **Mitigation**: Principled separation (knowledge-gap vs uncertainty). Add threshold sensitivity analysis. Temperature analysis provides independent validation.\\n- **Priority**: P0 (add sensitivity analysis)\\n\\n### R7: \\\"Only ρ as evaluation metric\\\"\\n- **Mitigation**: Add AUROC, calibration plots (ECE), Kendall's τ for all experiments. ECE data now available: NER best calibrated = EM (0.353), RE best = voting (0.272). Logprob worst calibrated (NER 0.706, RE 0.769).\\n- **Priority**: P0\\n\\n### R8: \\\"Formula-implementation discrepancy\\\"\\n- **Mitigation**: Paper must describe actual algorithm (type-grouped Hungarian matching with max(|g_a|,|g_b|) denominator)\\n- **Priority**: P0, paper writing fix\\n\\n### R9: \\\"Evaluation circularity (T>0 consistency vs T=0 F1)\\\"\\n- **Mitigation**: Add leave-one-out SJ evaluation as robustness check. Justify cross-mode design (greedy = deterministic reference, standard in TTS literature).\\n- **Priority**: P0\\n\\n### R10: \\\"Insufficient related work\\\" (三档一致 [B][M][W])\\n- **Mitigation**: Expand to 35+ references. Must cite:\\n  - USC (Chen 2024) — empirical differentiation, not just citation\\n  - Semantic uncertainty (Kuhn 2023), calibration (Kadavath 2022, Guo 2017, Desai & Durrett 2020)\\n  - **Conformal prediction for structured outputs**: Fisch et al. 2021, Angelopoulos et al. 2021, Bates et al. 2021\\n  - **Token-level NER uncertainty**: Xiao & Wang 2019, Shelmanov et al. 2021, He et al. 2020\\n  - **Ensemble/MC-dropout**: Lakshminarayanan et al. 2017, Gal & Ghahramani 2016\\n  - **Verifier/reward models**: Cobbe et al. 2021, Lightman et al. 2023\\n  - **TTS scaling theory**: Snell et al. 2024, Brown et al. 2024\\n  - **Structured calibration**: Kuleshov & Liang 2015, Jagannatha & Yu 2022\\n  - **IE confidence**: Culotta & McCallum 2004\\n  - SelfCheckGPT (Manakul 2023), selective prediction (Geifman & El-Yaniv 2017)\\n  - **[2025-2026 新颖性自查补充 — 必引]**:\\n    - CISC (ACL Findings 2025) — confidence-weighted majority vote for reasoning; 对比：我们用 structural similarity 而非 confidence 加权，且面向 set-structured IE 输出\\n    - Self-Certainty Best-of-N (ICLR 2026, arxiv 2502.18581) — KL-divergence reward-free selection; 对比：我们发现 log-prob 是唯一有效 selection signal (与其方向互补)，且揭示 correlation-selection gap\\n    - ReASC (2026, arxiv 2601.02970) — reliability-aware adaptive self-consistency; 对比：仍限于 reasoning 离散答案\\n    - Atomic Self-Consistency (EMNLP 2024) — 子声明级一致性 for long-form text; 对比：我们在 entity-set 级别做结构化度量\\n    - **Nédellec & Xia (Genomics Informatics, 2026-02, PMC12888769)** — \\\"Consistency–accuracy correlation in hard-prompted LLMs for entity and relation extraction\\\"。最直接竞争者：4 LLMs 在植物健康 NER/RE 上研究 consistency-accuracy 相关性。**关键差异**：(a) 他们用 surface-level string matching，自承\\\"overlooks semantically consistent outputs\\\"，我们的 SJ 正好解决此问题; (b) 不研究 best-of-N selection; (c) 单领域 hard-prompted (T=0); (d) 无多信号家族对比。论文 Intro 可引用其 limitation 作为 SJ 的动机\\n  - **[2025-2026 新颖性自查补充 — 应引]**:\\n    - UQ for LLMs Survey (ACL Findings 2025) — 最全面 LLM 不确定性综述\\n    - UQ+Calibration Survey (arxiv 2503.15850, 2025) — 第二篇综合综述\\n    - Semantic Entropy Probes (2024) — 低成本不确定性估计\\n    - Latent Self-Consistency (2025, arxiv 2508.18395) — embedding 空间一致性\\n    - Ranked Voting SC (2025, arxiv 2505.10772) — 排名投票变体，仍限于推理任务\\n    - Know Your Limits: Abstention Survey (TACL 2025) — 选择性预测综述，与 Claim 1 selective prediction 角度直接相关\\n    - Confidence Estimation Survey (NAACL 2024, arxiv 2311.08298) — LLM 置信度估计全景定位\\n    - **CoCoA (Vashurin et al., NeurIPS 2025, arxiv 2502.04964)** — MBR 框架融合 confidence+consistency 做 UQ，在 QA/摘要/翻译上评估。与我们 exp-016 ensemble (SJ+logprob) 对标，但未涉及 structured IE\\n    - **Vashurin et al. (arxiv 2510.20460, 2025)** — VCE/MSP/Sample Consistency/CoCoA 四方法系统评估，任务不含 structured IE\\n  - **需新增 Related Work 小节**:\\n    - \\\"Test-Time Scaling & Sample Selection\\\" — 将 CISC/Self-Certainty/ReASC 集中讨论，明确 positioning：现有工作均面向 reasoning/QA 的离散答案，我们首次在 structured IE 上做系统信号对比并发现 correlation-selection gap\\n    - \\\"Consistency for Structured IE\\\" — 引 Nédellec & Xia 2026 作为同期工作，显式对比：surface matching vs structural metrics (SJ)；他们的 limitation 是我们的 motivation\\n- **Priority**: P0, Paper Agent handles\\n\\n### R11: \\\"SJ+logprob ensemble missing\\\" (Dream 2 — both reviewers)\\n- **Status**: ⚠️ REVISED by exp_016_rerun_1024. Results:\\n  - Ensemble AUROC (5-fold CV LR): NER 0.666 ± 0.070, RE 0.662 ± 0.078\\n  - Best single signal EM: NER AUROC 0.749, RE AUROC 0.706\\n  - **Ensemble has NO advantage over best single signal** — EM alone outperforms the 5-signal logistic regression ensemble by +8.3pp (NER) and +4.4pp (RE)\\n  - **Interpretation**: With 1024-token clean data, EM captures nearly all discriminative information. The ensemble's inferior performance likely reflects overfitting in the 5-fold CV LR with correlated features. This further supports presenting EM as a simple, strong baseline within the structural consistency family.\\n- **Priority**: DONE — write into paper with honest interpretation (no ensemble advantage claim)\\n\\n### R12: \\\"No supervised upper bound / reward model comparison\\\" (Dream 2)\\n- **Mitigation**: exp-016 LR ensemble (5-signal, 5-fold CV) underperforms best single signal EM (AUROC 0.666 vs 0.749), suggesting feature redundancy. exp-019 supervised verifier SKIPPED (DDL risk + scope creep). Free-form ablation provides the \\\"so what\\\": gap is fundamental → closing it requires fundamentally different approaches (trained verifiers, not just better unsupervised signals). Positioned as future work with explicit motivation from ablation evidence.\\n- **Priority**: P1, addressed via framing (future work motivated by ablation)\\n\\n### R13: \\\"Headroom capture rate low\\\" (Dream 2)\\n- **Mitigation**: NER oracle 0.7758, greedy 0.6439, best signal (logprob) 0.6501 → captures 0.5% of headroom. RE oracle 0.5850, greedy 0.4042, best signal (greedy itself) → 0% capture. Discuss explicitly in paper. Contextualize vs other unsupervised TTS methods. Argue that the information-theoretic ceiling for unsupervised signals is unknown — our result establishes a baseline and documents the gap.\\n- **Priority**: P0, paper writing\\n\\n### R14: \\\"Cross-model validation thin — need more than 2×8B\\\" (Dream 2)\\n- **Status**: ✅ RESOLVED by 4B scale ablation. 2×2 matrix: {CoNLL, SciERC} × {Qwen3-8B, Qwen3-4B}. All correlation metrics maintained or improved at 4B (e.g. SciERC NER SJ_ρ: 0.3825→0.4221, +3.96pp). Combined with LLaMA-3.1-8B cross-architecture data, now have 3 model configurations (Qwen3-8B, Qwen3-4B, LLaMA-3.1-8B). 70B infeasible — acknowledge as limitation.\\n- **Priority**: P0, RESOLVED\\n\\n### R15: \\\"Log-prob definition ambiguity — Eq.1 vs best-of-N ranking\\\" (Dream 2 cross-tier, [W])\\n- **Mitigation**: Paper must clarify: log-prob ranks among N candidates (each sample's generation log-prob), not just score greedy output. Cost comparison table must state \\\"all best-of-N require N forward passes; log-prob adds zero ranking overhead.\\\"\\n- **Priority**: P0, Paper Agent handles\\n\\n### R16: \\\"Zero figures — data-rich paper with only tables\\\" (Dream 2 cross-tier, [W])\\n- **Mitigation**: Paper Agent must include ≥3 figures: (1) selection curves (F1 vs N for each signal + oracle), (2) reliability diagram (calibration), (3) N-scaling or cost-effectiveness scatter. Data exists from exp-010/015.\\n- **Priority**: P0, Paper Agent handles\\n\\n### R17: \\\"Diagnostic framework overclaimed — descriptive not prescriptive\\\" (Dream 2 cross-tier, [M][W])\\n- **Mitigation**: Soften \\\"diagnostic framework\\\" to \\\"diagnostic analysis\\\" throughout. Current taxonomy (ceiling/floor/compound error) is descriptive. Either formalize with a priori metrics or reframe as empirical analysis.\\n- **Priority**: P0, Paper Agent handles\\n\\n### R18: \\\"No discussion of when consistency WOULD help\\\" (Dream 2 cross-tier, [W])\\n- **Mitigation**: Add discussion paragraph: consistency should outperform log-prob when (a) model calibration is poor (in-context learning without fine-tuning), (b) log-prob unavailable (closed-source APIs), (c) ensemble/mixture settings, (d) tasks where model is systematically overconfident.\\n- **Priority**: P1, Paper Agent handles\\n\\n### R19: \\\"Negative result partially predictable for fine-tuned models\\\" (Dream 2 cross-tier, [W])\\n- **Mitigation**: Paper must argue non-obviousness: (a) self-consistency demonstrably helps for reasoning tasks (Wang et al. 2023), (b) structured prediction has internal structure that surface metrics can't capture, (c) the DEGREE of log-prob's strength and the task-complexity boundary are not predictable a priori.\\n- **Priority**: P1, Paper Agent handles\\n\\n## Venue Fit\\n\\nEMNLP **Main Conference** target. Strengths:\\n- Systematic empirical comparison with mechanistic diagnosis (not just \\\"signals don't work\\\" but \\\"here's exactly why\\\")\\n- Two novel failure mechanisms (instance degeneracy + LP compression) + unifying capability-diversity tension\\n- Controlled ablation (free-form decoding) providing causal evidence\\n- Cross-model (Qwen3-8B/4B + LLaMA-3.1-8B), cross-dataset (SciERC + CoNLL + WNUT), cross-task (NER + RE) validation\\n\\nMain Conference gap vs Findings:\\n- ✅ 3rd NER dataset (Few-NERD) — DONE, confirms LP alignment as primary predictor\\n- ✅ LoRA rank=8 ablation — DONE, multi-causal confirmed\\n- ✅ Bootstrap significance — DONE, LP p<0.05 on Few-NERD\\n- ✅ Numerical audit — DONE, all corrections applied\\n- **Remaining**: Dream #3 validation (target ≥3.5), final editorial pass\\n\\nRisk assessment:\\n- **Strongest asset**: LP alignment as primary selection predictor + within-dataset causal evidence (epoch/temperature ablation) — honest empirical characterization with actionable implications\\n- **Second strongest**: QE-vs-selection decoupling (signals always useful for QE even when selection fails)\\n- **Weakest flank**: D154 removed \\\"monotonic gradient\\\" claim, but the within/cross distinction is more nuanced and honest — reviewers should appreciate this\\n- **Critical path**: Dream #3 → final submission to Review Director → DDL 2026-05-25\", \"total_chars\": 35571, \"truncated\": false}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "00b1324d-45e8-4306-b897-73d258e01d25",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"path\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/paper_framing.md\\\", \\\"content\\\": \\\"# Paper Framing — struct_self_consist_ie\\\\n\\\\n> Updated 2026-05-19 — D157+D160 TRIPLE CONTRIBUTION + SCALE UPGRADE. Title: \\\\\\\"Strong Predictors, Weak Selectors: Addressing the Correlation-Selection Gap in Self-Consistency for Named Entity Recognition\\\\\\\". Entity construction θ=2/N (+1.02pp SciERC, +1.40pp FewNERD, multi-seed N=8 mean). **72B zero-shot confirms gap is fundamental**: LP ρ=-0.002 (CoNLL) / 0.081 (SciERC); LP-weighted construction +1.53pp (SciERC ZS); θ=2/N fails in zero-shot (-0.52pp SciERC, -0.92pp CoNLL). Gating bootstrap CI: τ=0.3 stable in [0.2,0.4]. D162: Decomposition formula deleted (R²=-8.53). Scale: 7B→14B→32B→72B Qwen2.5 + 8B cross-family (Qwen3+LLaMA). 14B/32B training in progress.\\\\n\\\\n## Target Venue\\\\n- Primary: EMNLP 2026 **Main Conference** (via ARR May 2026)\\\\n- Deadline: ARR May cycle, 2026-05-25\\\\n\\\\n## Core Claims (D157 updated — TRIPLE CONTRIBUTION: QE + diagnostic + prescriptive)\\\\n\\\\n### Claim 1 (PRIMARY — Dual Contribution: QE Framework + Selection Diagnostic)\\\\n**Positive contribution (A)**: Confidence signals reliably predict structured IE output quality at the population level (AUROC up to 0.82, ρ up to 0.45), enabling practical QE/selective prediction.\\\\n**Diagnostic contribution (B)** (D154 revised): Selection viability depends on LP signal quality and dataset characteristics, not degeneracy alone:\\\\n- **Degeneracy as headroom predictor**: High degeneracy eliminates selection headroom (CoNLL 47.4% degen → 0 net gain). Within fixed dataset-model settings, degeneracy causally modulates LP effectiveness (SciERC epoch ablation: −1.18/+0.74/+0.99pp at 3/5/10 epochs; per-entity-type within Few-NERD ρ=−0.881). But across datasets, degeneracy alone does NOT predict LP selection direction (23-point cross-configuration ρ=0.052, p=0.81).\\\\n- **LP-quality alignment as primary predictor**: LP must track entity-level F1 within instances. Few-NERD within-instance ρ(LP,F1) ≈ 0.5-0.66 → LP selection +1.36pp (p<0.05). SciERC ρ(LP,F1) ≈ 0.18-0.24 → LP fails despite similar degeneracy (17.8% vs 13.8%). This is the primary determinant of LP selection success across datasets.\\\\n- **Structural signals (SJ/FK/EM/VC)**: universally fail regardless — instance-level aggregates cannot rank candidates by construction.\\\\n- **Multi-causal diagnosis (D154)**: (1) degeneracy modulates headroom within settings; (2) LP-quality alignment determines cross-dataset selection success; (3) LoRA rank=8 reduces degeneracy (7.2% vs 17.8%) AND improves LP spread (0.057 vs 0.041 nats) but SciERC's weak LP-F1 alignment (ρ~0.24) still prevents selection success → LP alignment is the binding constraint, degeneracy is a within-setting modulator.\\\\n\\\\nThe framing is NOT \\\\\\\"selection fails\\\\\\\" (pure negative) but \\\\\\\"we characterize WHEN LP works (strong LP-F1 alignment), WHY it fails elsewhere (weak alignment + compression), and WHAT distinguishes LP from structural signals\\\\\\\" (empirical characterization with diagnostic implications).\\\\n\\\\n**Three-layer argument + Capability-diversity tension**:\\\\n- Layer A (design property, noted not discovered): 4/5 signals are instance-level aggregates → cannot rank candidates by construction. This is a conceptual clarification — the \\\\\\\"methodological premise\\\\\\\" — not an empirical finding.\\\\n- Layer B (empirical — instance degeneracy): 21-58% of instances produce identical F1 across all N samples, eliminating selection headroom. Within-instance ρ=0.524 (SciERC) and 0.994 (CoNLL) — signals ARE correlated within instances, but degeneracy makes this irrelevant. Non-degenerate instances show MBR closing 23-41% of oracle gap. Selection recovers T=1.0 sampling degradation (LP 0.647 vs Random 0.610, +3.7pp) but only matches T=0 greedy (0.645 macro) at 8× inference cost — zero marginal gain.\\\\n- Layer C (empirical — LP-quality alignment, revised D123): LP selection requires adequate within-instance correlation with task quality. Few-NERD ρ(LP,F1)≈0.5-0.66 → selection succeeds (+1.36pp). SciERC ρ(LP,F1)≈0.18-0.24 → selection fails even when LP range is adequate (rank=8: 0.057 nats). LP compression (median range 0.041 nats on SciERC full-rank) is a contributing factor but NOT the sole explanation — rank=8 expands LP range to 0.057 yet still fails. Entity-token LP shows 4× variance but WORSE selection (-2.0pp). Free-form ablation confirms compression is model/task intrinsic for NER (std ratio 0.97).\\\\n- **Capability-diversity tension** (unifying insight, D111): Model capability → output convergence → instance degeneracy → vanishing selection headroom. Evidence: CoNLL (91% F1) → 58% degeneracy, SciERC (66% F1) → 21%, WNUT (48% F1) → ~0%. Scale dimension: 8B → 21% degen vs 4B → 10.4% on SciERC. This is NOT an \\\\\\\"artifact\\\\\\\" — it is a **consequence of capability**, a structural inevitability. The better the model, the less test-time scaling can help via unsupervised selection.\\\\n\\\\n**Distinction from MBR literature**: Eikema et al.'s MBR failure = utility function misalignment. Our failure = utility IS aligned (within-instance ρ=0.524) but headroom eliminated by degeneracy — qualitatively novel mechanism.\\\\n\\\\n**Key evidence (score compression)**:\\\\n- Non-tied subset (40%): logprob selection +2.9pp vs greedy (p=0.01), within-instance ρ: 0.08→0.39\\\\n- Full set: logprob +0.6pp, bootstrap p=0.39, Cohen's d=0.038 (negligible), 95% CI [-3.0, +4.2]pp\\\\n- Oracle headroom: NER +13pp, RE +18pp → information exists but signals can't access it\\\\n\\\\n**Key evidence (free-form ablation)** [DONE — exp_freeform_ablation, NEGATIVE]:\\\\n- LP distribution: constrained std=0.0206, free-form std=0.0199 (ratio 0.97, virtually unchanged)\\\\n- Tied fraction: 59.7% → 57.7% (-2.0pp, negligible)\\\\n- NER selection: +0.59pp → +0.18pp (both negligible vs greedy)\\\\n- RE selection: -0.68pp → +1.69pp (flipped positive — secondary finding)\\\\n- NER VC rho: 0.379 → 0.409 (slight QE improvement, selection still fails)\\\\n- Parse rate: 99.95% (fine-tuned model retains JSON format without grammar)\\\\n- **Conclusion**: Score compression is model/task intrinsic. The gap is universal.\\\\n\\\\n**Key evidence (scale ablation)** [DONE — 2×2 matrix: {CoNLL, SciERC} × {Qwen3-8B, Qwen3-4B}]:\\\\n- CoNLL NER: 4B greedy_f1=0.9234 (>8B 0.9123, +1.11pp), SJ_ρ=0.4217 (≈8B 0.4357, −1.4pp), FK_ρ=0.4181 (>8B 0.3998, +1.83pp)\\\\n- SciERC NER: 4B SJ_ρ=0.4221 (>8B 0.3825, +3.96pp), FK_ρ=0.3258 (>8B 0.2590, +6.68pp)\\\\n- SciERC RE: 4B SJ_ρ=0.2673 (>8B 0.2441, +2.32pp), FK_ρ=0.3593 (>8B 0.2782, +8.11pp); struct>surface ✗ at both scales\\\\n- **Conclusion**: Correlation strength maintained or improved at 4B across all 4 cells. The gap originates from within-instance signal misalignment, not model capacity. Task difficulty (SciERC RE zero-F1 rate) remains the primary driver, consistent across scales.\\\\n- CoNLL 4B headroom: 1.70pp (vs 8B 4.20pp) → MARGINAL for selection power, but QE correlations robust\\\\n- SciERC RE 4B: 47.6% zero-F1, RE LP_ρ_cond=0.1135 (p=0.074, n.s.) → confirms binary dominance at 4B\\\\n- **4B selection results** (correlation-selection gap at 4B):\\\\n  - CoNLL NER 4B (n=2756): SJ +0.07pp, FK +0.03pp, LP +0.09pp vs greedy 0.9213. All ≤0.1pp — MARGINAL (headroom 1.70pp)\\\\n  - SciERC NER 4B (n=529): SJ **-1.49pp**, FK -1.56pp, LP -2.23pp vs greedy 0.6622. Oracle 0.7925 (+13.02pp). **All signals WORSE than greedy despite 13pp oracle headroom — gap confirmed at 4B**\\\\n  - SciERC NER 4B gap demonstration: SJ-FK ρ gap = +0.096 (strong correlation advantage), SJ-FK selection F1 gap = +0.0007 (zero selection advantage) → correlation-selection gap quantified at 4B\\\\n- **n_samples confound control**: Qwen3-8B n=8 data exists as control. CoNLL SJ: n8 ρ=0.4389 → n16 ρ=0.4496 (Δ=0.011, CI crosses zero). SciERC SJ: n8→n16 Δ=0.066, CI=[0.004, 0.128] weak effect. n_samples not a confound for 4B-8B comparison.\\\\n- **Paper framing**: \\\\\\\"Scale ablation shows the gap is not an artifact of a particular model size; correlation strength is maintained at 4B, confirming that the gap originates from within-instance signal misalignment rather than model capacity.\\\\\\\"\\\\n\\\\n**exp-019 supervised verifier**: IN PROGRESS (D116 Dream feedback — all 3 tiers flagged as critical gap). Simplified to logistic regression on 5 signals (scikit-learn, CPU, ~30min). If supervised verifier partially closes oracle gap → proves gap IS closable, signals carry information but unsupervised heuristics are too weak. Grounds the \\\\\\\"what would be needed\\\\\\\" part of Contribution B.\\\\n\\\\n**exp-023 LoRA rank=8 ablation** [DONE]: rank=8 vs rank=32 on SciERC. Degeneracy: 7.2% vs 21% (3× reduction). Oracle headroom: 16.0pp vs 13.3pp. But ALL selection methods still fail to beat greedy (LP -0.5pp, SJ -0.9pp). QE correlation preserved (VC ρ=0.394, SJ ρ=0.365). **Key insight**: Reducing degeneracy is NECESSARY but NOT SUFFICIENT — signals themselves lack the discriminative power to exploit increased headroom. Strengthens multi-causal argument and points to trained verifiers as the path forward. Dream 三档公认最强实验。\\\\n\\\\n**exp-021 Few-NERD Full** [DONE — Scenario B: LP works, structural fails]:\\\\n- Dataset: Few-NERD INTRA coarse 8-type, 131k train, 32,565 test (gold-filtered)\\\\n- Degeneracy: 10.0% (vs SciERC 21%, CoNLL 58%) — lowest in our study\\\\n- LP selection: +1.36pp vs greedy (95% CI [+1.02, +1.34], p<0.05, bootstrap B=10000). **First dataset where LP significantly improves selection.**\\\\n- Structural signals: SJ -0.42pp, FK -0.55pp, EM -0.31pp, VC -0.18pp — ALL fail\\\\n- QE correlation (unified pipeline): LP ρ=0.22 (global), SJ ρ=0.38, FK ρ=0.35 — QE preserved; within-instance LP ρ≈0.5-0.7\\\\n- Oracle headroom: 13.8pp — ample room for selection\\\\n- **Key insight**: LP succeeds where LP-F1 alignment is strong; structural signals fail regardless. Within Few-NERD, per-entity-type analysis shows ρ=−0.881 between degeneracy and LP delta (within-dataset causal effect). But cross-dataset, the gradient CoNLL→SciERC→Few-NERD does NOT monotonically predict LP effectiveness (D154: ρ=0.052 at 23 points).\\\\n\\\\n**Bonus finding (parse rate)**: Free-form parse rate 99.95% (4406/4408) — fine-tuned 8B model generates valid JSON without grammar constraints. Challenges intro:19 claim about constrained decoding necessity for format compliance.\\\\n\\\\n**Implications**: Not just \\\\\\\"signals don't work\\\\\\\" but \\\\\\\"here's WHY they don't work (intrinsic score compression), here's proof it's universal (controlled ablation via elimination), and here's the forward direction (breaking LP compression requires fundamentally different approaches — trained verifiers, multi-round refinement — not simply relaxing decoding constraints).\\\\\\\"\\\\n\\\\n### Claim 2 (METHODOLOGY — QE Evaluation Framework)\\\\nSystematic evaluation of 5 confidence signals across 4 families for structured IE quality estimation. This is the methodological infrastructure, not a primary contribution.\\\\n\\\\n**Key results**:\\\\n- NER: EM AUROC 0.749, voting_conf ρ=0.379, SJ ρ=0.360 — all >> logprob (AUROC 0.578, ρ=0.205). 3-seed consistent: SJ > FK delta=0.093~0.122\\\\n- RE (3-seed confirmed): **LP > SJ > FK** (mean ρ: LP 0.302, SJ 0.265, FK 0.254). Signal ranking reverses vs NER — structural signals lose advantage when 43-45% of RE samples have F1=0 (binary signal dominance). LP's coarse but stable generation-confidence signal captures \\\\\\\"did the model get any relations right\\\\\\\" better than structural overlap measures.\\\\n- Difficulty-dependent signal ranking: WNUT-17 conditional collapse (ρ significant → n.s.) + logprob ρ=−0.410 (non-obvious: overconfidence on OOD)\\\\n- Temperature robustness: SJ Δρ=±0.01 vs FK Δρ=±0.06-0.09. T=0.7: LP full ρ improves 0.205→0.249, LP cond ρ 0.154→0.185; FK 0.267→0.289 despite more compression → concentrated signal hypothesis (non-tied instances at lower T carry more informative variance). **Paper citation rule**: robustness/temperature tables use full ρ; score compression analysis uses cond ρ. Always annotate which variant.\\\\n- **Task-dependent signal effectiveness** (new finding from RE 3-seed): The optimal signal family depends on task structure. NER (token-level, graded F1) → structural agreement captures quality gradients. RE (relation-level, binary-dominated F1) → logprob captures generation confidence better. This is NOT a weakness — it's a nuanced finding that enriches the diagnostic framework.\\\\n\\\\n**Evidence preserved from original Claim 1** (SciERC, N=8, T=1.0, exp_012_rerun_1024):\\\\n- NER full (n=529): ρ — voting_conf 0.379, SJ 0.360, EM 0.295, FK 0.267, logprob 0.205; AUROC — EM 0.749, SJ 0.692, voting_conf 0.684, FK 0.629, logprob 0.578\\\\n- RE full (n=397): AUROC — EM 0.706, voting_conf 0.694, SJ 0.670, FK 0.609, logprob 0.601\\\\n- ECE (NER): EM 0.353, voting 0.381, SJ 0.453, FK 0.451, logprob 0.706\\\\n\\\\n### Claim 2b (Selection evidence)\\\\n**exp_016_rerun_1024 evidence** (SciERC 8B, N=8, T=1.0):\\\\n- NER best-of-N (n=529): logprob 0.6501 > sj 0.6450 = ensemble 0.6450 > greedy 0.6439 > voting 0.6337 > random 0.6077 (oracle 0.7758)\\\\n- RE best-of-N (n=397): greedy 0.4042 > logprob 0.3948 > sj 0.3855 = ensemble 0.3855 > voting 0.3592 > random 0.3544 (oracle 0.5850)\\\\n\\\\n**4B selection evidence** (N=8, T=1.0):\\\\n- CoNLL NER 4B (n=2756): greedy 0.9213, SJ 0.9220 (+0.07pp), FK 0.9215, LP 0.9221 (+0.09pp), oracle 0.9382. Headroom 1.70pp → selection indistinguishable\\\\n- SciERC NER 4B (n=529): greedy 0.6622, SJ 0.6473 (-1.49pp), FK 0.6466 (-1.56pp), LP 0.6399 (-2.23pp), oracle 0.7925 (+13.02pp). **All signals worse than greedy** → correlation-selection gap at 4B confirmed\\\\n\\\\n**exp_016_rerun_1024_bootstrap evidence** (3-seed bootstrap, 1000 iterations):\\\\n- NER logprob vs greedy: bootstrap 95% CI [−0.030, +0.042], permutation p=0.39\\\\n- Effect size: Cohen's d=0.038 (negligible), sign test win rate=0.466\\\\n\\\\n### Claim 3 (Diagnostic — task-complexity boundary + task-dependent signal effectiveness)\\\\nThe effectiveness of consistency-based confidence is governed by task structural complexity: compound error propagation in relational tasks degrades the consistency-accuracy correlation on the full instance set, but the signal remains valid within the model's capability range. This boundary applies across all confidence signals tested.\\\\n\\\\n**RE 3-seed mechanism** (D073, confirmed at 4B): 43-47% of RE samples have F1=0 (8B: 43-45%, 4B: 47.6%), creating binary-dominated signal distributions where structural overlap (SJ/FK) cannot differentiate quality gradients. Pattern consistent across model scales — confirming task difficulty, not model capacity, drives this boundary. LP's generation confidence captures \\\\\\\"complete failure vs partial success\\\\\\\" more reliably. 3-seed RE QE: LP ρ=0.302 > SJ 0.265 > FK 0.254. **Definitive binary dominance evidence**: RE LP full ρ=0.266 but cond ρ=0.011 (p=0.86, completely n.s.) — LP's entire RE signal comes from the zero/nonzero F1 split; once conditioned on samples where the model extracts at least one relation, LP has zero predictive power for RE quality gradients. In contrast, NER LP cond ρ remains informative (0.154–0.185). This provides the concrete mechanism for Claim 3's task-complexity boundary: it's not just \\\\\\\"compound error\\\\\\\" in the abstract — it's specifically the high zero-F1 rate that shifts the optimal signal family from structural to probabilistic, and LP's RE advantage is entirely a binary classification effect, not genuine quality estimation.\\\\n\\\\n**MVP evidence**: RE full vs cond AUROC lift — EM: 0.706→0.752 (+4.6pp), SJ: 0.670→0.646 (−2.4pp, 待确认), voting_conf: 0.694→0.642 (−5.2pp, 待确认). Component decomposition shows all RE components equally weak (head_sj rho=0.210). T=0.7 naturally separates knowledge-gap vs uncertainty errors.\\\\n\\\\n**exp-005 evidence**: Conditional filtering dwarfs temperature tuning — RE SJ cond lift +0.07~0.14 vs temperature effect ±0.01. T=1.0 preserves more oracle headroom (RE: 0.167 vs 0.131) and diversity (1-SJ: 0.389 vs 0.313). Recommendation: T=1.0 + conditional filtering, not temperature optimization.\\\\n\\\\n**exp-001 N-scaling evidence** (SciERC, n=200 subset, ⚠️ needs full-set confirmation):\\\\n- RE N=16: voting_conf ρ=0.448 (vs N=8 0.340, +0.108), SJ ρ=0.333 (vs 0.244, +0.089), all signals improve +0.07~0.10\\\\n- NER N=16: flat (already saturated at N=8) — voting_conf 0.401 vs 0.392\\\\n- **Key insight**: The task-complexity boundary is partially a SAMPLE BUDGET boundary. Compound error propagation increases per-instance variance, requiring more samples (N=16 vs N=8) to average out noise. This makes Claim 2 more nuanced: RE consistency fails at N=8 not because the signal is absent, but because it's noisier and needs more samples to manifest.\\\\n- ⚠️ Caveat: exp-001 ran on 200/529 instances. Full-set replication needed before claiming in paper.\\\\n\\\\n### Claim 4 (D154: Empirical Characterization of Selection Boundaries)\\\\n**Contribution C (Selection Boundary Characterization)**: Empirical analysis of when and why LP selection succeeds or fails, with DGS as exploratory heuristic (not validated framework).\\\\n- **Core finding (D154)**: Selection viability depends on LP signal quality (within-instance ρ(LP,F1)) and dataset characteristics. Cross-dataset degeneracy-LP correlation is ρ=0.052 (23 points, p=0.81) — degeneracy alone does not predict selection direction. Within fixed settings, degeneracy causally modulates LP effectiveness (epoch ablation, temperature ablation, per-entity-type analysis).\\\\n- **DGS as explored heuristic** (demoted from \\\\\\\"validated framework\\\\\\\"): Mixed results across dataset×model:\\\\n  - Few-NERD Qwen: +0.92pp (significant) — strong LP alignment (ρ~0.5)\\\\n  - SciERC Qwen: +0.71pp (not significant) — weak alignment (ρ~0.2)\\\\n  - CoNLL Qwen: -0.81pp (significant negative) — high degen + weak alignment\\\\n  - CoNLL LLaMA: +0.14pp (significant positive) — LP-quality alignment adequate\\\\n  - Cross-model sign reversal on CoNLL illustrates LP alignment's role, but DGS does not constitute a reliable prescriptive method\\\\n- **MBR**: Uniformly negative, excluded. Exception: SciERC T=1.2 +1.8pp under high-diversity conditions.\\\\n- **Status**: D154 reframing complete. DGS is ablation evidence, not core contribution.\\\\n\\\\n## Story Spine (D157 — Triple Contribution: QE + Diagnostic + Prescriptive, Main Conference)\\\\n\\\\n**Problem**: Test-time scaling via multi-sample generation improves LLM reasoning, but its effectiveness for structured information extraction is unclear. Practitioners need to know: (1) can confidence signals estimate output quality? (2) can they select better outputs? (3) if not, what SHOULD they do instead?\\\\n\\\\n**Existing approaches & gaps**: Self-consistency (Wang et al. 2023) succeeds for discrete-answer reasoning via majority vote on discrete answers. MBR decoding succeeds for MT. But structured IE outputs (entity sets, relation triples) present a fundamentally different challenge — prior work applies instance-level selection (pick one of N complete outputs), which is the wrong analogy for set-structured outputs. We show the correct analogy is entity-level construction (aggregate across outputs).\\\\n\\\\n**Our framing (D157 — TRIPLE CONTRIBUTION)**:\\\\n\\\\n**Contribution A (Positive — QE Framework)**: Five confidence signals across four families reliably predict structured IE output quality (AUROC 0.82, ρ 0.45). Signal ranking is task-dependent: structural > probabilistic for NER, reversed for RE. QE enables selective prediction: filtering 20% low-confidence instances yields +5-8pp F1 gain (AUPRC 0.70-0.92, VC strongest signal).\\\\n\\\\n**Contribution B (Diagnostic — Why Instance-Level Selection Fails)**:\\\\n1. **Design property**: 4/5 signals are instance-level aggregates → cannot rank candidates by construction.\\\\n2. **Instance Degeneracy**: 21-58% of instances produce identical F1 across all N samples, eliminating selection headroom.\\\\n3. **LP Compression**: Logprob within-instance range compressed (0.041 nats). Free-form ablation confirms intrinsic (std ratio 0.97).\\\\n4. **Multi-causal**: LoRA rank=8 reduces degeneracy 3× (7.2% vs 21%) and increases oracle headroom (+2.7pp), but ALL selection methods still fail to beat greedy → low degeneracy is NECESSARY but NOT SUFFICIENT.\\\\n5. **Capability-diversity tension**: Higher capability → more convergence → more degeneracy. CoNLL 91% F1→58% degen, SciERC 66%→21%.\\\\n6. **LP alignment as primary predictor**: LP selection viability depends on within-instance ρ(LP,F1). Few-NERD (ρ~0.5-0.7) → LP +1.38pp (p<0.05). SciERC (ρ~0.2) → LP fails despite similar degeneracy. Cross-dataset degeneracy ρ=0.052 (23 configs, p=0.81).\\\\n\\\\n**Contribution C (Prescriptive — Entity-Level Construction + Practitioner Protocol, D157)**:\\\\nThe correct self-consistency analogy for structured IE is NOT instance-level selection but entity-level construction: aggregate entities across N samples via majority vote, constructing a new output from parts.\\\\n- **Entity construction (multi-seed N=8 mean)**: SciERC +1.02pp, FewNERD +1.40pp, CoNLL +0.10pp (n.s.). Mechanism: recall gain by aggregating low-frequency correct entities across samples.\\\\n- **72B zero-shot construction**: LP-weighted construction SciERC ZS +1.53pp (stronger than fine-tuned!), CoNLL ZS -0.37pp (headroom-limited). **θ=2/N fails in zero-shot** (SciERC -0.52pp, CoNLL -0.92pp) → LP-weighting is necessary in zero-shot regime.\\\\n- **Construction effectiveness is headroom-dependent**: Works when oracle headroom is sufficient (SciERC 15pp → +1.53pp), fails when near ceiling (CoNLL 5.3pp → -0.37pp). This is consistent across fine-tuned and zero-shot regimes.\\\\n- **LP-alignment gating (preliminary diagnostic)**: Probe 50 instances on validation set to compute adjusted alignment score → automatically select construction vs LP selection. 3/3 datasets correct gating. Bootstrap CI: τ=0.3 at center of [0.25, 0.35] stable plateau, routing decisions stable across τ∈[0.2, 0.4] (stability ≥95%).\\\\n- **Selective prediction**: QE-driven human-in-the-loop — retain 80% high-confidence instances, F1 +5-8pp. VC is strongest signal across all datasets.\\\\n\\\\n**QE-vs-Selection Decoupling** (Dream-identified most novel insight): QE correlation (SJ ρ) is stable across LoRA rank configurations (0.360→0.378) while selection gap changes dramatically. Signals are ALWAYS useful for flagging uncertain instances, even when they cannot improve selection.\\\\n\\\\n**Headline**: \\\\\\\"We present a triple contribution for structured IE test-time scaling: (1) a QE framework showing confidence signals reliably predict output quality and enable selective prediction (+5-8pp @80% coverage); (2) a diagnostic revealing that the correlation-selection gap is fundamental — persisting from 4B to 72B and from fine-tuned to zero-shot regimes — driven by degeneracy, LP compression, and LP-alignment misalignment; and (3) entity-level construction as a diagnostic-motivated mitigation that significantly improves over greedy decoding (+1.02pp SciERC, +1.40pp FewNERD fine-tuned; +1.53pp SciERC zero-shot via LP-weighting), with effectiveness governed by oracle headroom.\\\\\\\"\\\\n\\\\n**Title candidates**:\\\\n- \\\\\\\"Don't Select, Construct: Diagnosing and Fixing Test-Time Scaling for Structured Information Extraction\\\\\\\"\\\\n- \\\\\\\"Strong Predictors, Weak Selectors: From Diagnosis to Entity-Level Construction for Structured IE\\\\\\\"\\\\n- \\\\\\\"Beyond Selection: Entity-Level Construction as the Correct Self-Consistency for Structured IE\\\\\\\"\\\\n\\\\n## Anticipated Reviewer Concerns\\\\n\\\\n### R1: \\\\\\\"Only one NER dataset — generalization unclear\\\\\\\"\\\\n- **Status**: ✅ RESOLVED. 3 NER datasets (SciERC + CoNLL-2003 + Few-NERD INTRA) × 2 models (Qwen3-8B + LLaMA-3.1-8B) + scale ablation (Qwen3-4B). Few-NERD adds 32,565 instances with distinct degeneracy profile (10% vs 21-58%). Cross-dataset comparison revealing LP alignment as primary selection predictor (D154) is the paper's strongest empirical contribution.\\\\n- **Priority**: P0, RESOLVED\\\\n\\\\n### R2: \\\\\\\"Only one model family (Qwen3-8B)\\\\\\\"\\\\n- **Mitigation**: LLaMA-3.1-8B shows model-agnostic effect. ⚠️ **exp-007 数据被污染 (test data leakage)**，LLaMA SciERC 正确值来自 exp_018 (clean rerun)。unified_rho_full.json 的 LLaMA SciERC 条目必须替换为 exp_018 数据。正确 LLaMA SciERC N=8 3-seed mean: SJ 0.325, FK 0.256, VC 0.384, EM 0.279, LP 0.162。\\\\n- **Priority**: P0\\\\n\\\\n### R3: \\\\\\\"FK is a strawman baseline — what about log-prob, USC, exact-match?\\\\\\\"\\\\n- **Mitigation**: exp-012 (log-prob), exp-013 (exact-match), exp-014 (entity voting) provide comprehensive baseline comparison. Results: structural consistency family (EM+SJ+voting) >> log-prob >> FK. USC discussed in related work (LLM-as-judge, orthogonal approach).\\\\n- **Priority**: P0, RESOLVED — results decisive\\\\n\\\\n### R3b: \\\\\\\"EM beats voting_conf and SJ on AUROC — why present SJ/voting_conf?\\\\\\\"\\\\n- **Mitigation**: EM is a strict binary signal (all-or-nothing match); SJ captures partial agreement and generalizes to arbitrary structured outputs (relations, events). Voting_conf provides granular entity-level scores. NER full AUROC: EM 0.749 > SJ 0.692 > voting_conf 0.684, but ρ: voting_conf 0.379 > SJ 0.360 > EM 0.295. EM excels at binary discrimination but underperforms on rank ordering. SJ is also more temperature-robust (Δρ=±0.01). Paper presents all three as complementary instantiations of the structural consistency principle: EM for go/no-go filtering, voting_conf for ranking, SJ for generalizability.\\\\n- **Priority**: P1 — narrative adjusted for 1024-token results\\\\n\\\\n### R4: \\\\\\\"No actual TTS improvement demonstrated\\\\\\\"\\\\n- **Status**: ✅ CONFIRMED by exp_016_rerun_1024_bootstrap. No signal significantly outperforms greedy on either task. NER logprob +0.6pp not significant (bootstrap p=0.39, 95% CI [−0.030, +0.042], Cohen's d=0.038). RE: greedy > all signals.\\\\n- **Mitigation**: Paper PIVOTS to \\\\\\\"confidence estimation + correlation-selection gap analysis.\\\\\\\" exp-006 redesigned as diagnostic: show selection curves to visualize the gap (F1 vs N per signal + oracle ceiling). The gap itself is a contribution, not a failure.\\\\n- **Priority**: P0 — narrative pivot complete, bootstrap confirms\\\\n\\\\n### R5: \\\\\\\"Sample size N=8 may be too small for reliable SJ estimation\\\\\\\"\\\\n- **Mitigation**: exp-001 (N=16) with multi-seed robustness\\\\n- **Priority**: P0\\\\n\\\\n### R6: \\\\\\\"Conditional analysis cherry-picks favorable instances\\\\\\\"\\\\n- **Mitigation**: Principled separation (knowledge-gap vs uncertainty). Add threshold sensitivity analysis. Temperature analysis provides independent validation.\\\\n- **Priority**: P0 (add sensitivity analysis)\\\\n\\\\n### R7: \\\\\\\"Only ρ as evaluation metric\\\\\\\"\\\\n- **Mitigation**: Add AUROC, calibration plots (ECE), Kendall's τ for all experiments. ECE data now available: NER best calibrated = EM (0.353), RE best = voting (0.272). Logprob worst calibrated (NER 0.706, RE 0.769).\\\\n- **Priority**: P0\\\\n\\\\n### R8: \\\\\\\"Formula-implementation discrepancy\\\\\\\"\\\\n- **Mitigation**: Paper must describe actual algorithm (type-grouped Hungarian matching with max(|g_a|,|g_b|) denominator)\\\\n- **Priority**: P0, paper writing fix\\\\n\\\\n### R9: \\\\\\\"Evaluation circularity (T>0 consistency vs T=0 F1)\\\\\\\"\\\\n- **Mitigation**: Add leave-one-out SJ evaluation as robustness check. Justify cross-mode design (greedy = deterministic reference, standard in TTS literature).\\\\n- **Priority**: P0\\\\n\\\\n### R10: \\\\\\\"Insufficient related work\\\\\\\" (三档一致 [B][M][W])\\\\n- **Mitigation**: Expand to 35+ references. Must cite:\\\\n  - USC (Chen 2024) — empirical differentiation, not just citation\\\\n  - Semantic uncertainty (Kuhn 2023), calibration (Kadavath 2022, Guo 2017, Desai & Durrett 2020)\\\\n  - **Conformal prediction for structured outputs**: Fisch et al. 2021, Angelopoulos et al. 2021, Bates et al. 2021\\\\n  - **Token-level NER uncertainty**: Xiao & Wang 2019, Shelmanov et al. 2021, He et al. 2020\\\\n  - **Ensemble/MC-dropout**: Lakshminarayanan et al. 2017, Gal & Ghahramani 2016\\\\n  - **Verifier/reward models**: Cobbe et al. 2021, Lightman et al. 2023\\\\n  - **TTS scaling theory**: Snell et al. 2024, Brown et al. 2024\\\\n  - **Structured calibration**: Kuleshov & Liang 2015, Jagannatha & Yu 2022\\\\n  - **IE confidence**: Culotta & McCallum 2004\\\\n  - SelfCheckGPT (Manakul 2023), selective prediction (Geifman & El-Yaniv 2017)\\\\n  - **[2025-2026 新颖性自查补充 — 必引]**:\\\\n    - CISC (ACL Findings 2025) — confidence-weighted majority vote for reasoning; 对比：我们用 structural similarity 而非 confidence 加权，且面向 set-structured IE 输出\\\\n    - Self-Certainty Best-of-N (ICLR 2026, arxiv 2502.18581) — KL-divergence reward-free selection; 对比：我们发现 log-prob 是唯一有效 selection signal (与其方向互补)，且揭示 correlation-selection gap\\\\n    - ReASC (2026, arxiv 2601.02970) — reliability-aware adaptive self-consistency; 对比：仍限于 reasoning 离散答案\\\\n    - Atomic Self-Consistency (EMNLP 2024) — 子声明级一致性 for long-form text; 对比：我们在 entity-set 级别做结构化度量\\\\n    - **Nédellec & Xia (Genomics Informatics, 2026-02, PMC12888769)** — \\\\\\\"Consistency–accuracy correlation in hard-prompted LLMs for entity and relation extraction\\\\\\\"。最直接竞争者：4 LLMs 在植物健康 NER/RE 上研究 consistency-accuracy 相关性。**关键差异**：(a) 他们用 surface-level string matching，自承\\\\\\\"overlooks semantically consistent outputs\\\\\\\"，我们的 SJ 正好解决此问题; (b) 不研究 best-of-N selection; (c) 单领域 hard-prompted (T=0); (d) 无多信号家族对比。论文 Intro 可引用其 limitation 作为 SJ 的动机\\\\n  - **[2025-2026 新颖性自查补充 — 应引]**:\\\\n    - UQ for LLMs Survey (ACL Findings 2025) — 最全面 LLM 不确定性综述\\\\n    - UQ+Calibration Survey (arxiv 2503.15850, 2025) — 第二篇综合综述\\\\n    - Semantic Entropy Probes (2024) — 低成本不确定性估计\\\\n    - Latent Self-Consistency (2025, arxiv 2508.18395) — embedding 空间一致性\\\\n    - Ranked Voting SC (2025, arxiv 2505.10772) — 排名投票变体，仍限于推理任务\\\\n    - Know Your Limits: Abstention Survey (TACL 2025) — 选择性预测综述，与 Claim 1 selective prediction 角度直接相关\\\\n    - Confidence Estimation Survey (NAACL 2024, arxiv 2311.08298) — LLM 置信度估计全景定位\\\\n    - **CoCoA (Vashurin et al., NeurIPS 2025, arxiv 2502.04964)** — MBR 框架融合 confidence+consistency 做 UQ，在 QA/摘要/翻译上评估。与我们 exp-016 ensemble (SJ+logprob) 对标，但未涉及 structured IE\\\\n    - **Vashurin et al. (arxiv 2510.20460, 2025)** — VCE/MSP/Sample Consistency/CoCoA 四方法系统评估，任务不含 structured IE\\\\n  - **需新增 Related Work 小节**:\\\\n    - \\\\\\\"Test-Time Scaling & Sample Selection\\\\\\\" — 将 CISC/Self-Certainty/ReASC 集中讨论，明确 positioning：现有工作均面向 reasoning/QA 的离散答案，我们首次在 structured IE 上做系统信号对比并发现 correlation-selection gap\\\\n    - \\\\\\\"Consistency for Structured IE\\\\\\\" — 引 Nédellec & Xia 2026 作为同期工作，显式对比：surface matching vs structural metrics (SJ)；他们的 limitation 是我们的 motivation\\\\n- **Priority**: P0, Paper Agent handles\\\\n\\\\n### R11: \\\\\\\"SJ+logprob ensemble missing\\\\\\\" (Dream 2 — both reviewers)\\\\n- **Status**: ⚠️ REVISED by exp_016_rerun_1024. Results:\\\\n  - Ensemble AUROC (5-fold CV LR): NER 0.666 ± 0.070, RE 0.662 ± 0.078\\\\n  - Best single signal EM: NER AUROC 0.749, RE AUROC 0.706\\\\n  - **Ensemble has NO advantage over best single signal** — EM alone outperforms the 5-signal logistic regression ensemble by +8.3pp (NER) and +4.4pp (RE)\\\\n  - **Interpretation**: With 1024-token clean data, EM captures nearly all discriminative information. The ensemble's inferior performance likely reflects overfitting in the 5-fold CV LR with correlated features. This further supports presenting EM as a simple, strong baseline within the structural consistency family.\\\\n- **Priority**: DONE — write into paper with honest interpretation (no ensemble advantage claim)\\\\n\\\\n### R12: \\\\\\\"No supervised upper bound / reward model comparison\\\\\\\" (Dream 2)\\\\n- **Mitigation**: exp-016 LR ensemble (5-signal, 5-fold CV) underperforms best single signal EM (AUROC 0.666 vs 0.749), suggesting feature redundancy. exp-019 supervised verifier SKIPPED (DDL risk + scope creep). Free-form ablation provides the \\\\\\\"so what\\\\\\\": gap is fundamental → closing it requires fundamentally different approaches (trained verifiers, not just better unsupervised signals). Positioned as future work with explicit motivation from ablation evidence.\\\\n- **Priority**: P1, addressed via framing (future work motivated by ablation)\\\\n\\\\n### R13: \\\\\\\"Headroom capture rate low\\\\\\\" (Dream 2)\\\\n- **Mitigation**: NER oracle 0.7758, greedy 0.6439, best signal (logprob) 0.6501 → captures 0.5% of headroom. RE oracle 0.5850, greedy 0.4042, best signal (greedy itself) → 0% capture. Discuss explicitly in paper. Contextualize vs other unsupervised TTS methods. Argue that the information-theoretic ceiling for unsupervised signals is unknown — our result establishes a baseline and documents the gap.\\\\n- **Priority**: P0, paper writing\\\\n\\\\n### R14: \\\\\\\"Cross-model validation thin — need more than 2×8B\\\\\\\" (Dream 2)\\\\n- **Status**: ✅ RESOLVED by 4B scale ablation. 2×2 matrix: {CoNLL, SciERC} × {Qwen3-8B, Qwen3-4B}. All correlation metrics maintained or improved at 4B (e.g. SciERC NER SJ_ρ: 0.3825→0.4221, +3.96pp). Combined with LLaMA-3.1-8B cross-architecture data, now have 3 model configurations (Qwen3-8B, Qwen3-4B, LLaMA-3.1-8B). 70B infeasible — acknowledge as limitation.\\\\n- **Priority**: P0, RESOLVED\\\\n\\\\n### R15: \\\\\\\"Log-prob definition ambiguity — Eq.1 vs best-of-N ranking\\\\\\\" (Dream 2 cross-tier, [W])\\\\n- **Mitigation**: Paper must clarify: log-prob ranks among N candidates (each sample's generation log-prob), not just score greedy output. Cost comparison table must state \\\\\\\"all best-of-N require N forward passes; log-prob adds zero ranking overhead.\\\\\\\"\\\\n- **Priority**: P0, Paper Agent handles\\\\n\\\\n### R16: \\\\\\\"Zero figures — data-rich paper with only tables\\\\\\\" (Dream 2 cross-tier, [W])\\\\n- **Mitigation**: Paper Agent must include ≥3 figures: (1) selection curves (F1 vs N for each signal + oracle), (2) reliability diagram (calibration), (3) N-scaling or cost-effectiveness scatter. Data exists from exp-010/015.\\\\n- **Priority**: P0, Paper Agent handles\\\\n\\\\n### R17: \\\\\\\"Diagnostic framework overclaimed — descriptive not prescriptive\\\\\\\" (Dream 2 cross-tier, [M][W])\\\\n- **Mitigation**: Soften \\\\\\\"diagnostic framework\\\\\\\" to \\\\\\\"diagnostic analysis\\\\\\\" throughout. Current taxonomy (ceiling/floor/compound error) is descriptive. Either formalize with a priori metrics or reframe as empirical analysis.\\\\n- **Priority**: P0, Paper Agent handles\\\\n\\\\n### R18: \\\\\\\"No discussion of when consistency WOULD help\\\\\\\" (Dream 2 cross-tier, [W])\\\\n- **Mitigation**: Add discussion paragraph: consistency should outperform log-prob when (a) model calibration is poor (in-context learning without fine-tuning), (b) log-prob unavailable (closed-source APIs), (c) ensemble/mixture settings, (d) tasks where model is systematically overconfident.\\\\n- **Priority**: P1, Paper Agent handles\\\\n\\\\n### R19: \\\\\\\"Negative result partially predictable for fine-tuned models\\\\\\\" (Dream 2 cross-tier, [W])\\\\n- **Mitigation**: Paper must argue non-obviousness: (a) self-consistency demonstrably helps for reasoning tasks (Wang et al. 2023), (b) structured prediction has internal structure that surface metrics can't capture, (c) the DEGREE of log-prob's strength and the task-complexity boundary are not predictable a priori.\\\\n- **Priority**: P1, Paper Agent handles\\\\n\\\\n## Venue Fit\\\\n\\\\nEMNLP **Main Conference** target. Strengths:\\\\n- Systematic empirical comparison with mechanistic diagnosis (not just \\\\\\\"signals don't work\\\\\\\" but \\\\\\\"here's exactly why\\\\\\\")\\\\n- Two novel failure mechanisms (instance degeneracy + LP compression) + unifying capability-diversity tension\\\\n- Controlled ablation (free-form decoding) providing causal evidence\\\\n- Cross-model (Qwen3-8B/4B + LLaMA-3.1-8B), cross-dataset (SciERC + CoNLL + WNUT), cross-task (NER + RE) validation\\\\n\\\\nMain Conference gap vs Findings:\\\\n- ✅ 3rd NER dataset (Few-NERD) — DONE, confirms LP alignment as primary predictor\\\\n- ✅ LoRA rank=8 ablation — DONE, multi-causal confirmed\\\\n- ✅ Bootstrap significance — DONE, LP p<0.05 on Few-NERD\\\\n- ✅ Numerical audit — DONE, all corrections applied\\\\n- **Remaining**: Dream #3 validation (target ≥3.5), final editorial pass\\\\n\\\\nRisk assessment:\\\\n- **Strongest asset**: LP alignment as primary selection predictor + within-dataset causal evidence (epoch/temperature ablation) — honest empirical characterization with actionable implications\\\\n- **Second strongest**: QE-vs-selection decoupling (signals always useful for QE even when selection fails)\\\\n- **Weakest flank**: D154 removed \\\\\\\"monotonic gradient\\\\\\\" claim, but the within/cross distinction is more nuanced and honest — reviewers should appreciate this\\\\n- **Critical path**: Dream #3 → final submission to Review Director → DDL 2026-05-25\\\", \\\"total_chars\\\": 35571, \\\"truncated\\\": false}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/paper_framing.md\", \"content\": \"# Paper Framing — struct_self_consist_ie\\n\\n> Updated 2026-05-19 — D157+D160 TRIPLE CONTRIBUTION + SCALE UPGRADE. Title: \\\"Strong Predictors, Weak Selectors: Addressing the Correlation-Selection Gap in Self-Consistency for Named Entity Recognition\\\". Entity construction θ=2/N (+1.02pp SciERC, +1.40pp FewNERD, multi-seed N=8 mean). **72B zero-shot confirms gap is fundamental**: LP ρ=-0.002 (CoNLL) / 0.081 (SciERC); LP-weighted construction +1.53pp (SciERC ZS); θ=2/N fails in zero-shot (-0.52pp SciERC, -0.92pp CoNLL). Gating bootstrap CI: τ=0.3 stable in [0.2,0.4]. D162: Decomposition formula deleted (R²=-8.53). Scale: 7B→14B→32B→72B Qwen2.5 + 8B cross-family (Qwen3+LLaMA). 14B/32B training in progress.\\n\\n## Target Venue\\n- Primary: EMNLP 2026 **Main Conference** (via ARR May 2026)\\n- Deadline: ARR May cycle, 2026-05-25\\n\\n## Core Claims (D157 updated — TRIPLE CONTRIBUTION: QE + diagnostic + prescriptive)\\n\\n### Claim 1 (PRIMARY — Dual Contribution: QE Framework + Selection Diagnostic)\\n**Positive contribution (A)**: Confidence signals reliably predict structured IE output quality at the population level (AUROC up to 0.82, ρ up to 0.45), enabling practical QE/selective prediction.\\n**Diagnostic contribution (B)** (D154 revised): Selection viability depends on LP signal quality and dataset characteristics, not degeneracy alone:\\n- **Degeneracy as headroom predictor**: High degeneracy eliminates selection headroom (CoNLL 47.4% degen → 0 net gain). Within fixed dataset-model settings, degeneracy causally modulates LP effectiveness (SciERC epoch ablation: −1.18/+0.74/+0.99pp at 3/5/10 epochs; per-entity-type within Few-NERD ρ=−0.881). But across datasets, degeneracy alone does NOT predict LP selection direction (23-point cross-configuration ρ=0.052, p=0.81).\\n- **LP-quality alignment as primary predictor**: LP must track entity-level F1 within instances. Few-NERD within-instance ρ(LP,F1) ≈ 0.5-0.66 → LP selection +1.36pp (p<0.05). SciERC ρ(LP,F1) ≈ 0.18-0.24 → LP fails despite similar degeneracy (17.8% vs 13.8%). This is the primary determinant of LP selection success across datasets.\\n- **Structural signals (SJ/FK/EM/VC)**: universally fail regardless — instance-level aggregates cannot rank candidates by construction.\\n- **Multi-causal diagnosis (D154)**: (1) degeneracy modulates headroom within settings; (2) LP-quality alignment determines cross-dataset selection success; (3) LoRA rank=8 reduces degeneracy (7.2% vs 17.8%) AND improves LP spread (0.057 vs 0.041 nats) but SciERC's weak LP-F1 alignment (ρ~0.24) still prevents selection success → LP alignment is the binding constraint, degeneracy is a within-setting modulator.\\n\\nThe framing is NOT \\\"selection fails\\\" (pure negative) but \\\"we characterize WHEN LP works (strong LP-F1 alignment), WHY it fails elsewhere (weak alignment + compression), and WHAT distinguishes LP from structural signals\\\" (empirical characterization with diagnostic implications).\\n\\n**Three-layer argument + Capability-diversity tension**:\\n- Layer A (design property, noted not discovered): 4/5 signals are instance-level aggregates → cannot rank candidates by construction. This is a conceptual clarification — the \\\"methodological premise\\\" — not an empirical finding.\\n- Layer B (empirical — instance degeneracy): 21-58% of instances produce identical F1 across all N samples, eliminating selection headroom. Within-instance ρ=0.524 (SciERC) and 0.994 (CoNLL) — signals ARE correlated within instances, but degeneracy makes this irrelevant. Non-degenerate instances show MBR closing 23-41% of oracle gap. Selection recovers T=1.0 sampling degradation (LP 0.647 vs Random 0.610, +3.7pp) but only matches T=0 greedy (0.645 macro) at 8× inference cost — zero marginal gain.\\n- Layer C (empirical — LP-quality alignment, revised D123): LP selection requires adequate within-instance correlation with task quality. Few-NERD ρ(LP,F1)≈0.5-0.66 → selection succeeds (+1.36pp). SciERC ρ(LP,F1)≈0.18-0.24 → selection fails even when LP range is adequate (rank=8: 0.057 nats). LP compression (median range 0.041 nats on SciERC full-rank) is a contributing factor but NOT the sole explanation — rank=8 expands LP range to 0.057 yet still fails. Entity-token LP shows 4× variance but WORSE selection (-2.0pp). Free-form ablation confirms compression is model/task intrinsic for NER (std ratio 0.97).\\n- **Capability-diversity tension** (unifying insight, D111): Model capability → output convergence → instance degeneracy → vanishing selection headroom. Evidence: CoNLL (91% F1) → 58% degeneracy, SciERC (66% F1) → 21%, WNUT (48% F1) → ~0%. Scale dimension: 8B → 21% degen vs 4B → 10.4% on SciERC. This is NOT an \\\"artifact\\\" — it is a **consequence of capability**, a structural inevitability. The better the model, the less test-time scaling can help via unsupervised selection.\\n\\n**Distinction from MBR literature**: Eikema et al.'s MBR failure = utility function misalignment. Our failure = utility IS aligned (within-instance ρ=0.524) but headroom eliminated by degeneracy — qualitatively novel mechanism.\\n\\n**Key evidence (score compression)**:\\n- Non-tied subset (40%): logprob selection +2.9pp vs greedy (p=0.01), within-instance ρ: 0.08→0.39\\n- Full set: logprob +0.6pp, bootstrap p=0.39, Cohen's d=0.038 (negligible), 95% CI [-3.0, +4.2]pp\\n- Oracle headroom: NER +13pp, RE +18pp → information exists but signals can't access it\\n\\n**Key evidence (free-form ablation)** [DONE — exp_freeform_ablation, NEGATIVE]:\\n- LP distribution: constrained std=0.0206, free-form std=0.0199 (ratio 0.97, virtually unchanged)\\n- Tied fraction: 59.7% → 57.7% (-2.0pp, negligible)\\n- NER selection: +0.59pp → +0.18pp (both negligible vs greedy)\\n- RE selection: -0.68pp → +1.69pp (flipped positive — secondary finding)\\n- NER VC rho: 0.379 → 0.409 (slight QE improvement, selection still fails)\\n- Parse rate: 99.95% (fine-tuned model retains JSON format without grammar)\\n- **Conclusion**: Score compression is model/task intrinsic. The gap is universal.\\n\\n**Key evidence (scale ablation)** [DONE — 2×2 matrix: {CoNLL, SciERC} × {Qwen3-8B, Qwen3-4B}]:\\n- CoNLL NER: 4B greedy_f1=0.9234 (>8B 0.9123, +1.11pp), SJ_ρ=0.4217 (≈8B 0.4357, −1.4pp), FK_ρ=0.4181 (>8B 0.3998, +1.83pp)\\n- SciERC NER: 4B SJ_ρ=0.4221 (>8B 0.3825, +3.96pp), FK_ρ=0.3258 (>8B 0.2590, +6.68pp)\\n- SciERC RE: 4B SJ_ρ=0.2673 (>8B 0.2441, +2.32pp), FK_ρ=0.3593 (>8B 0.2782, +8.11pp); struct>surface ✗ at both scales\\n- **Conclusion**: Correlation strength maintained or improved at 4B across all 4 cells. The gap originates from within-instance signal misalignment, not model capacity. Task difficulty (SciERC RE zero-F1 rate) remains the primary driver, consistent across scales.\\n- CoNLL 4B headroom: 1.70pp (vs 8B 4.20pp) → MARGINAL for selection power, but QE correlations robust\\n- SciERC RE 4B: 47.6% zero-F1, RE LP_ρ_cond=0.1135 (p=0.074, n.s.) → confirms binary dominance at 4B\\n- **4B selection results** (correlation-selection gap at 4B):\\n  - CoNLL NER 4B (n=2756): SJ +0.07pp, FK +0.03pp, LP +0.09pp vs greedy 0.9213. All ≤0.1pp — MARGINAL (headroom 1.70pp)\\n  - SciERC NER 4B (n=529): SJ **-1.49pp**, FK -1.56pp, LP -2.23pp vs greedy 0.6622. Oracle 0.7925 (+13.02pp). **All signals WORSE than greedy despite 13pp oracle headroom — gap confirmed at 4B**\\n  - SciERC NER 4B gap demonstration: SJ-FK ρ gap = +0.096 (strong correlation advantage), SJ-FK selection F1 gap = +0.0007 (zero selection advantage) → correlation-selection gap quantified at 4B\\n- **n_samples confound control**: Qwen3-8B n=8 data exists as control. CoNLL SJ: n8 ρ=0.4389 → n16 ρ=0.4496 (Δ=0.011, CI crosses zero). SciERC SJ: n8→n16 Δ=0.066, CI=[0.004, 0.128] weak effect. n_samples not a confound for 4B-8B comparison.\\n- **Paper framing**: \\\"Scale ablation shows the gap is not an artifact of a particular model size; correlation strength is maintained at 4B, confirming that the gap originates from within-instance signal misalignment rather than model capacity.\\\"\\n\\n**exp-019 supervised verifier**: IN PROGRESS (D116 Dream feedback — all 3 tiers flagged as critical gap). Simplified to logistic regression on 5 signals (scikit-learn, CPU, ~30min). If supervised verifier partially closes oracle gap → proves gap IS closable, signals carry information but unsupervised heuristics are too weak. Grounds the \\\"what would be needed\\\" part of Contribution B.\\n\\n**exp-023 LoRA rank=8 ablation** [DONE]: rank=8 vs rank=32 on SciERC. Degeneracy: 7.2% vs 21% (3× reduction). Oracle headroom: 16.0pp vs 13.3pp. But ALL selection methods still fail to beat greedy (LP -0.5pp, SJ -0.9pp). QE correlation preserved (VC ρ=0.394, SJ ρ=0.365). **Key insight**: Reducing degeneracy is NECESSARY but NOT SUFFICIENT — signals themselves lack the discriminative power to exploit increased headroom. Strengthens multi-causal argument and points to trained verifiers as the path forward. Dream 三档公认最强实验。\\n\\n**exp-021 Few-NERD Full** [DONE — Scenario B: LP works, structural fails]:\\n- Dataset: Few-NERD INTRA coarse 8-type, 131k train, 32,565 test (gold-filtered)\\n- Degeneracy: 10.0% (vs SciERC 21%, CoNLL 58%) — lowest in our study\\n- LP selection: +1.36pp vs greedy (95% CI [+1.02, +1.34], p<0.05, bootstrap B=10000). **First dataset where LP significantly improves selection.**\\n- Structural signals: SJ -0.42pp, FK -0.55pp, EM -0.31pp, VC -0.18pp — ALL fail\\n- QE correlation (unified pipeline): LP ρ=0.22 (global), SJ ρ=0.38, FK ρ=0.35 — QE preserved; within-instance LP ρ≈0.5-0.7\\n- Oracle headroom: 13.8pp — ample room for selection\\n- **Key insight**: LP succeeds where LP-F1 alignment is strong; structural signals fail regardless. Within Few-NERD, per-entity-type analysis shows ρ=−0.881 between degeneracy and LP delta (within-dataset causal effect). But cross-dataset, the gradient CoNLL→SciERC→Few-NERD does NOT monotonically predict LP effectiveness (D154: ρ=0.052 at 23 points).\\n\\n**Bonus finding (parse rate)**: Free-form parse rate 99.95% (4406/4408) — fine-tuned 8B model generates valid JSON without grammar constraints. Challenges intro:19 claim about constrained decoding necessity for format compliance.\\n\\n**Implications**: Not just \\\"signals don't work\\\" but \\\"here's WHY they don't work (intrinsic score compression), here's proof it's universal (controlled ablation via elimination), and here's the forward direction (breaking LP compression requires fundamentally different approaches — trained verifiers, multi-round refinement — not simply relaxing decoding constraints).\\\"\\n\\n### Claim 2 (METHODOLOGY — QE Evaluation Framework)\\nSystematic evaluation of 5 confidence signals across 4 families for structured IE quality estimation. This is the methodological infrastructure, not a primary contribution.\\n\\n**Key results**:\\n- NER: EM AUROC 0.749, voting_conf ρ=0.379, SJ ρ=0.360 — all >> logprob (AUROC 0.578, ρ=0.205). 3-seed consistent: SJ > FK delta=0.093~0.122\\n- RE (3-seed confirmed): **LP > SJ > FK** (mean ρ: LP 0.302, SJ 0.265, FK 0.254). Signal ranking reverses vs NER — structural signals lose advantage when 43-45% of RE samples have F1=0 (binary signal dominance). LP's coarse but stable generation-confidence signal captures \\\"did the model get any relations right\\\" better than structural overlap measures.\\n- Difficulty-dependent signal ranking: WNUT-17 conditional collapse (ρ significant → n.s.) + logprob ρ=−0.410 (non-obvious: overconfidence on OOD)\\n- Temperature robustness: SJ Δρ=±0.01 vs FK Δρ=±0.06-0.09. T=0.7: LP full ρ improves 0.205→0.249, LP cond ρ 0.154→0.185; FK 0.267→0.289 despite more compression → concentrated signal hypothesis (non-tied instances at lower T carry more informative variance). **Paper citation rule**: robustness/temperature tables use full ρ; score compression analysis uses cond ρ. Always annotate which variant.\\n- **Task-dependent signal effectiveness** (new finding from RE 3-seed): The optimal signal family depends on task structure. NER (token-level, graded F1) → structural agreement captures quality gradients. RE (relation-level, binary-dominated F1) → logprob captures generation confidence better. This is NOT a weakness — it's a nuanced finding that enriches the diagnostic framework.\\n\\n**Evidence preserved from original Claim 1** (SciERC, N=8, T=1.0, exp_012_rerun_1024):\\n- NER full (n=529): ρ — voting_conf 0.379, SJ 0.360, EM 0.295, FK 0.267, logprob 0.205; AUROC — EM 0.749, SJ 0.692, voting_conf 0.684, FK 0.629, logprob 0.578\\n- RE full (n=397): AUROC — EM 0.706, voting_conf 0.694, SJ 0.670, FK 0.609, logprob 0.601\\n- ECE (NER): EM 0.353, voting 0.381, SJ 0.453, FK 0.451, logprob 0.706\\n\\n### Claim 2b (Selection evidence)\\n**exp_016_rerun_1024 evidence** (SciERC 8B, N=8, T=1.0):\\n- NER best-of-N (n=529): logprob 0.6501 > sj 0.6450 = ensemble 0.6450 > greedy 0.6439 > voting 0.6337 > random 0.6077 (oracle 0.7758)\\n- RE best-of-N (n=397): greedy 0.4042 > logprob 0.3948 > sj 0.3855 = ensemble 0.3855 > voting 0.3592 > random 0.3544 (oracle 0.5850)\\n\\n**4B selection evidence** (N=8, T=1.0):\\n- CoNLL NER 4B (n=2756): greedy 0.9213, SJ 0.9220 (+0.07pp), FK 0.9215, LP 0.9221 (+0.09pp), oracle 0.9382. Headroom 1.70pp → selection indistinguishable\\n- SciERC NER 4B (n=529): greedy 0.6622, SJ 0.6473 (-1.49pp), FK 0.6466 (-1.56pp), LP 0.6399 (-2.23pp), oracle 0.7925 (+13.02pp). **All signals worse than greedy** → correlation-selection gap at 4B confirmed\\n\\n**exp_016_rerun_1024_bootstrap evidence** (3-seed bootstrap, 1000 iterations):\\n- NER logprob vs greedy: bootstrap 95% CI [−0.030, +0.042], permutation p=0.39\\n- Effect size: Cohen's d=0.038 (negligible), sign test win rate=0.466\\n\\n### Claim 3 (Diagnostic — task-complexity boundary + task-dependent signal effectiveness)\\nThe effectiveness of consistency-based confidence is governed by task structural complexity: compound error propagation in relational tasks degrades the consistency-accuracy correlation on the full instance set, but the signal remains valid within the model's capability range. This boundary applies across all confidence signals tested.\\n\\n**RE 3-seed mechanism** (D073, confirmed at 4B): 43-47% of RE samples have F1=0 (8B: 43-45%, 4B: 47.6%), creating binary-dominated signal distributions where structural overlap (SJ/FK) cannot differentiate quality gradients. Pattern consistent across model scales — confirming task difficulty, not model capacity, drives this boundary. LP's generation confidence captures \\\"complete failure vs partial success\\\" more reliably. 3-seed RE QE: LP ρ=0.302 > SJ 0.265 > FK 0.254. **Definitive binary dominance evidence**: RE LP full ρ=0.266 but cond ρ=0.011 (p=0.86, completely n.s.) — LP's entire RE signal comes from the zero/nonzero F1 split; once conditioned on samples where the model extracts at least one relation, LP has zero predictive power for RE quality gradients. In contrast, NER LP cond ρ remains informative (0.154–0.185). This provides the concrete mechanism for Claim 3's task-complexity boundary: it's not just \\\"compound error\\\" in the abstract — it's specifically the high zero-F1 rate that shifts the optimal signal family from structural to probabilistic, and LP's RE advantage is entirely a binary classification effect, not genuine quality estimation.\\n\\n**MVP evidence**: RE full vs cond AUROC lift — EM: 0.706→0.752 (+4.6pp), SJ: 0.670→0.646 (−2.4pp, 待确认), voting_conf: 0.694→0.642 (−5.2pp, 待确认). Component decomposition shows all RE components equally weak (head_sj rho=0.210). T=0.7 naturally separates knowledge-gap vs uncertainty errors.\\n\\n**exp-005 evidence**: Conditional filtering dwarfs temperature tuning — RE SJ cond lift +0.07~0.14 vs temperature effect ±0.01. T=1.0 preserves more oracle headroom (RE: 0.167 vs 0.131) and diversity (1-SJ: 0.389 vs 0.313). Recommendation: T=1.0 + conditional filtering, not temperature optimization.\\n\\n**exp-001 N-scaling evidence** (SciERC, n=200 subset, ⚠️ needs full-set confirmation):\\n- RE N=16: voting_conf ρ=0.448 (vs N=8 0.340, +0.108), SJ ρ=0.333 (vs 0.244, +0.089), all signals improve +0.07~0.10\\n- NER N=16: flat (already saturated at N=8) — voting_conf 0.401 vs 0.392\\n- **Key insight**: The task-complexity boundary is partially a SAMPLE BUDGET boundary. Compound error propagation increases per-instance variance, requiring more samples (N=16 vs N=8) to average out noise. This makes Claim 2 more nuanced: RE consistency fails at N=8 not because the signal is absent, but because it's noisier and needs more samples to manifest.\\n- ⚠️ Caveat: exp-001 ran on 200/529 instances. Full-set replication needed before claiming in paper.\\n\\n### Claim 4 (D154: Empirical Characterization of Selection Boundaries)\\n**Contribution C (Selection Boundary Characterization)**: Empirical analysis of when and why LP selection succeeds or fails, with DGS as exploratory heuristic (not validated framework).\\n- **Core finding (D154)**: Selection viability depends on LP signal quality (within-instance ρ(LP,F1)) and dataset characteristics. Cross-dataset degeneracy-LP correlation is ρ=0.052 (23 points, p=0.81) — degeneracy alone does not predict selection direction. Within fixed settings, degeneracy causally modulates LP effectiveness (epoch ablation, temperature ablation, per-entity-type analysis).\\n- **DGS as explored heuristic** (demoted from \\\"validated framework\\\"): Mixed results across dataset×model:\\n  - Few-NERD Qwen: +0.92pp (significant) — strong LP alignment (ρ~0.5)\\n  - SciERC Qwen: +0.71pp (not significant) — weak alignment (ρ~0.2)\\n  - CoNLL Qwen: -0.81pp (significant negative) — high degen + weak alignment\\n  - CoNLL LLaMA: +0.14pp (significant positive) — LP-quality alignment adequate\\n  - Cross-model sign reversal on CoNLL illustrates LP alignment's role, but DGS does not constitute a reliable prescriptive method\\n- **MBR**: Uniformly negative, excluded. Exception: SciERC T=1.2 +1.8pp under high-diversity conditions.\\n- **Status**: D154 reframing complete. DGS is ablation evidence, not core contribution.\\n\\n## Story Spine (D157 — Triple Contribution: QE + Diagnostic + Prescriptive, Main Conference)\\n\\n**Problem**: Test-time scaling via multi-sample generation improves LLM reasoning, but its effectiveness for structured information extraction is unclear. Practitioners need to know: (1) can confidence signals estimate output quality? (2) can they select better outputs? (3) if not, what SHOULD they do instead?\\n\\n**Existing approaches & gaps**: Self-consistency (Wang et al. 2023) succeeds for discrete-answer reasoning via majority vote on discrete answers. MBR decoding succeeds for MT. But structured IE outputs (entity sets, relation triples) present a fundamentally different challenge — prior work applies instance-level selection (pick one of N complete outputs), which is the wrong analogy for set-structured outputs. We show the correct analogy is entity-level construction (aggregate across outputs).\\n\\n**Our framing (D157 — TRIPLE CONTRIBUTION)**:\\n\\n**Contribution A (Positive — QE Framework)**: Five confidence signals across four families reliably predict structured IE output quality (AUROC 0.82, ρ 0.45). Signal ranking is task-dependent: structural > probabilistic for NER, reversed for RE. QE enables selective prediction: filtering 20% low-confidence instances yields +5-8pp F1 gain (AUPRC 0.70-0.92, VC strongest signal).\\n\\n**Contribution B (Diagnostic — Why Instance-Level Selection Fails)**:\\n1. **Design property**: 4/5 signals are instance-level aggregates → cannot rank candidates by construction.\\n2. **Instance Degeneracy**: 21-58% of instances produce identical F1 across all N samples, eliminating selection headroom.\\n3. **LP Compression**: Logprob within-instance range compressed (0.041 nats). Free-form ablation confirms intrinsic (std ratio 0.97).\\n4. **Multi-causal**: LoRA rank=8 reduces degeneracy 3× (7.2% vs 21%) and increases oracle headroom (+2.7pp), but ALL selection methods still fail to beat greedy → low degeneracy is NECESSARY but NOT SUFFICIENT.\\n5. **Capability-diversity tension**: Higher capability → more convergence → more degeneracy. CoNLL 91% F1→58% degen, SciERC 66%→21%.\\n6. **LP alignment as primary predictor**: LP selection viability depends on within-instance ρ(LP,F1). Few-NERD (ρ~0.5-0.7) → LP +1.38pp (p<0.05). SciERC (ρ~0.2) → LP fails despite similar degeneracy. Cross-dataset degeneracy ρ=0.052 (23 configs, p=0.81).\\n\\n**Contribution C (Prescriptive — Entity-Level Construction + Practitioner Protocol, D157)**:\\nThe correct self-consistency analogy for structured IE is NOT instance-level selection but entity-level construction: aggregate entities across N samples via majority vote, constructing a new output from parts.\\n- **Entity construction (multi-seed N=8 mean)**: SciERC +1.02pp, FewNERD +1.40pp, CoNLL +0.10pp (n.s.). Mechanism: recall gain by aggregating low-frequency correct entities across samples.\\n- **72B zero-shot construction**: LP-weighted construction SciERC ZS +1.53pp (stronger than fine-tuned!), CoNLL ZS -0.37pp (headroom-limited). **θ=2/N fails in zero-shot** (SciERC -0.52pp, CoNLL -0.92pp) → LP-weighting is necessary in zero-shot regime.\\n- **Construction effectiveness is headroom-dependent**: Works when oracle headroom is sufficient (SciERC 15pp → +1.53pp), fails when near ceiling (CoNLL 5.3pp → -0.37pp). This is consistent across fine-tuned and zero-shot regimes.\\n- **LP-alignment gating (preliminary diagnostic)**: Probe 50 instances on validation set to compute adjusted alignment score → automatically select construction vs LP selection. 3/3 datasets correct gating. Bootstrap CI: τ=0.3 at center of [0.25, 0.35] stable plateau, routing decisions stable across τ∈[0.2, 0.4] (stability ≥95%).\\n- **Selective prediction**: QE-driven human-in-the-loop — retain 80% high-confidence instances, F1 +5-8pp. VC is strongest signal across all datasets.\\n\\n**QE-vs-Selection Decoupling** (Dream-identified most novel insight): QE correlation (SJ ρ) is stable across LoRA rank configurations (0.360→0.378) while selection gap changes dramatically. Signals are ALWAYS useful for flagging uncertain instances, even when they cannot improve selection.\\n\\n**Headline**: \\\"We present a triple contribution for structured IE test-time scaling: (1) a QE framework showing confidence signals reliably predict output quality and enable selective prediction (+5-8pp @80% coverage); (2) a diagnostic revealing that the correlation-selection gap is fundamental — persisting from 4B to 72B and from fine-tuned to zero-shot regimes — driven by degeneracy, LP compression, and LP-alignment misalignment; and (3) entity-level construction as a diagnostic-motivated mitigation that significantly improves over greedy decoding (+1.02pp SciERC, +1.40pp FewNERD fine-tuned; +1.53pp SciERC zero-shot via LP-weighting), with effectiveness governed by oracle headroom.\\\"\\n\\n**Title candidates**:\\n- \\\"Don't Select, Construct: Diagnosing and Fixing Test-Time Scaling for Structured Information Extraction\\\"\\n- \\\"Strong Predictors, Weak Selectors: From Diagnosis to Entity-Level Construction for Structured IE\\\"\\n- \\\"Beyond Selection: Entity-Level Construction as the Correct Self-Consistency for Structured IE\\\"\\n\\n## Anticipated Reviewer Concerns\\n\\n### R1: \\\"Only one NER dataset — generalization unclear\\\"\\n- **Status**: ✅ RESOLVED. 3 NER datasets (SciERC + CoNLL-2003 + Few-NERD INTRA) × 2 models (Qwen3-8B + LLaMA-3.1-8B) + scale ablation (Qwen3-4B). Few-NERD adds 32,565 instances with distinct degeneracy profile (10% vs 21-58%). Cross-dataset comparison revealing LP alignment as primary selection predictor (D154) is the paper's strongest empirical contribution.\\n- **Priority**: P0, RESOLVED\\n\\n### R2: \\\"Only one model family (Qwen3-8B)\\\"\\n- **Mitigation**: LLaMA-3.1-8B shows model-agnostic effect. ⚠️ **exp-007 数据被污染 (test data leakage)**，LLaMA SciERC 正确值来自 exp_018 (clean rerun)。unified_rho_full.json 的 LLaMA SciERC 条目必须替换为 exp_018 数据。正确 LLaMA SciERC N=8 3-seed mean: SJ 0.325, FK 0.256, VC 0.384, EM 0.279, LP 0.162。\\n- **Priority**: P0\\n\\n### R3: \\\"FK is a strawman baseline — what about log-prob, USC, exact-match?\\\"\\n- **Mitigation**: exp-012 (log-prob), exp-013 (exact-match), exp-014 (entity voting) provide comprehensive baseline comparison. Results: structural consistency family (EM+SJ+voting) >> log-prob >> FK. USC discussed in related work (LLM-as-judge, orthogonal approach).\\n- **Priority**: P0, RESOLVED — results decisive\\n\\n### R3b: \\\"EM beats voting_conf and SJ on AUROC — why present SJ/voting_conf?\\\"\\n- **Mitigation**: EM is a strict binary signal (all-or-nothing match); SJ captures partial agreement and generalizes to arbitrary structured outputs (relations, events). Voting_conf provides granular entity-level scores. NER full AUROC: EM 0.749 > SJ 0.692 > voting_conf 0.684, but ρ: voting_conf 0.379 > SJ 0.360 > EM 0.295. EM excels at binary discrimination but underperforms on rank ordering. SJ is also more temperature-robust (Δρ=±0.01). Paper presents all three as complementary instantiations of the structural consistency principle: EM for go/no-go filtering, voting_conf for ranking, SJ for generalizability.\\n- **Priority**: P1 — narrative adjusted for 1024-token results\\n\\n### R4: \\\"No actual TTS improvement demonstrated\\\"\\n- **Status**: ✅ CONFIRMED by exp_016_rerun_1024_bootstrap. No signal significantly outperforms greedy on either task. NER logprob +0.6pp not significant (bootstrap p=0.39, 95% CI [−0.030, +0.042], Cohen's d=0.038). RE: greedy > all signals.\\n- **Mitigation**: Paper PIVOTS to \\\"confidence estimation + correlation-selection gap analysis.\\\" exp-006 redesigned as diagnostic: show selection curves to visualize the gap (F1 vs N per signal + oracle ceiling). The gap itself is a contribution, not a failure.\\n- **Priority**: P0 — narrative pivot complete, bootstrap confirms\\n\\n### R5: \\\"Sample size N=8 may be too small for reliable SJ estimation\\\"\\n- **Mitigation**: exp-001 (N=16) with multi-seed robustness\\n- **Priority**: P0\\n\\n### R6: \\\"Conditional analysis cherry-picks favorable instances\\\"\\n- **Mitigation**: Principled separation (knowledge-gap vs uncertainty). Add threshold sensitivity analysis. Temperature analysis provides independent validation.\\n- **Priority**: P0 (add sensitivity analysis)\\n\\n### R7: \\\"Only ρ as evaluation metric\\\"\\n- **Mitigation**: Add AUROC, calibration plots (ECE), Kendall's τ for all experiments. ECE data now available: NER best calibrated = EM (0.353), RE best = voting (0.272). Logprob worst calibrated (NER 0.706, RE 0.769).\\n- **Priority**: P0\\n\\n### R8: \\\"Formula-implementation discrepancy\\\"\\n- **Mitigation**: Paper must describe actual algorithm (type-grouped Hungarian matching with max(|g_a|,|g_b|) denominator)\\n- **Priority**: P0, paper writing fix\\n\\n### R9: \\\"Evaluation circularity (T>0 consistency vs T=0 F1)\\\"\\n- **Mitigation**: Add leave-one-out SJ evaluation as robustness check. Justify cross-mode design (greedy = deterministic reference, standard in TTS literature).\\n- **Priority**: P0\\n\\n### R10: \\\"Insufficient related work\\\" (三档一致 [B][M][W])\\n- **Mitigation**: Expand to 35+ references. Must cite:\\n  - USC (Chen 2024) — empirical differentiation, not just citation\\n  - Semantic uncertainty (Kuhn 2023), calibration (Kadavath 2022, Guo 2017, Desai & Durrett 2020)\\n  - **Conformal prediction for structured outputs**: Fisch et al. 2021, Angelopoulos et al. 2021, Bates et al. 2021\\n  - **Token-level NER uncertainty**: Xiao & Wang 2019, Shelmanov et al. 2021, He et al. 2020\\n  - **Ensemble/MC-dropout**: Lakshminarayanan et al. 2017, Gal & Ghahramani 2016\\n  - **Verifier/reward models**: Cobbe et al. 2021, Lightman et al. 2023\\n  - **TTS scaling theory**: Snell et al. 2024, Brown et al. 2024\\n  - **Structured calibration**: Kuleshov & Liang 2015, Jagannatha & Yu 2022\\n  - **IE confidence**: Culotta & McCallum 2004\\n  - SelfCheckGPT (Manakul 2023), selective prediction (Geifman & El-Yaniv 2017)\\n  - **[2025-2026 新颖性自查补充 — 必引]**:\\n    - CISC (ACL Findings 2025) — confidence-weighted majority vote for reasoning; 对比：我们用 structural similarity 而非 confidence 加权，且面向 set-structured IE 输出\\n    - Self-Certainty Best-of-N (ICLR 2026, arxiv 2502.18581) — KL-divergence reward-free selection; 对比：我们发现 log-prob 是唯一有效 selection signal (与其方向互补)，且揭示 correlation-selection gap\\n    - ReASC (2026, arxiv 2601.02970) — reliability-aware adaptive self-consistency; 对比：仍限于 reasoning 离散答案\\n    - Atomic Self-Consistency (EMNLP 2024) — 子声明级一致性 for long-form text; 对比：我们在 entity-set 级别做结构化度量\\n    - **Nédellec & Xia (Genomics Informatics, 2026-02, PMC12888769)** — \\\"Consistency–accuracy correlation in hard-prompted LLMs for entity and relation extraction\\\"。最直接竞争者：4 LLMs 在植物健康 NER/RE 上研究 consistency-accuracy 相关性。**关键差异**：(a) 他们用 surface-level string matching，自承\\\"overlooks semantically consistent outputs\\\"，我们的 SJ 正好解决此问题; (b) 不研究 best-of-N selection; (c) 单领域 hard-prompted (T=0); (d) 无多信号家族对比。论文 Intro 可引用其 limitation 作为 SJ 的动机\\n  - **[2025-2026 新颖性自查补充 — 应引]**:\\n    - UQ for LLMs Survey (ACL Findings 2025) — 最全面 LLM 不确定性综述\\n    - UQ+Calibration Survey (arxiv 2503.15850, 2025) — 第二篇综合综述\\n    - Semantic Entropy Probes (2024) — 低成本不确定性估计\\n    - Latent Self-Consistency (2025, arxiv 2508.18395) — embedding 空间一致性\\n    - Ranked Voting SC (2025, arxiv 2505.10772) — 排名投票变体，仍限于推理任务\\n    - Know Your Limits: Abstention Survey (TACL 2025) — 选择性预测综述，与 Claim 1 selective prediction 角度直接相关\\n    - Confidence Estimation Survey (NAACL 2024, arxiv 2311.08298) — LLM 置信度估计全景定位\\n    - **CoCoA (Vashurin et al., NeurIPS 2025, arxiv 2502.04964)** — MBR 框架融合 confidence+consistency 做 UQ，在 QA/摘要/翻译上评估。与我们 exp-016 ensemble (SJ+logprob) 对标，但未涉及 structured IE\\n    - **Vashurin et al. (arxiv 2510.20460, 2025)** — VCE/MSP/Sample Consistency/CoCoA 四方法系统评估，任务不含 structured IE\\n  - **需新增 Related Work 小节**:\\n    - \\\"Test-Time Scaling & Sample Selection\\\" — 将 CISC/Self-Certainty/ReASC 集中讨论，明确 positioning：现有工作均面向 reasoning/QA 的离散答案，我们首次在 structured IE 上做系统信号对比并发现 correlation-selection gap\\n    - \\\"Consistency for Structured IE\\\" — 引 Nédellec & Xia 2026 作为同期工作，显式对比：surface matching vs structural metrics (SJ)；他们的 limitation 是我们的 motivation\\n- **Priority**: P0, Paper Agent handles\\n\\n### R11: \\\"SJ+logprob ensemble missing\\\" (Dream 2 — both reviewers)\\n- **Status**: ⚠️ REVISED by exp_016_rerun_1024. Results:\\n  - Ensemble AUROC (5-fold CV LR): NER 0.666 ± 0.070, RE 0.662 ± 0.078\\n  - Best single signal EM: NER AUROC 0.749, RE AUROC 0.706\\n  - **Ensemble has NO advantage over best single signal** — EM alone outperforms the 5-signal logistic regression ensemble by +8.3pp (NER) and +4.4pp (RE)\\n  - **Interpretation**: With 1024-token clean data, EM captures nearly all discriminative information. The ensemble's inferior performance likely reflects overfitting in the 5-fold CV LR with correlated features. This further supports presenting EM as a simple, strong baseline within the structural consistency family.\\n- **Priority**: DONE — write into paper with honest interpretation (no ensemble advantage claim)\\n\\n### R12: \\\"No supervised upper bound / reward model comparison\\\" (Dream 2)\\n- **Mitigation**: exp-016 LR ensemble (5-signal, 5-fold CV) underperforms best single signal EM (AUROC 0.666 vs 0.749), suggesting feature redundancy. exp-019 supervised verifier SKIPPED (DDL risk + scope creep). Free-form ablation provides the \\\"so what\\\": gap is fundamental → closing it requires fundamentally different approaches (trained verifiers, not just better unsupervised signals). Positioned as future work with explicit motivation from ablation evidence.\\n- **Priority**: P1, addressed via framing (future work motivated by ablation)\\n\\n### R13: \\\"Headroom capture rate low\\\" (Dream 2)\\n- **Mitigation**: NER oracle 0.7758, greedy 0.6439, best signal (logprob) 0.6501 → captures 0.5% of headroom. RE oracle 0.5850, greedy 0.4042, best signal (greedy itself) → 0% capture. Discuss explicitly in paper. Contextualize vs other unsupervised TTS methods. Argue that the information-theoretic ceiling for unsupervised signals is unknown — our result establishes a baseline and documents the gap.\\n- **Priority**: P0, paper writing\\n\\n### R14: \\\"Cross-model validation thin — need more than 2×8B\\\" (Dream 2)\\n- **Status**: ✅ RESOLVED by 4B scale ablation. 2×2 matrix: {CoNLL, SciERC} × {Qwen3-8B, Qwen3-4B}. All correlation metrics maintained or improved at 4B (e.g. SciERC NER SJ_ρ: 0.3825→0.4221, +3.96pp). Combined with LLaMA-3.1-8B cross-architecture data, now have 3 model configurations (Qwen3-8B, Qwen3-4B, LLaMA-3.1-8B). 70B infeasible — acknowledge as limitation.\\n- **Priority**: P0, RESOLVED\\n\\n### R15: \\\"Log-prob definition ambiguity — Eq.1 vs best-of-N ranking\\\" (Dream 2 cross-tier, [W])\\n- **Mitigation**: Paper must clarify: log-prob ranks among N candidates (each sample's generation log-prob), not just score greedy output. Cost comparison table must state \\\"all best-of-N require N forward passes; log-prob adds zero ranking overhead.\\\"\\n- **Priority**: P0, Paper Agent handles\\n\\n### R16: \\\"Zero figures — data-rich paper with only tables\\\" (Dream 2 cross-tier, [W])\\n- **Mitigation**: Paper Agent must include ≥3 figures: (1) selection curves (F1 vs N for each signal + oracle), (2) reliability diagram (calibration), (3) N-scaling or cost-effectiveness scatter. Data exists from exp-010/015.\\n- **Priority**: P0, Paper Agent handles\\n\\n### R17: \\\"Diagnostic framework overclaimed — descriptive not prescriptive\\\" (Dream 2 cross-tier, [M][W])\\n- **Mitigation**: Soften \\\"diagnostic framework\\\" to \\\"diagnostic analysis\\\" throughout. Current taxonomy (ceiling/floor/compound error) is descriptive. Either formalize with a priori metrics or reframe as empirical analysis.\\n- **Priority**: P0, Paper Agent handles\\n\\n### R18: \\\"No discussion of when consistency WOULD help\\\" (Dream 2 cross-tier, [W])\\n- **Mitigation**: Add discussion paragraph: consistency should outperform log-prob when (a) model calibration is poor (in-context learning without fine-tuning), (b) log-prob unavailable (closed-source APIs), (c) ensemble/mixture settings, (d) tasks where model is systematically overconfident.\\n- **Priority**: P1, Paper Agent handles\\n\\n### R19: \\\"Negative result partially predictable for fine-tuned models\\\" (Dream 2 cross-tier, [W])\\n- **Mitigation**: Paper must argue non-obviousness: (a) self-consistency demonstrably helps for reasoning tasks (Wang et al. 2023), (b) structured prediction has internal structure that surface metrics can't capture, (c) the DEGREE of log-prob's strength and the task-complexity boundary are not predictable a priori.\\n- **Priority**: P1, Paper Agent handles\\n\\n## Venue Fit\\n\\nEMNLP **Main Conference** target. Strengths:\\n- Systematic empirical comparison with mechanistic diagnosis (not just \\\"signals don't work\\\" but \\\"here's exactly why\\\")\\n- Two novel failure mechanisms (instance degeneracy + LP compression) + unifying capability-diversity tension\\n- Controlled ablation (free-form decoding) providing causal evidence\\n- Cross-model (Qwen3-8B/4B + LLaMA-3.1-8B), cross-dataset (SciERC + CoNLL + WNUT), cross-task (NER + RE) validation\\n\\nMain Conference gap vs Findings:\\n- ✅ 3rd NER dataset (Few-NERD) — DONE, confirms LP alignment as primary predictor\\n- ✅ LoRA rank=8 ablation — DONE, multi-causal confirmed\\n- ✅ Bootstrap significance — DONE, LP p<0.05 on Few-NERD\\n- ✅ Numerical audit — DONE, all corrections applied\\n- **Remaining**: Dream #3 validation (target ≥3.5), final editorial pass\\n\\nRisk assessment:\\n- **Strongest asset**: LP alignment as primary selection predictor + within-dataset causal evidence (epoch/temperature ablation) — honest empirical characterization with actionable implications\\n- **Second strongest**: QE-vs-selection decoupling (signals always useful for QE even when selection fails)\\n- **Weakest flank**: D154 removed \\\"monotonic gradient\\\" claim, but the within/cross distinction is more nuanced and honest — reviewers should appreciate this\\n- **Critical path**: Dream #3 → final submission to Review Director → DDL 2026-05-25\", \"total_chars\": 35571, \"truncated\": false}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---


### Tool call

_source line 12_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__read_registry · `toolu_01CFDHoGCr1xHs3SjTbdTReQ`</summary>

```json
{
  "project": "struct_self_consist_ie",
  "limit": 0,
  "fields": [
    "*"
  ]
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "cd3cacfa-840c-4723-8b09-93409534d6de",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012oRWrC1xpgk7rVew6w8JjZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 1811,
      "cache_read_input_tokens": 23911,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1811
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

_source line 13 · 2026-05-19T13:33:36.192Z_

<details><summary>↩ Tool result · `toolu_01CFDHoGCr1xHs3SjTbdTReQ`</summary>

```text
Error: result (265,254 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt.
Format: JSON with schema: {result: string}
Use offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.
REQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:
- You MUST read the content from the file at /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt in sequential chunks until 100% of the content has been read.
- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.
- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***

```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "70b18da7-0144-40c3-bcb6-c6279cd049ce",
  "tool_use_result": {
    "content": "Error: result (265,254 characters) exceeds maximum allowed tokens. Output has been saved to /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt.\nFormat: JSON with schema: {result: string}\nUse offset and limit parameters to read specific portions of the file, search within it for specific content, and jq to make structured queries.\nREQUIREMENTS FOR SUMMARIZATION/ANALYSIS/REVIEW:\n- You MUST read the content from the file at /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt in sequential chunks until 100% of the content has been read.\n- If you receive truncation warnings when reading the file, reduce the chunk size until you have read 100% of the content without truncation.\n- Before producing ANY summary or analysis, you MUST explicitly describe what portion of the content you have read. ***If you did not read the entire content, you MUST explicitly state this.***\n",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"experiments\": {\"exp_qwen25_72b_zeroshot\": {\"status\": \"RUNNING\", \"retry_count\": 1, \"created_at\": \"2026-05-19T06:19:28.597Z\", \"updated_at\": \"2026-05-19T12:48:36.347Z\", \"hypothesis\": \"A larger zero-shot model (72B) will show higher greedy F1 and wider oracle-greedy gap than fine-tuned smaller models, because increased capacity enables more diverse valid extractions per stochastic sample, making self-consistency signals (SJ, FK, VC, EM) more informative for quality estimation.\", \"server\": \"autodl-5090-b\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-b\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"started_at\": \"2026-05-19T06:47:42.658Z\"}, \"notes\": \"2026-05-19 12:47 UTC: RECOVERED from false-positive startup recovery failure. 289848/301184 prompts (96.2%). SciERC ✅ (551) CoNLL ✅ (3453) FewNERD ~96%. ETA ~10-15min. PID 59040, 4×5090 100% util. Cron registered.\", \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"completed_at\": \"2026-05-19T12:44:26.198Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"2026-05-19 11:36 UTC: 69.8% complete (210352/301184 prompts). SciERC ✅ CoNLL ✅ FewNERD ~66%. ETA ~1h15m. vLLM PID 59040, 4×5090 100% util.\"}}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0,1,2,3 python code/zeroshot_inference_72b.py --datasets scierc conll2003 fewnerd --output-dir output/72b_zeroshot --seed 42\", \"server\": \"autodl-5090-b\", \"data_path\": \"data/{scierc,conll2003,fewnerd}\", \"data_count\": 41630, \"model_name\": \"Qwen2.5-72B-Instruct-AWQ\", \"seed\": 42, \"gpu_ids\": [\"cuda:0\", \"cuda:1\", \"cuda:2\", \"cuda:3\"], \"pid\": 59040}}, \"exp_qwen25_14b_fewnerd\": {\"status\": \"RUNNING\", \"retry_count\": 1, \"created_at\": \"2026-05-19T06:19:31.620Z\", \"updated_at\": \"2026-05-19T12:48:33.954Z\", \"hypothesis\": \"The correlation-selection gap pattern is consistent at 14B scale, filling the gap between 8B and 32B. Qwen2.5-14B QLoRA fine-tuned on FewNERD should show intermediate degeneracy rates and similar signal ranking patterns, providing a smooth scaling curve for the diagnostic findings.\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:0,cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-c\", \"gpu\": \"cuda:0,cuda:1\", \"started_at\": \"2026-05-19T06:47:43.938Z\"}, \"notes\": \"2026-05-19 12:47 UTC: RECOVERED from false-positive startup recovery failure. Step 6483/41180 (15.7%), loss 0.0608, ~2.2s/it, ETA ~21h. checkpoint-6000 saved. screen train_14b_s42 PID 56766, GPU 0,1 95-96% util. Cron registered on PID 56773.\", \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"completed_at\": \"2026-05-19T12:44:29.453Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\", \"notes\": \"2026-05-19 11:36 UTC: step 4934/41180 (12.0%), loss 0.067, ~2.15s/it, ETA ~22h. checkpoint-4000 saved. screen train_14b_s42, 2×5090 76-77% util.\"}}, \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0,1 FORCE_TORCHRUN=1 NNODES=1 NPROC_PER_NODE=2 llamafactory-cli train train_config_qwen25_14b_fewnerd_s42.yaml\", \"server\": \"autodl-5090-c\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/llmfactory_train.json\", \"data_count\": 131767, \"model_name\": \"Qwen2.5-14B-Instruct\", \"seed\": 42, \"gpu_ids\": [\"cuda:0\", \"cuda:1\"], \"screen_session\": \"train_14b_s42\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/train_qwen25_14b_fewnerd_s42.log\"}}, \"exp_qwen25_32b_fewnerd\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T06:19:25.428Z\", \"updated_at\": \"2026-05-19T12:24:14.706Z\", \"hypothesis\": \"Scaling from Qwen3-8B to Qwen2.5-32B-Instruct with QLoRA fine-tuning on FewNERD will improve structured self-consistency IE performance due to stronger base model capabilities in instruction following and entity recognition.\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"started_at\": \"2026-05-19T06:47:41.246Z\"}, \"notes\": \"2026-05-19 11:36 UTC: step 2177/41180 (5.3%), loss 0.0663, ~2.44s/it, ETA ~26h. checkpoint-2000 saved. PID 804438, 4×5090 87-100% util.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0,1,2,3 FORCE_TORCHRUN=1 NNODES=1 NPROC_PER_NODE=4 llamafactory-cli train /root/autodl-tmp/struct_self_consist_ie/train_config_qwen25_32b_fewnerd_s42.yaml\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/llmfactory_train.json\", \"data_count\": 131767, \"model_name\": \"Qwen2.5-32B-Instruct\", \"seed\": 42, \"method\": \"QLoRA-4bit-nf4 (rank=32, alpha=64, target=all)\", \"output_dir\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-32b-fewnerd-qlora-s42\", \"config_path\": \"/root/autodl-tmp/struct_self_consist_ie/train_config_qwen25_32b_fewnerd_s42.yaml\", \"epochs\": 5, \"effective_batch_size\": 16, \"lr\": \"2e-4\", \"gpu_ids\": [\"cuda:0\", \"cuda:1\", \"cuda:2\", \"cuda:3\"], \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/train_qwen25_32b_fewnerd_s42.log\", \"pid\": 804438}}, \"exp_qwen25_7b_fewnerd\": {\"status\": \"RUNNING\", \"retry_count\": 0, \"created_at\": \"2026-05-19T06:41:43.121Z\", \"updated_at\": \"2026-05-19T12:23:28.347Z\", \"hypothesis\": \"Qwen2.5-7B QLoRA fine-tuned on FewNERD will produce structurally diverse samples enabling self-consistency-based entity extraction with meaningful LP-weighted consensus signals, comparable to the 14B model but with lower compute cost.\", \"spec\": {\"server\": \"autodl-5090-c\", \"gpu_ids\": [\"cuda:2\", \"cuda:3\"], \"command\": \"nohup bash run_fewnerd_qwen25_7b_pipeline.sh > logs/pipeline_qwen25_7b_fewnerd.log 2>&1 &\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/llmfactory_train.json\", \"data_count\": 131767, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-7b-fewnerd-qlora-s42\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/pipeline_qwen25_7b_fewnerd.log\", \"training_config\": \"train_config_qwen25_7b_fewnerd_s42.yaml\", \"export_config\": \"export_config_qwen25_7b_fewnerd.yaml\", \"pipeline_script\": \"run_fewnerd_qwen25_7b_pipeline.sh\", \"method\": \"QLoRA 4-bit nf4, rank=32, alpha=64, 5 epochs, lr=2e-4, effective_batch=32\", \"pipeline_phases\": \"train -> export/merge -> 3-seed N=8 inference (42/123/456) -> signal analysis -> entity construction\"}, \"notes\": \"2026-05-19 11:36 UTC: step 138/20590 (0.7%), ~2.34s/it, ETA ~13.3h. Pipeline PID 71837, llamafactory PID 71844. cuda:2,3 98-100% util. Cron registered on pipeline PID.\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2,cuda:3\"}, \"exp_wnut17_qwen25_7b\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T06:19:33.960Z\", \"updated_at\": \"2026-05-19T11:49:07.313Z\", \"hypothesis\": \"The correlation-selection gap extends to noisy social media NER (WNUT-17). Unlike formal-domain datasets (SciERC/CoNLL/FewNERD), WNUT-17 has higher surface-level noise which may affect structural signal reliability differently. This tests domain generalization of the diagnostic framework.\", \"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2,cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090-c\", \"gpu\": \"cuda:2,cuda:3\", \"started_at\": \"2026-05-19T06:47:45.220Z\"}, \"spec\": {\"server\": \"autodl-5090-c\", \"gpu_ids\": [\"cuda:2\", \"cuda:3\"], \"command\": \"bash wait_and_train.sh (screen: exp_wnut17_7b)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/wnut17/llmfactory_train.json\", \"data_count\": 3404, \"model_name\": \"Qwen2.5-7B-Instruct\", \"seed\": 42, \"training_config\": \"train_config_qwen25_7b_wnut17_s42.yaml\", \"method\": \"QLoRA 4-bit (bnb nf4), rank=32, alpha=64, all targets\", \"gpus\": \"cuda:2,3 (2x5090)\", \"epochs\": 5, \"effective_batch_size\": 32, \"pipeline\": \"train → export → 3-seed inference (N=8, T=1.0) → signal analysis → entity construction\", \"checkpoint_source\": \"self-trained on WNUT-17\", \"eval_data\": \"WNUT-17 test set\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen25-7b-wnut17-qlora-s42\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/exp_wnut17_7b_pipeline.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"seed42\": {\"greedy_f1\": 0.4524, \"construction_f1\": 0.4439, \"construction_delta_pp\": -0.84, \"construction_p\": 0.95}, \"seed123\": {\"greedy_f1\": 0.4518, \"construction_f1\": 0.4579, \"construction_delta_pp\": 0.61, \"construction_p\": 0.08}, \"seed456\": {\"greedy_f1\": 0.4526, \"construction_f1\": 0.4583, \"construction_delta_pp\": 0.57, \"construction_p\": 0.12}, \"oracle_headroom_pp\": \"6.3-9.2\"}, \"completed_at\": \"2026-05-19T11:22:56.623Z\"}, \"exp_llama_fewnerd_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:18:49.938Z\", \"updated_at\": \"2026-05-19T03:15:04.486Z\", \"hypothesis\": \"LLaMA-3.1-8B fine-tuned on FewNERD shows the same structured self-consistency phenomena (degeneracy, LP-F1 alignment, signal ranking) as Qwen models, providing cross-model generalization evidence. 3-seed inference (42/123/456) for statistical robustness.\", \"parent\": \"exp_llama_fewnerd_lora\", \"spec\": {\"command\": \"bash code/run_llama_fewnerd_inference.sh\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd/\", \"data_count\": 37648, \"model_name\": \"LLaMA-3.1-8B-FewNERD-LoRA-merged\", \"seed\": \"42,123,456\", \"checkpoint_source\": \"exp_llama_fewnerd_lora\", \"eval_data\": \"FewNERD test set\", \"checkpoint_path\": \"checkpoints/llama3.1-8b-fewnerd-merged/\", \"log_path\": \"logs/llama_fewnerd_inference.log\"}, \"conclusion\": \"success\", \"metrics\": {\"3seed_mean\": {\"greedy_f1\": 0.7842, \"oracle_f1\": 0.8843, \"headroom_pp\": 10.01, \"degeneracy_pct\": 23.36, \"lp_delta_pp\": 0.36, \"dgs_delta_pp\": -0.35}, \"seed_42\": {\"greedy_f1\": 0.7841, \"oracle_f1\": 0.8854, \"degen\": 27.32}, \"seed_123\": {\"greedy_f1\": 0.784, \"oracle_f1\": 0.8839, \"degen\": 24.63}, \"seed_456\": {\"greedy_f1\": 0.7844, \"oracle_f1\": 0.8835, \"degen\": 18.13}, \"signal_ranking\": \"LP (+0.36pp) > SJ (-0.52) > FK (-0.53) > EM (-1.02) > VC (-2.39)\", \"lp_only_positive\": true, \"n_instances_gold_filtered\": 32565}, \"completed_at\": \"2026-05-19T03:15:04.486Z\"}, \"exp_entity_construction\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:00:12.074Z\", \"updated_at\": \"2026-05-19T02:40:17.571Z\", \"hypothesis\": \"Entity-level majority vote construction is the correct self-consistency analogy for structured IE: instead of selecting the best instance-level output, assemble a better output from entity-level consensus across N samples. Construction should outperform both greedy and best-of-N selection.\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/entity_construction_fair.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/*/samples_*.json\", \"data_count\": 3, \"model_name\": \"analysis_cpu\", \"seed\": 42, \"checkpoint_path\": \"output/entity_construction_fair/\", \"log_path\": \"output/entity_construction_fair/\"}, \"completed_at\": \"2026-05-19T02:15:19.616Z\", \"metrics\": {\"n16_fair_cv\": {\"scierc_ner\": {\"cv_uniform_delta\": \"+1.35pp\", \"p_value\": 0.018, \"significant\": true}, \"conll_ner\": {\"cv_uniform_delta\": \"+0.10pp\", \"p_value\": 0.303, \"significant\": false}, \"fewnerd_ner\": {\"cv_uniform_delta\": \"+1.32pp\", \"p_value\": 0, \"significant\": true}, \"scierc_re\": {\"cv_uniform_delta\": \"+1.69pp\", \"p_value\": 0.049, \"significant\": true}}, \"n8_fair_cv\": {\"scierc_ner\": {\"uniform_confirm\": \"+1.54pp (p=0.023, sig)\", \"lp_weighted_confirm\": \"+1.67pp (p=0.004, sig)\", \"cv_uniform\": \"+1.12pp (p=0.057, borderline)\"}, \"conll_ner\": {\"cv_uniform\": \"-0.39pp (p=0.963, not sig)\"}, \"fewnerd_ner\": {\"lp_weighted_cv\": \"+0.88pp (p=0.000, sig)\", \"uniform_cv\": \"+0.32pp (p=0.003, sig)\"}}, \"adaptive_combination\": \"INVALIDATED - gold label leakage confirmed\", \"note\": \"5-fold CV, bootstrap B=10000, paired one-sided\"}}, \"exp_lp_alignment_gating\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:00:16.520Z\", \"updated_at\": \"2026-05-19T02:15:48.197Z\", \"hypothesis\": \"Within-instance LP-F1 alignment score (adjusted by valid_ratio for degeneracy) can automatically gate whether LP selection should be applied to a dataset. A small probe sample (50-100 instances) suffices for a stable gating decision.\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/lp_alignment_gated_selection.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/*/samples_*.json\", \"data_count\": 3, \"model_name\": \"analysis_cpu\", \"seed\": 42, \"checkpoint_path\": \"output/prescriptive_analysis/\", \"log_path\": \"output/prescriptive_analysis/\"}, \"completed_at\": \"2026-05-19T02:15:23.716Z\", \"metrics\": {\"adjusted_score\": \"mean_rho * valid_ratio\", \"threshold\": 0.3, \"accuracy\": \"3/3 datasets correct\", \"robust_range\": \"0.2-0.4\"}}, \"exp_selective_prediction\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-19T02:00:13.989Z\", \"updated_at\": \"2026-05-19T02:15:46.588Z\", \"hypothesis\": \"QE signals (especially voting_confidence) can drive practical selective prediction: filtering out low-confidence instances yields significant F1 improvement on retained instances, enabling human-AI collaboration for structured IE.\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/selective_prediction.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/*/samples_*.json\", \"data_count\": 3, \"model_name\": \"analysis_cpu\", \"seed\": 42, \"checkpoint_path\": \"output/prescriptive_analysis/\", \"log_path\": \"output/prescriptive_analysis/\"}, \"completed_at\": \"2026-05-19T02:15:21.704Z\", \"metrics\": {\"vc_best_signal\": true, \"f1_at_80pct_coverage\": {\"scierc\": \"+5.0pp\", \"conll\": \"+8.4pp\", \"fewnerd\": \"+6.2pp\"}, \"precision_coverage_curves\": \"output/prescriptive_analysis/fig_selective_prediction.pdf\"}}, \"exp_llama_fewnerd_lora\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T13:20:55.859Z\", \"updated_at\": \"2026-05-19T01:08:20.832Z\", \"hypothesis\": \"LLaMA-based model with LoRA fine-tuning on Few-NERD can provide a second model family (beyond Qwen) for cross-model generalization evidence of structured self-consistency phenomena in NER\", \"spec\": {\"command\": \"llamafactory-cli train train_config_llama_fewnerd.yaml\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": 137865, \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd\", \"data_count\": -1, \"model_name\": \"LLaMA-Few-NERD-LoRA\", \"seed\": 42, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/llama_fewnerd_train.log\", \"run_script\": \"run_llama_fewnerd_train_single_gpu.sh\", \"tmux_session\": \"llama_fewnerd\", \"note\": \"Retroactively registered - data_count unknown, seed assumed 42\"}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/llama3.1-8b-fewnerd-lora\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/llama_fewnerd_train.log\", \"conclusion\": \"success\", \"metrics\": {\"epoch\": 3, \"train_loss\": 0.0516, \"eval_loss\": 0.0323, \"train_runtime_hours\": 15.35, \"total_steps\": 24708, \"final_checkpoint\": \"checkpoint-24708\", \"adapter_size_mb\": 320}, \"completed_at\": \"2026-05-19T01:08:20.832Z\"}, \"hidden_state_probe_conll_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:57:45.711Z\", \"updated_at\": \"2026-05-19T00:30:18.272Z\", \"conclusion\": \"killed\", \"notes\": \"Not in D154 Dual Contribution framing\", \"completed_at\": \"2026-05-19T00:30:18.272Z\"}, \"hidden_state_probe_conll_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T12:35:05.317Z\", \"updated_at\": \"2026-05-19T00:30:16.471Z\", \"conclusion\": \"killed\", \"notes\": \"Not in D154 Dual Contribution framing\", \"completed_at\": \"2026-05-19T00:30:16.471Z\"}, \"exp_031_fewnerd_t12\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:04:12.040Z\", \"updated_at\": \"2026-05-19T00:30:14.652Z\", \"hypothesis\": \"FewNERD T=1.2 temperature ablation: test if higher temperature reduces degeneracy on FewNERD as observed on SciERC\", \"conclusion\": \"killed\", \"failure_reason\": \"数据不可用于论文：测试集(37648 vs T=1.0的5000)、N(8 vs 16)、分析管道(MVP pilot vs 5-signal)三重不一致。Director决定不重跑(DDL约束+非核心claim)。\", \"notes\": \"T=1.2 ablation not in paper scope, SciERC T=1.2 sufficient\", \"completed_at\": \"2026-05-19T00:30:14.652Z\"}, \"exp_030_conll_t12\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T20:24:47.839Z\", \"updated_at\": \"2026-05-19T00:30:12.698Z\", \"hypothesis\": \"CoNLL T=1.2 temperature ablation: test if higher temperature reduces degeneracy on CoNLL as observed on SciERC\", \"conclusion\": \"killed\", \"failure_reason\": \"数据不可用于论文：N不一致(N=8 vs T=1.0基准的N=16)。Director决定不重跑——SciERC T消融(T=0.5/0.8/1.0/1.2, 551inst, N=8)已够用，论文温度消融用SciERC单数据集。\", \"notes\": \"T=1.2 ablation not in paper scope, SciERC T=1.2 sufficient\", \"completed_at\": \"2026-05-19T00:30:12.699Z\"}, \"mbr_pilot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:56:06.462Z\", \"updated_at\": \"2026-05-19T00:29:39.285Z\", \"conclusion\": \"killed\", \"notes\": \"MBR tested negative as one of 6 methods, stale entry\", \"completed_at\": \"2026-05-19T00:29:39.285Z\"}, \"dgs_pilot\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T17:56:04.572Z\", \"updated_at\": \"2026-05-19T00:29:37.275Z\", \"hypothesis\": \"Degeneracy-Gated Selection (DGS) validates Two-Condition Theory: using degeneracy rate as gating mechanism to switch between greedy (degenerate) and LP selection (non-degenerate), the improvement direction should follow a monotonic gradient — low degeneracy yields positive delta, high degeneracy yields negative delta.\", \"conclusion\": \"killed\", \"notes\": \"D154: DGS demoted to explored heuristic, cross-model direction contradiction (D152)\", \"completed_at\": \"2026-05-19T00:29:37.275Z\"}, \"exp_fewnerd_s789_n8\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T23:17:34.011Z\", \"updated_at\": \"2026-05-18T23:18:28.125Z\", \"hypothesis\": \"FewNERD seed789 (4th seed) for statistical CI strengthening: 4-seed protocol provides tighter confidence intervals on LP selection gain and DGS effectiveness in low-degeneracy regime.\", \"parent\": \"exp_029a\", \"spec\": {\"command\": \"python code/analyze_fewnerd_s789.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/samples.jsonl\", \"data_count\": 37648, \"model_name\": \"Qwen3-8B (ft_002_v2)\", \"seed\": 789, \"checkpoint_source\": \"exp_021 shards\", \"eval_data\": \"FewNERD test (37648 instances, 32565 gold-filtered)\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/fewnerd_seed789_merged/run.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T23:18:17.902Z\", \"metrics\": {\"greedy_f1\": 0.7478, \"oracle_f1\": 0.8714, \"headroom_pp\": 12.37, \"degen_rate\": 0.1177, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 37648, \"n_valid\": 32565, \"lp_sel_f1\": 0.7614, \"lp_delta_pp\": 1.36, \"lp_rho_global\": 0.1788, \"lp_rho_cond\": 0.176, \"dgs_f1\": 0.7621, \"dgs_delta_pp\": 1.43, \"dgs_vs_lp_pp\": 0.07, \"best_signal\": \"LP\", \"four_seed_mean_greedy\": 0.7481, \"four_seed_mean_lp_delta_pp\": 1.38, \"four_seed_lp_delta_ci95\": [1.32, 1.44]}}, \"exp_026_t12_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:43.694Z\", \"updated_at\": \"2026-05-18T22:07:24.547Z\", \"hypothesis\": \"Temperature ablation (T=1.2, seed=456) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 456 --n_samples 8 --temperature 1.2\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t12_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t12_seed456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:07:05.941Z\", \"metrics\": {\"ner_greedy_f1\": 0.6637, \"ner_oracle_f1\": 0.7821, \"rho_sj_ner\": 0.3995, \"sample_f1_pct_zero\": 14.08, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t12_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:42.754Z\", \"updated_at\": \"2026-05-18T22:07:23.135Z\", \"hypothesis\": \"Temperature ablation (T=1.2, seed=123) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 123 --n_samples 8 --temperature 1.2\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t12_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t12_seed123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:07:04.119Z\", \"metrics\": {\"ner_greedy_f1\": 0.6595, \"ner_oracle_f1\": 0.7895, \"rho_sj_ner\": 0.359, \"sample_f1_pct_zero\": 13.99, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t10_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:41.840Z\", \"updated_at\": \"2026-05-18T22:07:21.767Z\", \"hypothesis\": \"Temperature ablation (T=1.0, seed=456) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 456 --n_samples 8 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:07:02.272Z\", \"metrics\": {\"ner_greedy_f1\": 0.6621, \"ner_oracle_f1\": 0.7754, \"rho_sj_ner\": 0.3921, \"sample_f1_pct_zero\": 12.97, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t10_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:40.599Z\", \"updated_at\": \"2026-05-18T22:07:20.459Z\", \"hypothesis\": \"Temperature ablation (T=1.0, seed=123) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 123 --n_samples 8 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:07:00.430Z\", \"metrics\": {\"ner_greedy_f1\": 0.6633, \"ner_oracle_f1\": 0.7777, \"rho_sj_ner\": 0.3809, \"sample_f1_pct_zero\": 12.59, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t10_seed42\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:39.473Z\", \"updated_at\": \"2026-05-18T22:07:19.035Z\", \"hypothesis\": \"Temperature ablation (T=1.0, seed=42) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 42 --n_samples 8 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed42\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t10_seed42.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:06:58.573Z\", \"metrics\": {\"ner_greedy_f1\": 0.6617, \"ner_oracle_f1\": 0.7798, \"rho_sj_ner\": 0.3598, \"sample_f1_pct_zero\": 12.9, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t08_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:38.605Z\", \"updated_at\": \"2026-05-18T22:07:17.604Z\", \"hypothesis\": \"Temperature ablation (T=0.8, seed=456) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 456 --n_samples 8 --temperature 0.8\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t08_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t08_seed456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:06:56.681Z\", \"metrics\": {\"ner_greedy_f1\": 0.6641, \"ner_oracle_f1\": 0.7694, \"rho_sj_ner\": 0.3771, \"sample_f1_pct_zero\": 11.79, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t08_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:37.454Z\", \"updated_at\": \"2026-05-18T22:07:16.089Z\", \"hypothesis\": \"Temperature ablation (T=0.8, seed=123) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 123 --n_samples 8 --temperature 0.8\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t08_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t08_seed123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:06:54.734Z\", \"metrics\": {\"ner_greedy_f1\": 0.6607, \"ner_oracle_f1\": 0.7714, \"rho_sj_ner\": 0.3893, \"sample_f1_pct_zero\": 11.22, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t05_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:36.536Z\", \"updated_at\": \"2026-05-18T22:07:14.675Z\", \"hypothesis\": \"Temperature ablation (T=0.5, seed=456) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 456 --n_samples 8 --temperature 0.5\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t05_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t05_seed456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:06:52.749Z\", \"metrics\": {\"ner_greedy_f1\": 0.6639, \"ner_oracle_f1\": 0.7437, \"rho_sj_ner\": 0.3279, \"sample_f1_pct_zero\": 10.28, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_026_t05_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:05:35.201Z\", \"updated_at\": \"2026-05-18T22:07:13.198Z\", \"hypothesis\": \"Temperature ablation (T=0.5, seed=123) of Qwen3-8B SciERC N=8 SCS inference to study temperature sensitivity of structural consistency signals.\", \"spec\": {\"command\": \"python scs_inference.py --dataset scierc --seed 123 --n_samples 8 --temperature 0.5\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t05_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_026_t05_seed123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:06:50.703Z\", \"metrics\": {\"ner_greedy_f1\": 0.6611, \"ner_oracle_f1\": 0.7444, \"rho_sj_ner\": 0.3133, \"sample_f1_pct_zero\": 10.09, \"instance_count\": 551, \"n_valid\": 529}}, \"exp_029b\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-17T23:32:18.543Z\", \"updated_at\": \"2026-05-18T22:05:45.856Z\", \"hypothesis\": \"Training convergence modulates degeneracy across datasets. SciERC 10-epoch training should produce higher degeneracy than 5-epoch baseline (17.8%), confirming monotonic epoch-degeneracy relationship across datasets.\", \"parent\": \"ft_002_v2\", \"failure_reason\": \"OOM on cuda:1 due to residual vLLM process (PID 416808) occupying 30.2GB VRAM\", \"reproduce\": {\"finished_at\": \"2026-05-18T02:05:15.948Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T00:55:29.806594+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T01:58:43.646574+00:00\"}, {\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T02:05:20.480884+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"completed_at\": \"2026-05-18T00:56:47.625Z\", \"spec\": {\"pid\": \"441471\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"command\": \"FORCE_TORCHRUN=0 CUDA_VISIBLE_DEVICES=1 llamafactory-cli train train_config_scierc_10ep.yaml\", \"data_path\": \"scierc_uie_train\", \"data_count\": 1861, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_source\": \"Qwen/Qwen3-8B\", \"eval_data\": \"scierc_uie_test\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-10epoch-lora/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_029b.log\"}, \"metrics\": {\"degen_rate\": 0.478, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"conclusion\": \"success\"}, \"exp_029a\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T23:32:17.191Z\", \"updated_at\": \"2026-05-18T22:05:44.959Z\", \"hypothesis\": \"Training convergence modulates degeneracy across datasets. SciERC 3-epoch training should produce lower degeneracy than 5-epoch baseline (17.8%), confirming epoch confound is not Few-NERD-specific.\", \"parent\": \"ft_002_v2\", \"spec\": {\"command\": \"FORCE_TORCHRUN=0 CUDA_VISIBLE_DEVICES=0 bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && llamafactory-cli train train_config_scierc_3ep.yaml\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": 436761, \"data_path\": \"data/scierc_uie_train\", \"data_count\": 1861, \"model_name\": \"Qwen3-8B LoRA rank=32\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-3epoch-lora\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/exp_029a_inference.log\", \"checkpoint_source\": \"Qwen/Qwen3-8B\", \"eval_data\": \"data/scierc_uie_dev\"}, \"reproduce\": {\"finished_at\": \"2026-05-18T00:55:16.392Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-18T00:55:20.617085+00:00\"}]}, \"failure_reason\": \"\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T01:00:18.242Z\", \"metrics\": {\"degen_rate\": 0.064, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}}, \"exp_021_fewnerd_n8_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:03:17.992Z\", \"updated_at\": \"2026-05-18T22:04:50.774Z\", \"hypothesis\": \"Multi-seed replication (seed=456) of Qwen3-8B FewNERD N=8 SCS inference to validate structural consistency signal on fine-grained NER dataset.\", \"spec\": {\"command\": \"python scs_inference.py --dataset fewnerd --seed 456 --n_samples 8 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd\", \"data_count\": 37648, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_021_fewnerd_n8_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_021_fewnerd_n8_seed456_run.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:04:35.573Z\", \"metrics\": {\"degen_rate\": 0.1212, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 37648, \"n_valid\": 32565, \"n_gold_empty\": 5083, \"ner_greedy_f1\": 0.7888, \"ner_oracle_f1\": 0.881, \"rho_fk_ner\": 0.1632, \"rho_sj_ner\": 0.313, \"sample_f1_pct_zero\": 19.32}}, \"exp_021_fewnerd_n8_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:03:16.735Z\", \"updated_at\": \"2026-05-18T22:04:49.470Z\", \"hypothesis\": \"Multi-seed replication (seed=123) of Qwen3-8B FewNERD N=8 SCS inference to validate structural consistency signal on fine-grained NER dataset.\", \"spec\": {\"command\": \"python scs_inference.py --dataset fewnerd --seed 123 --n_samples 8 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd\", \"data_count\": 37648, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_021_fewnerd_n8_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_021_fewnerd_n8_seed123_run.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:04:33.731Z\", \"metrics\": {\"degen_rate\": 0.1312, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 37648, \"n_valid\": 32565, \"n_gold_empty\": 5083, \"ner_greedy_f1\": 0.7885, \"ner_oracle_f1\": 0.8892, \"rho_fk_ner\": 0.1602, \"rho_sj_ner\": 0.3083, \"sample_f1_pct_zero\": 20.39}}, \"exp_002_conll_n16_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:03:15.720Z\", \"updated_at\": \"2026-05-18T22:04:46.954Z\", \"hypothesis\": \"Multi-seed replication (seed=456) of Qwen3-8B CoNLL-2003 N=16 SCS inference to validate structural consistency signal stability across random seeds.\", \"spec\": {\"command\": \"python scs_inference.py --dataset conll2003 --seed 456 --n_samples 16 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 3453, \"model_name\": \"Qwen3-8B\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_002_conll_n16_seed456\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_002_conll_n16_seed456.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:04:31.934Z\", \"metrics\": {\"degen_rate\": 0.5544, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 3453, \"n_valid\": 2756, \"n_gold_empty\": 697, \"ner_greedy_f1\": 0.9074, \"ner_oracle_f1\": 0.9549, \"rho_fk_ner\": 0.4718, \"rho_sj_ner\": 0.4819, \"sample_f1_pct_zero\": 7.02}}, \"exp_002_conll_n16_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T22:03:14.343Z\", \"updated_at\": \"2026-05-18T22:04:45.039Z\", \"hypothesis\": \"Multi-seed replication (seed=123) of Qwen3-8B CoNLL-2003 N=16 SCS inference to validate structural consistency signal stability across random seeds.\", \"spec\": {\"command\": \"python scs_inference.py --dataset conll2003 --seed 123 --n_samples 16 --temperature 1.0\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 3453, \"model_name\": \"Qwen3-8B\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_002_conll_n16_seed123\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_002_conll_n16_seed123.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T22:04:29.992Z\", \"metrics\": {\"degen_rate\": 0.471, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 3453, \"n_valid\": 2756, \"n_gold_empty\": 697, \"ner_greedy_f1\": 0.9068, \"ner_oracle_f1\": 0.9633, \"rho_fk_ner\": 0.4524, \"rho_sj_ner\": 0.4621, \"sample_f1_pct_zero\": 7.54}}, \"exp_017_llama_conll_n16_s456_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:17:04.572Z\", \"updated_at\": \"2026-05-18T20:50:15.047Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA CoNLL N=16 seed456.\", \"parent\": \"exp_017_llama_conll_n16_s456\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 456, \"server\": \"autodl-5090\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n16_s456_r1024\", \"gpu\": \"cuda:2\", \"pid\": \"175870\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"tmux_session\": \"exp_017_llama_conll_n16_s456_r1024\"}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.8672, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 3453, \"n_valid\": 2756, \"n_gold_empty\": 697, \"parse_rate\": 1, \"ner_greedy_f1\": 0.9265, \"ner_oracle_f1\": 0.9499, \"rho_fk_ner\": 0.469, \"rho_sj_ner\": 0.4734, \"rho_vc_ner\": 0.4722, \"rho_em_ner\": 0.4752, \"rho_lp_ner\": 0.3099, \"auroc_fk_ner\": 0.7408, \"auroc_sj_ner\": 0.7428, \"auroc_vc_ner\": 0.7495, \"auroc_em_ner\": 0.7444, \"auroc_lp_ner\": 0.7628, \"auroc_note\": \"median F1=1.0, AUROC uses >=median threshold\", \"rho_note\": \"CORRECTED 2026-05-15: old values (rho_fk=0.8085,rho_sj=0.1895) were inflated/deflated by 697 gold-empty instances. Now uses gold-filtered pipeline (n=2756).\"}, \"checkpoint_path\": \"N/A (inference-only)\", \"log_path\": \"output/exp_017_llama_conll_n16_s456_r1024_run.log\", \"completed_at\": \"2026-05-15T11:45:25.899Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=456 (max_tokens=1024 rerun): cross-model multi-seed validation. Confirms structural>surface ordering is stable across seeds for LLaMA on CoNLL after gold-filtering correction.\"}, \"exp_017_llama_conll_n16_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:17:01.036Z\", \"updated_at\": \"2026-05-18T20:50:11.906Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA CoNLL N=16 seed42.\", \"parent\": \"exp_017_llama_conll_n16\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n16_r1024\", \"gpu\": \"cuda:1\", \"pid\": \"175734\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"tmux_session\": \"exp_017_llama_conll_n16_r1024\"}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.8647, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"instance_count\": 3453, \"n_valid\": 2756, \"n_gold_empty\": 697, \"parse_rate\": 1, \"ner_greedy_f1\": 0.9265, \"ner_oracle_f1\": 0.9499, \"rho_fk_ner\": 0.4752, \"rho_sj_ner\": 0.4836, \"rho_vc_ner\": 0.4746, \"rho_em_ner\": 0.4818, \"rho_lp_ner\": 0.3136, \"auroc_fk_ner\": 0.7467, \"auroc_sj_ner\": 0.7496, \"auroc_vc_ner\": 0.7529, \"auroc_em_ner\": 0.7508, \"auroc_lp_ner\": 0.7661, \"auroc_note\": \"median F1=1.0, AUROC uses >=median threshold\", \"rho_note\": \"CORRECTED 2026-05-15: old values (rho_fk=0.8095,rho_sj=0.1815) were inflated/deflated by 697 gold-empty instances. Now uses gold-filtered pipeline (n=2756).\"}, \"checkpoint_path\": \"N/A (inference-only)\", \"log_path\": \"output/exp_017_llama_conll_n16_r1024_run.log\", \"completed_at\": \"2026-05-15T11:45:23.213Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=42 (max_tokens=1024 rerun): cross-model baseline on CoNLL. Establishes LLaMA signal rankings after gold-filtering correction (fixes inflated FK ρ from gold-empty instances).\"}, \"exp_018_llama_scierc_seed456_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:12:43.492Z\", \"updated_at\": \"2026-05-18T20:50:04.988Z\", \"spec\": {\"hypothesis\": \"D066 fresh rerun: LLaMA SciERC seed=456 with explicit max_tokens=1024. Replaces exp_007 re-analysis for clean 3-seed comparison.\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed456_r1024\\\"\", \"server\": \"autodl-5090\", \"seed\": 456, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"model_path\": \"checkpoints/llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"subtask\": \"joint\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"N\": 8, \"T\": 1, \"max_tokens\": 1024, \"is_new_inference\": true, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed456_r1024/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed456_r1024.log\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": \"157584\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed456_r1024.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed456_r1024\\\"\", \"finished_at\": \"2026-05-15T06:18:22.307Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T06:18:24.880896+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_018_llama_scierc_seed456_r1024\", \"metrics\": {\"degen_rate\": 0.2741, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"ner_greedy_f1\": 0.6597, \"ner_oracle_f1\": 0.7683, \"ner_oracle_headroom\": 0.1086, \"ner_cond_rho_fk\": 0.1472, \"ner_cond_rho_sj\": 0.2718, \"ner_cond_rho_logprob\": 0.083, \"ner_logprob_auroc_cond\": 0.5485, \"re_greedy_f1\": 0.4338, \"re_oracle_f1\": 0.5834, \"re_oracle_headroom\": 0.1496, \"re_cond_rho_fk\": 0.2107, \"re_cond_rho_sj\": 0.3898, \"re_cond_rho_logprob\": 0.1252, \"re_logprob_auroc_cond\": 0.6119, \"ner_structural_beats_logprob\": true, \"re_structural_beats_logprob\": true}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:21:45.350Z\", \"hypothesis\": \"LLaMA SciERC seed=456 (max_tokens=1024): multi-seed cross-model validation. Complements seed42 for LLaMA 3-seed protocol on SciERC NER+RE signal rankings.\"}, \"exp_018_llama_scierc_seed42_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:09:57.155Z\", \"updated_at\": \"2026-05-18T20:50:00.335Z\", \"spec\": {\"hypothesis\": \"D066 fresh rerun: LLaMA SciERC seed=42 with explicit max_tokens=1024. Replaces exp_007_llama_inference for clean 3-seed comparison.\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 42 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed42_r1024\\\"\", \"server\": \"autodl-5090\", \"seed\": 42, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"model_path\": \"checkpoints/llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"subtask\": \"joint\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"N\": 8, \"T\": 1, \"max_tokens\": 1024, \"is_new_inference\": true, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed42_r1024/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed42_r1024.log\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"156809\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed42_r1024.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 42 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed42_r1024\\\"\", \"finished_at\": \"2026-05-15T06:15:47.963Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T06:15:50.613872+00:00\"}]}, \"metrics\": {\"degen_rate\": 0.2495, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"ner\": {\"full\": {\"SJ\": {\"rho\": 0.3096, \"tau\": 0.2288, \"auroc\": 0.6683}, \"FK\": {\"rho\": 0.2352, \"tau\": 0.1759, \"auroc\": 0.6069}, \"logprob\": {\"rho\": 0.1503, \"tau\": 0.1087, \"auroc\": 0.5318}, \"EM\": {\"rho\": 0.2587, \"tau\": 0.1966, \"auroc\": 0.7174}, \"voting_conf\": {\"rho\": 0.4053, \"tau\": 0.3042, \"auroc\": 0.6967}}, \"conditional\": {\"SJ\": {\"rho\": 0.2718, \"tau\": null, \"auroc\": 0.6565}, \"FK\": {\"rho\": 0.1472, \"tau\": null, \"auroc\": 0.5866}, \"logprob\": {\"rho\": 0.081, \"tau\": null, \"auroc\": 0.5129}, \"EM\": {\"rho\": 0.3165, \"tau\": null, \"auroc\": 0.7244}, \"voting_conf\": {\"rho\": 0.3078, \"tau\": null, \"auroc\": 0.6714}}, \"greedy_f1\": 0.6607, \"oracle_f1\": 0.7781, \"n_full\": 529, \"n_cond\": 478}, \"re\": {\"full\": {\"SJ\": {\"rho\": 0.2748, \"tau\": 0.2102, \"auroc\": 0.7244}, \"FK\": {\"rho\": 0.3027, \"tau\": 0.2337, \"auroc\": 0.691}, \"logprob\": {\"rho\": 0.3163, \"tau\": 0.233, \"auroc\": 0.6313}, \"EM\": {\"rho\": 0.1681, \"tau\": 0.1275, \"auroc\": 0.7697}, \"voting_conf\": {\"rho\": 0.384, \"tau\": 0.2965, \"auroc\": 0.7337}}, \"conditional\": {\"SJ\": {\"rho\": 0.3461, \"tau\": null, \"auroc\": 0.7233}, \"FK\": {\"rho\": 0.1969, \"tau\": null, \"auroc\": 0.6684}, \"logprob\": {\"rho\": 0.0888, \"tau\": null, \"auroc\": 0.5556}, \"EM\": {\"rho\": 0.4969, \"tau\": null, \"auroc\": 0.819}, \"voting_conf\": {\"rho\": 0.3433, \"tau\": null, \"auroc\": 0.7003}}, \"greedy_f1\": 0.4319, \"oracle_f1\": 0.5775, \"n_full\": 397, \"n_cond\": 251}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:21:47.660Z\", \"hypothesis\": \"LLaMA SciERC seed=42 (max_tokens=1024): cross-model validation on SciERC. Establishes LLaMA NER signal rankings on same dataset as Qwen for direct model-family comparison.\"}, \"exp_002_conll_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:12:16.041Z\", \"updated_at\": \"2026-05-18T20:49:50.398Z\", \"spec\": {\"hypothesis\": \"Qwen CoNLL-2003 N=16: cross-dataset N-scaling comparison with SciERC N=16\", \"plan_id\": \"exp-002\", \"parent\": \"exp_002_ner_conll2003\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_002_conll_n16\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-merged\", \"seed\": 42}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.4844, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"N\": 16, \"dataset\": \"conll2003\", \"subtask\": \"ner\", \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2614, \"greedy_f1\": 0.907, \"full\": {\"SJ_rho\": 0.4496, \"FK_rho\": 0.3928, \"logprob_rho\": 0.3146, \"EM_rho\": 0.4627, \"voting_conf_rho\": 0.4286, \"SJ_AUROC\": 0.8264, \"FK_AUROC\": 0.7821, \"logprob_AUROC\": 0.7531, \"EM_AUROC\": 0.8409, \"voting_conf_AUROC\": 0.8071, \"SJ_ECE\": 0.0747, \"FK_ECE\": 0.1786, \"logprob_ECE\": 0.2031, \"EM_ECE\": 0.0786, \"voting_conf_ECE\": 0.529}, \"conditional\": {\"SJ_rho\": 0.4208, \"FK_rho\": 0.3494, \"logprob_rho\": 0.3756, \"EM_rho\": 0.4658, \"voting_conf_rho\": 0.3654, \"SJ_AUROC\": 0.8405, \"FK_AUROC\": 0.7819, \"logprob_AUROC\": 0.8259, \"EM_AUROC\": 0.8781, \"voting_conf_AUROC\": 0.7951, \"SJ_ECE\": 0.0982, \"FK_ECE\": 0.1899, \"logprob_ECE\": 0.2504, \"EM_ECE\": 0.0997, \"voting_conf_ECE\": 0.6096}, \"n8_vs_n16_delta_rho_full\": {\"SJ\": 0.0139, \"FK\": -0.007, \"logprob\": -0.0011, \"EM\": 0.012, \"voting_conf\": 0.0049}}, \"checkpoint_path\": \"output/exp_002_conll_n16/samples.jsonl\", \"log_path\": \"output/exp_002_conll_n16.log\", \"completed_at\": \"2026-05-14T18:58:40.473Z\", \"hypothesis\": \"CoNLL N=16 NER: cross-dataset validation on high-performance NER dataset. Tests if structural signals retain advantage when base model performance is already high (greedy F1 > 0.9).\"}, \"exp_012_rerun_1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:11:33.777Z\", \"updated_at\": \"2026-05-18T20:49:42.395Z\", \"spec\": {\"hypothesis\": \"Verify if max_tokens=512 truncation inflated Table 1 N=8 SciERC signal values. Rerun with max_tokens=1024 for clean comparison.\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"parent\": \"exp_012_logprob_baseline\", \"data_count\": 551, \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_012_rerun_1024\", \"checkpoint_path\": \"output/exp_012_rerun_1024/\", \"log_path\": \"output/exp_012_rerun_1024/run.log\", \"data_path\": \"data/scierc/processed_data\"}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.1777, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"ner_full\": {\"n\": 529, \"SJ\": {\"rho\": 0.3599, \"tau\": 0.2646, \"AUROC\": 0.6917, \"ECE\": 0.4531, \"rho_ci95\": [0.2732, 0.4389], \"AUROC_ci95\": [0.6304, 0.7406]}, \"FK\": {\"rho\": 0.2665, \"tau\": 0.1974, \"AUROC\": 0.629, \"ECE\": 0.4512, \"rho_ci95\": [0.1743, 0.3486], \"AUROC_ci95\": [0.5612, 0.6882]}, \"logprob\": {\"rho\": 0.2052, \"tau\": 0.1478, \"AUROC\": 0.5783, \"ECE\": 0.7064, \"rho_ci95\": [0.1171, 0.2904], \"AUROC_ci95\": [0.5179, 0.6387]}, \"EM\": {\"rho\": 0.2945, \"tau\": 0.2208, \"AUROC\": 0.7493, \"ECE\": 0.3526, \"rho_ci95\": [0.2094, 0.37], \"AUROC_ci95\": [0.7002, 0.7928]}, \"voting_conf\": {\"rho\": 0.3792, \"tau\": 0.2805, \"AUROC\": 0.6841, \"ECE\": 0.3807, \"rho_ci95\": [0.2972, 0.4486], \"AUROC_ci95\": [0.6249, 0.7366]}}, \"ner_cond\": {\"n\": 477, \"SJ\": {\"rho\": 0.3113, \"tau\": 0.2257, \"AUROC\": 0.6772, \"ECE\": 0.4416, \"rho_ci95\": [0.2353, 0.3959], \"AUROC_ci95\": [0.621, 0.7337]}, \"FK\": {\"rho\": 0.1761, \"tau\": 0.1284, \"AUROC\": 0.6078, \"ECE\": 0.4389, \"rho_ci95\": [0.0839, 0.2665], \"AUROC_ci95\": [0.5442, 0.6709]}, \"logprob\": {\"rho\": 0.1538, \"tau\": 0.1111, \"AUROC\": 0.5633, \"ECE\": 0.6803, \"rho_ci95\": [0.0637, 0.2424], \"AUROC_ci95\": [0.5032, 0.6232]}, \"EM\": {\"rho\": 0.3596, \"tau\": 0.2735, \"AUROC\": 0.7556, \"ECE\": 0.3257, \"rho_ci95\": [0.2819, 0.4408], \"AUROC_ci95\": [0.7011, 0.8107]}, \"voting_conf\": {\"rho\": 0.3, \"tau\": 0.2189, \"AUROC\": 0.6618, \"ECE\": 0.3746, \"rho_ci95\": [0.2168, 0.3836], \"AUROC_ci95\": [0.6004, 0.7201]}}, \"re_full\": {\"n\": 397, \"SJ\": {\"rho\": 0.2503, \"tau\": 0.1878, \"AUROC\": 0.6702, \"ECE\": 0.3865}, \"FK\": {\"rho\": 0.2752, \"tau\": 0.2117, \"AUROC\": 0.6089, \"ECE\": 0.4405}, \"logprob\": {\"rho\": 0.2662, \"tau\": 0.1951, \"AUROC\": 0.6005, \"ECE\": 0.7694}, \"EM\": {\"rho\": 0.1344, \"tau\": 0.1081, \"AUROC\": 0.7059, \"ECE\": 0.3548}, \"voting_conf\": {\"rho\": 0.3498, \"tau\": 0.2663, \"AUROC\": 0.6935, \"ECE\": 0.2724}}, \"re_cond\": {\"n\": 238, \"SJ\": {\"rho\": 0.2457, \"tau\": 0.1811, \"AUROC\": 0.6463, \"ECE\": 0.2941}, \"FK\": {\"rho\": 0.1139, \"tau\": 0.0876, \"AUROC\": 0.551, \"ECE\": 0.3424}, \"logprob\": {\"rho\": 0.0112, \"tau\": 0.0051, \"AUROC\": 0.5186, \"ECE\": 0.6464}, \"EM\": {\"rho\": 0.4165, \"tau\": 0.3256, \"AUROC\": 0.7515, \"ECE\": 0.2232}, \"voting_conf\": {\"rho\": 0.2409, \"tau\": 0.178, \"AUROC\": 0.642, \"ECE\": 0.207}}, \"delta_vs_512_ner_full_rho\": {\"SJ\": 0.0034, \"FK\": 0.0014, \"EM\": 0.0379, \"voting_conf\": -0.1226, \"logprob\": 0.0656}, \"provenance_note\": \"exp_015_v2 scierc_n8_logprob used exp_012_logprob (max_tokens=512 truncated data). voting_conf was inflated 0.502→0.379, logprob was suppressed 0.140→0.205.\"}, \"completed_at\": \"2026-05-14T23:10:33.075Z\", \"hypothesis\": \"Canonical SciERC baseline with max_tokens=1024: Qwen3-8B ft_002_v2, N=8, T=1.0, seed=42, joint NER+RE. Establishes ground-truth ρ rankings and selection F1 for all 5 signals under correct generation length.\"}, \"exp_llama_scierc_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:15:27.504Z\", \"updated_at\": \"2026-05-18T20:49:10.758Z\", \"hypothesis\": \"LLaMA-3.1-8B on SciERC with seed=456 will show consistent 5-signal ranking patterns (SJ/FK > logprob) and DGS selection gains comparable to seed=42 and seed=123, confirming cross-seed stability.\", \"spec\": {\"command\": \"python3 code/analyze_llama_scierc_seed456_5signal.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_018_llama_scierc_seed456/samples.jsonl\", \"data_count\": 551, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": 456, \"checkpoint_source\": \"same as seed123\", \"eval_data\": \"SciERC test (551 instances)\", \"checkpoint_path\": \"output/exp_018_llama_scierc_seed456/5signal_dgs_report.json\", \"log_path\": \"output/exp_018_llama_scierc_seed456/run.log\"}, \"metrics\": {\"greedy_f1\": 0.6457, \"oracle_f1\": 0.7574, \"headroom\": 0.1117, \"dgs_f1\": 0.6454, \"degen_rate\": 0.2741, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"rho_SJ_full\": 0.3663, \"rho_FK_full\": 0.3115, \"rho_logprob_full\": 0.1911, \"rho_EM_full\": 0.3088, \"rho_vc_full\": 0.4135, \"auroc_SJ_full\": 0.7061, \"auroc_EM_full\": 0.7538, \"n_valid\": 529, \"n_conditional\": 478}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T19:16:00.973Z\"}, \"exp_007_llama_scierc_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:10:26.278Z\", \"updated_at\": \"2026-05-18T20:49:08.934Z\", \"name\": \"LLaMA-3.1-8B SciERC NER inference seed=123\", \"hypothesis\": \"Structural consistency signals (SJ, FK) correlate with entity F1 for LLaMA-8B on SciERC at seed=123, and DGS selection improves over greedy baseline\", \"spec\": {\"command\": \"python3 code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed123\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"LLaMA-3.1-8B-Instruct (SciERC LoRA fine-tuned)\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/llama3.1-8b-scierc-merged\", \"checkpoint_path\": \"checkpoints/llama3.1-8b-scierc-lora\", \"log_path\": \"output/exp_018_llama_scierc_seed123/report.json\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T19:11:30.781Z\", \"metrics\": {\"greedy_f1\": 0.6454, \"oracle_f1\": 0.7657, \"headroom\": 0.1204, \"degen_rate\": 0.2665, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"dgs_delta_pp\": -0.38, \"rho_SJ_full\": 0.3552, \"rho_voting_conf_full\": 0.4193, \"auroc_SJ_full\": 0.7092, \"auroc_EM_full\": 0.7468}}, \"exp_qwen3_4b_conll_scs_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:08:28.512Z\", \"updated_at\": \"2026-05-18T20:49:06.922Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-4b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_qwen3_4b_conll_scs_inference\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"222184\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_qwen3_4b_conll_scs_inference/report.json\", \"submitted_at\": \"2026-05-15T19:10:19.757Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-4b-conll2003-merged\", \"wall_clock_seconds\": 523.8, \"gpu_hours\": 0.15}, \"metrics\": {\"greedy_f1\": 0.9251, \"oracle_f1\": 0.9408, \"oracle_headroom_pp\": 1.57, \"SJ_rho_full\": 0.4045, \"SJ_rho_cond\": 0.4306, \"FK_rho_full\": 0.3961, \"FK_rho_cond\": 0.42, \"LP_rho_full\": 0.3186, \"LP_rho_cond\": 0.3378, \"LP_auroc_full\": 0.7689, \"LP_auroc_cond\": 0.8153, \"fleiss_kappa_mean\": 0.9349, \"soft_jaccard_mean\": 0.9754, \"structural_beats_surface\": true, \"rho_advantage_pp\": 0.84, \"n_instances\": 3453, \"n_gold_empty_filtered\": 697, \"n_greedy_f1_zero_filtered\": 112, \"verdict\": \"MARGINAL\", \"degen_rate\": 0.9057, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:19:03.585Z\", \"notes\": \"4B CoNLL SCS inference completed. SJ>FK>LP ordering preserved at 4B scale (rho 0.405>0.396>0.319). Greedy F1=0.925 outperforms 8B (0.907), but SJ rho is lower (0.405 vs 0.450 at 8B N=16). Structural beats surface confirmed (+0.84pp). Verdict MARGINAL due to small oracle headroom (1.57pp) — the model is already very good at CoNLL, leaving little room for selection improvement.\", \"hypothesis\": \"CoNLL 4B SCS inference (checkpoint-3800): cross-scale evidence for correlation-selection gap. Tests if structural>surface ranking and LP compression hold at smaller model scale on high-degeneracy dataset.\"}, \"exp_qwen3_4b_conll_scs_inference_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:41:33.501Z\", \"updated_at\": \"2026-05-18T20:49:03.705Z\", \"hypothesis\": \"CoNLL 4B SCS inference with best checkpoint-4200 (from resume training). Scale ablation: cross-scale evidence for correlation-selection gap. Compare vs v1 (ckpt-3800 baseline: greedy_f1=0.9251, SJ_rho=0.4045).\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-4b-conll2003-merged-ckpt4200 --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_qwen3_4b_conll_scs_inference_v2\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"Qwen3-4B (LoRA checkpoint-4200 merged)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/qwen3-4b-conll2003-lora/checkpoint-4200\", \"gpu\": [\"cuda:1\"], \"checkpoint_path\": \"checkpoints/qwen3-4b-conll2003-merged-ckpt4200\", \"log_path\": \"/tmp/infer_4b_conll_v2.log\", \"account\": \"root\", \"backend\": \"tmux\", \"tmux_session\": \"exp_4b_conll_scs_v2\"}, \"metrics\": {\"greedy_f1\": 0.9234, \"oracle_f1\": 0.9404, \"oracle_headroom_pp\": 1.7, \"SJ_rho_full\": 0.4217, \"SJ_rho_cond\": 0.459, \"FK_rho_full\": 0.4181, \"FK_rho_cond\": 0.4538, \"LP_rho_full\": 0.3313, \"LP_rho_cond\": 0.3487, \"LP_auroc_full\": 0.7761, \"LP_auroc_cond\": 0.8209, \"n_instances\": 3453, \"verdict\": \"MARGINAL\", \"degen_rate\": 0.9057, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:54:14.575Z\", \"notes\": \"Gold-filter audit (2026-05-16): CONSISTENT. _full metrics (SJ_rho=0.4217, FK_rho=0.4181) are computed on gold-filtered set (n=2756), same as 8B Table 1 values. _full does NOT mean all 3453 instances — it means gold-nonempty instances. _cond further excludes greedy-F1=0 (n=2641). Confirmed via run_mvp_pilot.py source code and report.json n values.\"}, \"exp_qwen3_4b_scierc_scs_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:45:33.384Z\", \"updated_at\": \"2026-05-18T20:49:01.260Z\", \"hypothesis\": \"SciERC 4B SCS inference after v4 finetune merge. Complete 2x2 scale matrix (4B SciERC cell). Cross-scale + cross-task evidence for correlation-selection gap.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-4b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_qwen3_4b_scierc_scs_inference\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-4b-scierc-merged (checkpoint-400)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/qwen3-4b-scierc-merged\", \"eval_data\": \"scierc test set\"}, \"metrics\": {\"ner_greedy_f1\": 0.6612, \"ner_oracle_f1\": 0.7839, \"ner_headroom_pp\": 12.28, \"ner_SJ_rho\": 0.4221, \"ner_FK_rho\": 0.3258, \"ner_LP_rho\": 0.28, \"re_greedy_f1\": 0.4136, \"re_oracle_f1\": 0.5846, \"re_headroom_pp\": 17.1, \"re_SJ_rho\": 0.2673, \"re_FK_rho\": 0.3593, \"re_LP_rho\": 0.3512, \"re_sample_f1_pct_zero\": 0.476, \"re_LP_rho_cond\": 0.1135, \"re_LP_rho_cond_p\": 0.074, \"degen_rate\": 0.104, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"checkpoint_path\": \"checkpoints/qwen3-4b-scierc-merged/\", \"log_path\": \"/tmp/exp_qwen3_4b_scierc_scs_inference.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T20:00:03.730Z\"}, \"exp_027_fewnerd_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T05:28:57.036Z\", \"updated_at\": \"2026-05-18T20:48:58.455Z\", \"spec\": {\"hypothesis\": \"LP selection scales with N in low-degeneracy regime: N=16 should yield LP Δ > +2pp (vs N=8 +1.36pp) on Few-NERD (10% degen), because more samples increase oracle headroom while LP ranking remains effective.\", \"parent\": \"exp_021_fewnerd_full\", \"model_name\": \"qwen3-8b-fewnerd-exp021-merged\", \"data_path\": \"data/fewnerd_n16_subset/test.json\", \"data_count\": 5000, \"seed\": 42, \"server\": \"autodl-5090\", \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-fewnerd-exp021-merged --data_dir data/fewnerd_n16_subset --dataset fewnerd --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --collect_logprobs --start_index {0,1250,2500,3750} --end_index {1250,2500,3750,5000} --output_dir output/exp_027_fewnerd_n16/shard_{0-3}\", \"checkpoint_path\": \"output/exp_027_fewnerd_n16/sampled_results.jsonl\", \"log_path\": \"output/exp_027_fewnerd_n16/\"}, \"conclusion\": \"success\", \"metrics\": {\"LP_delta_pp\": 1.88, \"LP_delta_95CI\": [1.41, 2.37], \"degen_rate\": 0.0706, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"greedy_f1\": 0.7478, \"lp_sel_f1\": 0.7666, \"oracle_f1\": 0.902, \"headroom_pp\": 15.42, \"all_8_types_positive\": true, \"n_instances\": 5000, \"N_samples\": 16, \"bootstrap_p\": \"<0.001\"}, \"hypothesis\": \"LP selection scales with N in low-degeneracy regime: N=16 should yield LP Δ > +2pp (vs N=8 +1.36pp) on Few-NERD (10% degen), because more samples increase oracle headroom while LP ranking remains effective.\", \"completed_at\": \"2026-05-17T05:46:48.460Z\"}, \"exp_026_t12\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T13:18:18.780Z\", \"updated_at\": \"2026-05-18T20:48:24.965Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --n_samples 8 --temperature 1.2 --seed 42 --max_tokens 1024 --collect_logprobs --output_dir output/exp_026_t12\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"log_path\": \"output/exp_026_t12.log\", \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\"}, \"conclusion\": \"success\", \"metrics\": {\"temperature\": 1.2, \"task\": \"T-ablation\", \"degen_rate\": 0.1493, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"completed_at\": \"2026-05-16T14:26:37.648Z\", \"hypothesis\": \"Temperature T=1.2 ablation on SciERC: test if higher temperature increases sample diversity (lower degeneracy) and LP discriminative range, potentially improving LP selection while maintaining structural signal effectiveness.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_026_t08\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T12:57:46.027Z\", \"updated_at\": \"2026-05-18T20:48:24.112Z\", \"spec\": {\"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"log_path\": \"output/exp_026_t08/run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"temperature\": 0.8, \"task\": \"T-ablation\", \"degen_rate\": 0.2382, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"completed_at\": \"2026-05-16T14:26:36.243Z\", \"hypothesis\": \"Temperature T=0.8 ablation on SciERC: test if lower temperature increases LP compression (narrower range) while structural signals remain robust, supporting the claim that LP compression is intrinsic rather than temperature-driven.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_026_t05\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T12:19:35.753Z\", \"updated_at\": \"2026-05-18T20:48:23.339Z\", \"spec\": {\"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"log_path\": \"output/exp_026_t05/run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"temperature\": 0.5, \"task\": \"T-ablation\", \"degen_rate\": 0.414, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}, \"completed_at\": \"2026-05-16T14:26:34.808Z\", \"hypothesis\": \"Temperature T=0.5 ablation on SciERC: extreme low temperature expected to maximally compress LP scores and increase degeneracy, providing upper-bound evidence for LP compression as model-intrinsic phenomenon.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_026_T12\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T09:38:31.060Z\", \"updated_at\": \"2026-05-18T20:48:22.668Z\", \"hypothesis\": \"T=1.2 will decrease degeneracy rate and expand LP range vs T=1.0, but may degrade generation quality (lower greedy F1). Tests whether reducing degeneracy via higher T recovers selection headroom or if quality degradation offsets the benefit.\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-17T09:39:51.733Z\", \"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.2 --seed 42 --output_dir output/exp_026_T12/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T12_run.log\\\"\", \"finished_at\": \"2026-05-17T09:48:04.019Z\", \"training_hours\": 0.14}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.2 --seed 42 --output_dir output/exp_026_T12/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T12_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"381369\", \"log_path\": \"output/exp_026_T12_run.log\", \"submitted_at\": \"2026-05-17T09:41:39.393Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"output/exp_026_T12/\", \"wall_clock_seconds\": 1114.4, \"gpu_hours\": 0.31}, \"pid\": \"381369\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_T12.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T09:48:08.312470+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.1493, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"lp_range_mean\": 0.075, \"lp_range_std\": 0.059, \"within_instance_rho_mean\": 0.2245, \"within_instance_rho_median\": 0.3152, \"within_instance_rho_valid_pct\": 0.875, \"greedy_f1\": 0.62, \"oracle_f1\": 0.758, \"lp_sel_f1\": 0.621, \"sj_sel_f1\": 0.597, \"em_sel_f1\": 0.596, \"vc_sel_f1\": 0.582, \"sj_rho\": 0.384, \"fk_rho\": 0.386, \"lp_rho\": 0.182, \"vc_rho\": 0.342, \"sj_auroc\": 0.683, \"lp_auroc\": 0.566}, \"completed_at\": \"2026-05-17T10:00:13.771Z\"}, \"exp_026_T08\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T09:38:29.602Z\", \"updated_at\": \"2026-05-18T20:48:21.975Z\", \"hypothesis\": \"T=0.8 will show intermediate degeneracy between T=0.5 and T=1.0, establishing a monotonic degeneracy-temperature relationship. If LP selection improves at T=0.8 vs T=1.0, it identifies the optimal operating point for the selection mechanism.\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-17T09:39:50.780Z\", \"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.8 --seed 42 --output_dir output/exp_026_T08/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T08_run.log\\\"\", \"finished_at\": \"2026-05-17T09:47:56.543Z\", \"training_hours\": 0.13}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.8 --seed 42 --output_dir output/exp_026_T08/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T08_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"380680\", \"log_path\": \"output/exp_026_T08_run.log\", \"submitted_at\": \"2026-05-17T09:41:20.812Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"output/exp_026_T08/\", \"wall_clock_seconds\": 1131.4, \"gpu_hours\": 0.31}, \"pid\": \"380680\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_T08.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T09:48:02.635244+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.2382, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"lp_range_mean\": 0.043, \"lp_range_std\": 0.042, \"within_instance_rho_mean\": 0.1701, \"within_instance_rho_median\": 0.2635, \"within_instance_rho_valid_pct\": 0.728, \"greedy_f1\": 0.616, \"oracle_f1\": 0.737, \"lp_sel_f1\": 0.627, \"sj_sel_f1\": 0.619, \"em_sel_f1\": 0.611, \"vc_sel_f1\": 0.603, \"sj_rho\": 0.378, \"fk_rho\": 0.34, \"lp_rho\": 0.212, \"vc_rho\": 0.352, \"sj_auroc\": 0.662, \"lp_auroc\": 0.571}, \"completed_at\": \"2026-05-17T10:00:12.248Z\"}, \"exp_026_T05\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T09:38:28.066Z\", \"updated_at\": \"2026-05-18T20:48:16.286Z\", \"hypothesis\": \"T=0.5 will increase degeneracy rate (more deterministic outputs) and compress LP range on SciERC, reducing selection headroom. Maps the low-temperature end of the degeneracy-temperature frontier, validating that degeneracy is regime-dependent on sampling temperature.\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.5 --seed 42 --output_dir output/exp_026_T05/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T05_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"380188\", \"log_path\": \"output/exp_026_T05_run.log\", \"submitted_at\": \"2026-05-17T09:40:51.787Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"checkpoint_path\": \"output/exp_026_T05/\", \"wall_clock_seconds\": 1158.3, \"gpu_hours\": 0.32}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"pid\": \"380188\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_T05.log\", \"reproduce\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.5 --seed 42 --output_dir output/exp_026_T05/ --num_test 9999 --collect_logprobs 2>&1 | tee output/exp_026_T05_run.log\\\"\", \"finished_at\": \"2026-05-17T09:47:31.332Z\"}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T09:47:35.127151+00:00\"}]}, \"conclusion\": \"success\", \"metrics\": {\"degen_rate\": 0.414, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\", \"lp_range_mean\": 0.022, \"lp_range_std\": 0.021, \"within_instance_rho_mean\": 0.1306, \"within_instance_rho_median\": 0.2182, \"within_instance_rho_valid_pct\": 0.597, \"greedy_f1\": 0.617, \"oracle_f1\": 0.71, \"lp_sel_f1\": 0.622, \"sj_sel_f1\": 0.622, \"em_sel_f1\": 0.619, \"vc_sel_f1\": 0.61, \"sj_rho\": 0.333, \"fk_rho\": 0.341, \"lp_rho\": 0.208, \"vc_rho\": 0.353, \"sj_auroc\": 0.644, \"lp_auroc\": 0.577}, \"completed_at\": \"2026-05-17T10:00:10.083Z\"}, \"exp_017_llama_conll_n16_s123_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:17:02.953Z\", \"updated_at\": \"2026-05-18T20:47:52.122Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA CoNLL N=16 seed123.\", \"parent\": \"exp_017_llama_conll_n16_s123\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 123, \"server\": \"autodl-5090\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n16_s123_r1024\", \"data_path\": \"data/conll2003\", \"data_count\": 3453}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T01:20:51.219Z\", \"notes\": \"Output exists on autodl-5090. Registry status corrected from killed to success.\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=123 (max_tokens=1024 rerun): cross-model multi-seed validation. Confirms structural>surface ordering is stable across seeds for LLaMA on CoNLL after gold-filtering correction.\", \"metrics\": {\"degen_rate\": 0.8636, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}}, \"exp_018_llama_scierc_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:14.370Z\", \"updated_at\": \"2026-05-18T20:47:51.435Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: LLaMA SciERC N=8 seed=123, max_tokens=1024. Verify signal stability across seeds.\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --seed 123 --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp_018_llama_scierc_seed123\", \"server\": \"autodl-5090\", \"seed\": 123, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed123/\", \"log_path\": \"output/exp_018_llama_scierc_seed123.log\", \"samples_md5\": \"072eeca68236d46b4c5c84b945209abc\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:08:04.855Z\", \"hypothesis\": \"LLaMA SciERC seed=123: multi-seed cross-model validation. Complements seed42 for LLaMA 3-seed protocol on SciERC NER+RE signal rankings.\", \"metrics\": {\"degen_rate\": 0.2665, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}}, \"exp_018_qwen_scierc_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:13.570Z\", \"updated_at\": \"2026-05-18T20:47:50.032Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: Qwen SciERC N=8 seed=456, max_tokens=1024. Verify signal stability across seeds.\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --seed 456 --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp_018_qwen_scierc_seed456\", \"server\": \"autodl-5090\", \"seed\": 456, \"model_name\": \"Qwen3-8B-SciERC-merged-v2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"checkpoint_path\": \"output/exp_018_qwen_scierc_seed456/\", \"log_path\": \"output/exp_018_qwen_scierc_seed456/run.log\", \"samples_md5\": \"46d0de47ad7693c07e7df3a77c90c3be\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:08:03.898Z\", \"hypothesis\": \"Qwen SciERC seed=456: multi-seed Qwen validation. Part of 3-seed protocol (seed42=exp_012_rerun_1024, seed123, seed456) for statistical significance of signal rankings.\", \"metrics\": {\"degen_rate\": 0.2042, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}}, \"exp_018_qwen_scierc_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:12.747Z\", \"updated_at\": \"2026-05-18T20:47:49.306Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: Qwen SciERC N=8 seed=123, max_tokens=1024. Verify signal stability across seeds.\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --seed 123 --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp_018_qwen_scierc_seed123\", \"server\": \"autodl-5090\", \"seed\": 123, \"model_name\": \"Qwen3-8B-SciERC-merged-v2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"checkpoint_path\": \"output/exp_018_qwen_scierc_seed123/\", \"log_path\": \"output/exp_018_qwen_scierc_seed123.log\", \"samples_md5\": \"866a59581dea56f4633149f0b18a31ae\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T06:08:02.954Z\", \"hypothesis\": \"Qwen SciERC seed=123: multi-seed Qwen validation. Part of 3-seed protocol (seed42=exp_012_rerun_1024, seed123, seed456) for statistical significance of signal rankings.\", \"metrics\": {\"degen_rate\": 0.172, \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"}}, \"exp_epoch_dgs_analysis\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:59:57.921Z\", \"updated_at\": \"2026-05-18T20:01:46.134Z\", \"hypothesis\": \"DGS benefit is strictly monotonic with degeneracy rate: higher degeneracy → greater DGS improvement, validating that degeneracy rate is the key gating signal\", \"spec\": {\"command\": \"python3 code/epoch_dgs_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/struct_self_consist_ie/data/\", \"data_count\": \"all datasets\", \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/struct_self_consist_ie/output/epoch_dgs_analysis_results.json\", \"log_path\": \"/root/struct_self_consist_ie/output/epoch_dgs_analysis_results.json\", \"completed_at\": \"2026-05-18T20:01:46.134Z\"}, \"exp_diagnostic_calibration\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:59:56.064Z\", \"updated_at\": \"2026-05-18T20:01:44.364Z\", \"hypothesis\": \"A 3-indicator regression model (degeneracy rate, LP-F1 correlation, LP range) can quantitatively predict the optimal LP selection delta for unseen instances\", \"spec\": {\"command\": \"python3 code/diagnostic_calibration.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/struct_self_consist_ie/data/\", \"data_count\": \"all datasets\", \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/struct_self_consist_ie/output/diagnostic_calibration_results.json\", \"log_path\": \"/root/struct_self_consist_ie/output/diagnostic_calibration_results.json\", \"completed_at\": \"2026-05-18T20:01:44.364Z\"}, \"exp_adaptive_temperature\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:59:52.771Z\", \"updated_at\": \"2026-05-18T20:01:42.646Z\", \"hypothesis\": \"Adjusting sampling temperature based on instance-level confidence indicators can improve output diversity-quality tradeoff\", \"spec\": {\"command\": \"python3 code/adaptive_temperature.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/struct_self_consist_ie/data/\", \"data_count\": \"all datasets\", \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/struct_self_consist_ie/output/adaptive_temperature_results.json\", \"log_path\": \"/root/struct_self_consist_ie/output/adaptive_temperature_results.json\", \"completed_at\": \"2026-05-18T20:01:42.646Z\"}, \"exp_entity_consensus\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:59:50.628Z\", \"updated_at\": \"2026-05-18T20:01:40.869Z\", \"hypothesis\": \"Constructing new output from N samples using entity frequency thresholds and LP-weighted decisions can capture complementary information that single-sample selection misses\", \"spec\": {\"command\": \"python3 code/entity_consensus.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/struct_self_consist_ie/data/\", \"data_count\": \"all datasets\", \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/struct_self_consist_ie/output/entity_consensus_results.json\", \"log_path\": \"/root/struct_self_consist_ie/output/entity_consensus_results.json\", \"completed_at\": \"2026-05-18T20:01:40.869Z\"}, \"exp_ccs_selection\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T19:59:48.671Z\", \"updated_at\": \"2026-05-18T20:01:39.128Z\", \"hypothesis\": \"Three-stage cascaded selection (degen→greedy, low-LP-range→entity MV, high-LP-range→LP) can outperform single-strategy selection by adapting to local confidence patterns\", \"spec\": {\"command\": \"python3 code/ccs_selection.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/struct_self_consist_ie/data/\", \"data_count\": \"all datasets\", \"model_name\": \"Qwen3-8B\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"/root/struct_self_consist_ie/output/ccs_selection_results.json\", \"log_path\": \"/root/struct_self_consist_ie/output/ccs_selection_results.json\", \"completed_at\": \"2026-05-18T20:01:39.128Z\"}, \"exp_017_llama_conll\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-14T14:39:32.014Z\", \"updated_at\": \"2026-05-18T19:11:03.240Z\", \"completed_at\": \"2026-05-14T17:12:15.687Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"success\"}}, \"hypothesis\": \"On CoNLL (high degeneracy regime), LLaMA should show the same pattern as Qwen3: LP selection fails due to narrow headroom, but structural signals retain diagnostic value (QE rho). Cross-model validation of the degeneracy-driven signal effectiveness framework.\", \"parent\": \"exp_007_llama_inference\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-17T11:30:53.467Z\"}, \"metrics\": {\"degeneracy_cf1_gold_filtered\": 0.894, \"n_constant_f1\": 2465, \"n_gold_filtered\": 2756, \"n_total\": 3453, \"greedy_f1\": 0.9239, \"oracle_f1\": 0.9451, \"random_f1\": 0.9207, \"headroom_pp\": 2.11, \"dgs_f1\": 0.9254, \"dgs_delta_pp\": 0.14, \"dgs_nondegen_lp_delta_pp\": 1.37, \"selection_f1\": {\"SJ\": {\"f1\": 0.9237, \"delta_pp\": -0.04}, \"FK\": {\"f1\": 0.924, \"delta_pp\": -0.02}, \"VC\": {\"f1\": 0.925, \"delta_pp\": 0.08}, \"EM\": {\"f1\": 0.9244, \"delta_pp\": 0.02}, \"LP\": {\"f1\": 0.9244, \"delta_pp\": 0.02}}, \"qe_rho_full_3seed\": {\"SJ\": {\"mean\": 0.4631, \"sd\": 0.0074}, \"FK\": {\"mean\": 0.4546, \"sd\": 0.0061}, \"EM\": {\"mean\": 0.4603, \"sd\": 0.0078}, \"VC\": {\"mean\": 0.4579, \"sd\": 0.003}, \"LP\": {\"mean\": 0.3099, \"sd\": 0.0055}}, \"qe_auroc_full_3seed\": {\"SJ\": {\"mean\": 0.736, \"sd\": 0.0064}, \"FK\": {\"mean\": 0.732, \"sd\": 0.0063}, \"EM\": {\"mean\": 0.7355, \"sd\": 0.0069}, \"VC\": {\"mean\": 0.7394, \"sd\": 0.0041}, \"LP\": {\"mean\": 0.7629, \"sd\": 0.0044}}, \"lp_range\": {\"mean\": 0.0198, \"std\": 0.0315, \"median\": 0.0002}}, \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/exp017_full_signal_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/samples.jsonl\", \"data_count\": 3453, \"model_name\": \"llama3.1-8b-conll2003-merged\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/full_signal_analysis.json\"}}, \"exp_017_llama_conll_finetune\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T16:47:36.156Z\", \"updated_at\": \"2026-05-18T18:43:42.649Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 llamafactory-cli train train_config_llama_conll2003_3ep.yaml\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"674921\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_017_llama_conll_finetune.log\", \"submitted_at\": \"2026-05-18T16:47:35.786Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003/llmfactory_train.json\", \"data_count\": 14037, \"model_name\": \"Meta-Llama-3.1-8B-Instruct\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/llama3.1-8b-conll2003-lora-3ep\", \"checkpoint_source\": \"Meta-Llama-3.1-8B-Instruct (base model, LoRA from scratch)\", \"eval_data\": \"conll2003_uie_dev\", \"wall_clock_seconds\": 6176.5, \"gpu_hours\": 1.72}, \"hypothesis\": \"Structural self-consistency QE signals (SJ, FK, VC, EM) show model-agnostic diagnostic power: their Spearman rho with per-instance F1 should be comparable on LLaMA 3.1-8B as on Qwen 2.5-7B for CoNLL-2003 NER, even though degeneracy rates and absolute F1 may differ.\", \"parent\": \"exp_llama_fewnerd_lora\", \"conclusion\": \"success\", \"metrics\": {\"degeneracy_rate\": 0.853, \"greedy_f1\": 0.928, \"oracle_f1\": 0.951, \"headroom\": 0.023, \"selection_f1\": 0.934, \"full_rho_SJ\": 0.45, \"full_rho_FK\": 0.443, \"full_rho_VC\": 0.437, \"full_rho_EM\": 0.448, \"full_rho_LP\": 0.273, \"full_AUROC_SJ\": 0.752, \"full_AUROC_EM\": 0.753, \"full_AUROC_LP\": 0.739, \"cond_rho_SJ\": 0.454, \"cond_rho_EM\": 0.458, \"cond_rho_LP\": 0.311, \"cond_AUROC_EM\": 0.783, \"cond_AUROC_LP\": 0.804}, \"completed_at\": \"2026-05-18T18:30:32.331Z\"}, \"exp_028_entity_token_lp\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T18:22:18.594Z\", \"updated_at\": \"2026-05-18T18:23:06.601Z\", \"hypothesis\": \"Full-sequence mean LP underperforms as a quality signal because format/schema tokens dilute the entity-relevant logprob signal; isolating entity-only tokens should yield higher QE correlation and selection F1.\", \"conclusion\": \"negative\", \"spec\": {\"command\": \"python code/exp028_entity_token_lp_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_entity_token_lp/scierc/samples.jsonl\", \"data_count\": 529, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"log_path\": \"output/exp_028_entity_token_lp/analysis_results.json\"}, \"completed_at\": \"2026-05-18T18:22:59.312Z\", \"metrics\": {\"greedy_f1\": 0.643, \"oracle_f1\": 0.7845, \"full_lp_global_rho\": 0.2971, \"entity_text_type_lp_global_rho\": 0.4401, \"full_lp_selection_f1\": 0.6465, \"entity_text_type_lp_selection_f1\": 0.6357, \"dilution_ratio\": 0.32, \"full_lp_within_range_median\": 0.0402, \"entity_text_type_within_range_median\": 0.1346, \"schema_only_within_range_median\": 0.0089}}, \"exp_026_t12_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:28:36.812Z\", \"updated_at\": \"2026-05-18T15:30:33.407Z\", \"hypothesis\": \"Higher temperature (T=1.2) reduces degeneracy rate and increases LP range on SciERC NER, but may degrade absolute generation quality\", \"spec\": {\"command\": \"python code/analyze_exp026_temp_5signal.py --data_path output/exp_026_t12/samples.jsonl --output_dir output/exp_026_t12/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"665522\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_t12_scierc.log\", \"submitted_at\": \"2026-05-18T15:28:56.997Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"output/exp_026_t12/samples.jsonl\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"checkpoint_source\": \"ft_002_v2\", \"eval_data\": \"scierc_test_551\", \"wall_clock_seconds\": 96.4, \"gpu_hours\": 0.03}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T15:30:33.407Z\"}, \"exp_026_t08_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:28:36.084Z\", \"updated_at\": \"2026-05-18T15:30:31.219Z\", \"hypothesis\": \"Moderate temperature (T=0.8) provides intermediate degeneracy/LP-range tradeoff on SciERC NER, testing sensitivity of structural signals to temperature\", \"spec\": {\"command\": \"python code/analyze_exp026_temp_5signal.py --data_path output/exp_026_t08/samples.jsonl --output_dir output/exp_026_t08/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"665386\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_t08_scierc.log\", \"submitted_at\": \"2026-05-18T15:28:55.394Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"output/exp_026_t08/samples.jsonl\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"checkpoint_source\": \"ft_002_v2\", \"eval_data\": \"scierc_test_551\", \"wall_clock_seconds\": 95.8, \"gpu_hours\": 0.03}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T15:30:31.219Z\"}, \"exp_026_t05_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T15:28:34.135Z\", \"updated_at\": \"2026-05-18T15:30:28.965Z\", \"hypothesis\": \"Lower temperature (T=0.5) increases degeneracy rate and reduces LP range on SciERC NER, as reduced sampling diversity causes more identical outputs\", \"spec\": {\"command\": \"python code/analyze_exp026_temp_5signal.py --data_path output/exp_026_t05/samples.jsonl --output_dir output/exp_026_t05/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"665248\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_026_t05_scierc.log\", \"submitted_at\": \"2026-05-18T15:28:53.787Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"output/exp_026_t05/samples.jsonl\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"checkpoint_source\": \"ft_002_v2\", \"eval_data\": \"scierc_test_551\", \"wall_clock_seconds\": 95.2, \"gpu_hours\": 0.03}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-18T15:30:28.965Z\"}, \"exp_027_mlp_verifier\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-18T06:39:22.524Z\", \"updated_at\": \"2026-05-18T06:41:51.069Z\", \"metrics\": {\"lr_auroc\": 0.6522, \"mlp_auroc\": 0.6381, \"rf_auroc\": 0.5868, \"mlp_15feat_auroc\": 0.6341, \"lr_sel_f1\": 0.6406, \"mlp_sel_f1\": 0.6278, \"greedy_f1\": 0.6441, \"oracle_f1\": 0.8231, \"best_single_signal_auroc\": 0.6476, \"feature_bottleneck_confirmed\": true}, \"hypothesis\": \"MLP/RF等非线性模型能否通过组合5个QE信号(LP,SJ,FK,EM,VC)超越LR，或通过cross-signal interactions提取额外信息，从而缩小selection gap\", \"spec\": {\"command\": \"python train_mlp_verifier.py --n_samples 16 --cv_folds 5 --seeds 42,123,456\", \"server\": \"a100\", \"data_path\": \"output/exp_001_n16_seed*/samples.jsonl\", \"data_count\": 529, \"model_name\": \"sklearn LR/MLP/RF\", \"seed\": \"42,123,456\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp_027_mlp_verifier/\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-18T06:41:51.069Z\"}, \"exp_028_fewnerd_5epoch\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T07:53:12.913Z\", \"updated_at\": \"2026-05-17T20:29:42.274Z\", \"spec\": {\"hypothesis\": \"Few-NERD low degeneracy (10%) partially due to under-convergence at 3 epochs. 5 epochs should increase degeneracy as model becomes more confident, potentially reducing LP selection gain.\", \"parent\": \"exp_021_fewnerd_full\", \"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0,1,2,3 llamafactory-cli train train_config_fewnerd_5epoch_4gpu.yaml 2>&1 | tee logs/exp_028_4gpu_train.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0,1,2,3\", \"data_path\": \"data/fewnerd_uie_train\", \"data_count\": 131767, \"model_name\": \"Qwen3-8B LoRA rank=32\", \"seed\": 42, \"log_path\": \"logs/exp_028_4gpu_train.log\", \"checkpoint_path\": \"checkpoints/qwen3-8b-fewnerd-5epoch-lora\"}, \"conclusion\": \"negative\", \"metrics\": {\"degeneracy_cf1_gold\": 0.3133, \"greedy_f1\": 0.7773, \"lp_sel_delta_pp\": 0.624, \"lp_sel_f1\": 0.7835, \"oracle_f1\": 0.8723, \"within_instance_rho_mean\": 0.4066, \"within_instance_rho_median\": 0.6151}, \"hypothesis\": \"Few-NERD low degeneracy (10%) partially due to under-convergence at 3 epochs. 5 epochs should increase degeneracy as model becomes more confident, potentially reducing LP selection gain.\", \"completed_at\": \"2026-05-17T20:29:42.274Z\"}, \"exp_028\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-17T07:35:39.447Z\", \"updated_at\": \"2026-05-17T20:26:59.399Z\", \"hypothesis\": \"Few-NERD low degeneracy (10%) in exp-021 is NOT due to under-convergence at 3 epochs; training for 5 epochs will show similar degeneracy levels, confirming the structural property of this dataset rather than an artifact of insufficient training.\", \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\", \"completed_at\": \"2026-05-17T12:09:43.334Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"failed\"}, \"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-17T20:06:01.040147+00:00\"}]}, \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/bin/activate && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0,1,2,3 llamafactory-cli train train_config_fewnerd_5epoch_4gpu.yaml 2>&1 | tee logs/exp_028_4gpu_train.log\\\"\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/fewnerd_uie_train\", \"data_count\": 131767, \"model_name\": \"Qwen3-8B LoRA rank=32\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/qwen3-8b-fewnerd-5epoch-lora\", \"log_path\": \"logs/exp_028_4gpu_train.log\"}, \"reproduce\": {\"finished_at\": \"2026-05-17T20:05:57.260Z\"}, \"conclusion\": \"negative\", \"metrics\": {\"degeneracy_cf1_gold\": 0.313, \"greedy_f1\": 0.7773, \"lp_sel_f1\": 0.7835, \"lp_sel_delta_pp\": 0.62, \"oracle_f1\": 0.8723, \"within_instance_rho\": 0.4066, \"train_loss\": 0.0189, \"eval_loss\": 0.0311}}, \"exp_024_claim_audit\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-17T10:54:36.291Z\", \"updated_at\": \"2026-05-17T10:55:08.244Z\", \"hypothesis\": \"Systematic cross-chapter numerical consistency audit: verify all quantitative claims in paper against source experiment data, catch stale values and cross-reference errors before submission.\", \"conclusion\": \"success\", \"metrics\": {\"consistent\": 97, \"errors\": 1, \"warnings\": 5, \"old_residuals_found\": 0}, \"spec\": {\"checkpoint_path\": \"artifacts/exp_024_claim_audit/audit_report.md\", \"log_path\": \"N/A\", \"command\": \"CPU-only paper audit\", \"server\": \"local\", \"data_path\": \"docs/paper/\", \"data_count\": 0, \"model_name\": \"N/A\", \"seed\": 0}, \"completed_at\": \"2026-05-17T10:55:08.244Z\"}, \"exp_016_rerun_1024_bootstrap\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T23:44:21.577Z\", \"updated_at\": \"2026-05-17T03:33:39.786Z\", \"hypothesis\": \"3-seed bootstrap significance test for NER logprob vs greedy selection gap (+0.6pp). Tests whether the observed advantage is statistically significant.\", \"spec\": {\"command\": \"python code/bootstrap_significance.py\", \"server\": \"local\", \"data_path\": \"output/exp_016_rerun_1024/\", \"data_count\": 529, \"model_name\": \"N/A (statistical analysis)\", \"seed\": \"3-seed bootstrap (1000 iterations)\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp_016_rerun_1024_bootstrap/\"}, \"conclusion\": \"negative\", \"metrics\": {\"bootstrap_ci_95\": [-0.03, 0.042], \"permutation_p\": 0.39, \"cohen_d\": 0.038, \"sign_test_win_rate\": 0.466, \"ner_logprob_vs_greedy_delta\": 0.006, \"conclusion_summary\": \"NER selection: no signal significantly outperforms greedy; RE: same conclusion\"}, \"completed_at\": \"2026-05-14T23:44:48.818Z\", \"parent\": \"exp_016_rerun_1024\"}, \"exp_verbalized_confidence\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:45:20.552Z\", \"updated_at\": \"2026-05-17T03:33:39.197Z\", \"hypothesis\": \"Verbalized confidence baseline: let model self-rate extraction confidence. If also compressed → strengthens \\\"score compression is general\\\" claim. If effective → important positive finding requiring narrative adjustment.\", \"conclusion\": \"negative\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_verbalized_confidence.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_012_rerun_1024/samples.jsonl + output/exp002_conll2003/samples.jsonl\", \"data_count\": 3285, \"model_name\": \"qwen3-8b-scierc-merged-v2 + qwen3-8b-conll2003-merged\", \"seed\": 42, \"checkpoint_path\": \"output/review_round9_experiments/verbalized_confidence/\", \"log_path\": \"output/review_round9_experiments/verbalized_confidence_run.log\"}, \"completed_at\": \"2026-05-16T03:09:39.916Z\", \"metrics\": {\"scierc\": {\"VerbConf_rho\": 0.2965, \"VerbConf_auroc\": 0.6811, \"VerbConf_sel_f1\": 0.6195, \"VerbConf_delta\": -0.0245, \"best_existing_rho\": 0.3792, \"VerbConf_mean\": 8.58, \"VerbConf_std\": 1.15, \"parse_fail_rate\": 0.0026}, \"conll\": {\"VerbConf_rho\": 0.3366, \"VerbConf_auroc\": 0.7469, \"VerbConf_sel_f1\": 0.8886, \"VerbConf_delta\": -0.0193, \"best_existing_rho\": 0.4507, \"VerbConf_mean\": 9.24, \"VerbConf_std\": 1.32, \"parse_fail_rate\": 0}}, \"parent\": \"exp_012_rerun_1024\"}, \"exp_entity_token_lp\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T05:39:44.631Z\", \"updated_at\": \"2026-05-17T03:33:38.371Z\", \"hypothesis\": \"Entity-token LP: test Discussion hypothesis (d) format-token dilution. Re-inference with per-token logprobs, then compute entity-only LP variance and selection F1. If entity-token LP compression is reduced → pilot remedy for LP selection. Also includes LP z-score normalization as zero-cost baseline. Addresses SF2+SF3 from Round 12.\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0,cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:0,cuda:1\", \"started_at\": \"2026-05-16T05:41:33.768Z\"}, \"conclusion\": \"negative\", \"metrics\": {\"scierc_ner\": {\"greedy_f1\": 0.643, \"full_lp_sel_f1\": 0.6465, \"entity_lp_sel_f1\": 0.6262, \"oracle_f1\": 0.7845, \"entity_lp_delta_vs_full_lp\": -0.0203}, \"conll_ner\": {\"greedy_f1\": 0.9065, \"full_lp_sel_f1\": 0.8989, \"entity_lp_sel_f1\": 0.8659, \"oracle_f1\": 0.948, \"entity_lp_delta_vs_full_lp\": -0.033}, \"finding\": \"entity-token LP strictly worse than full-sequence LP; CoNLL entity tokens saturated (79.4% tied), SciERC entity tokens too sparse (5.3% of total)\"}, \"spec\": {\"command\": \"python analyze_entity_token_lp.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_012_rerun_1024/ + output/exp_002_conll_rerun_1024/\", \"data_count\": \"529 (SciERC NER) + 2756 (CoNLL NER)\", \"model_name\": \"Qwen3-8B (finetuned)\", \"seed\": 42, \"checkpoint_path\": \"artifacts/exp_entity_token_lp/results.json\", \"log_path\": \"artifacts/exp_entity_token_lp/report.md\"}, \"completed_at\": \"2026-05-16T06:28:46.845Z\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_freeform_ablation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T09:42:22.868Z\", \"updated_at\": \"2026-05-17T03:33:37.623Z\", \"spec\": {\"command\": \"python run_freeform_inference.py --seed 42 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"169042\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_freeform_ablation.log\", \"submitted_at\": \"2026-05-15T09:42:30.236Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"hypothesis\": \"Free-form decoding recovers logprob variance and selection ability lost under constrained decoding\", \"plan_id\": \"exp-018\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"tmux_session\": \"exp_freeform_ablation\", \"wall_clock_seconds\": 1059.0, \"gpu_hours\": 0.29}, \"conclusion\": \"negative\", \"metrics\": {\"lp_std_ratio_free_vs_constrained\": 0.97, \"lp_range_ratio\": 0.96, \"tied_fraction_constrained\": 0.597, \"tied_fraction_freeform\": 0.577, \"ner_selection_gap_constrained\": 0.0059, \"ner_selection_gap_freeform\": 0.0018, \"re_selection_gap_constrained\": -0.0068, \"re_selection_gap_freeform\": 0.0169, \"parse_rate\": 0.9995, \"ner_vc_rho_constrained\": 0.3792, \"ner_vc_rho_freeform\": 0.4089}, \"checkpoint_path\": \"N/A (inference-only experiment)\", \"completed_at\": \"2026-05-15T10:00:09.238Z\", \"hypothesis\": \"Free-form vs constrained decoding ablation on SciERC: test if removing JSON schema constraint changes LP variance distribution. If LP remains compressed under free-form, confirms compression is model-intrinsic not format-artifact.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_008_re_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:03:06.876Z\", \"updated_at\": \"2026-05-17T02:58:19.490Z\", \"spec\": {\"hypothesis\": \"RE N=16 confirms negative finding with higher statistical power. If rho still <0.30, task-complexity boundary is robust.\", \"plan_id\": \"exp-008\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"gpu\": \"cuda:2\", \"server\": \"gpu-5090-4x-2\", \"gpu_budget_hours\": 12, \"description\": \"RE N=16 on SciERC to confirm negative finding. Inference with log-prob capture.\", \"priority\": \"P1\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --collect_logprobs\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"seed\": 42, \"num_instances\": 200, \"partial\": true, \"note\": \"Only 200/551 instances due to --num_test default bug. Needs full rerun.\"}, \"metrics\": {\"ner\": {\"greedy_f1\": 0.6635, \"oracle_f1\": 0.8208, \"headroom\": 0.1572, \"rho_sj_full\": 0.377, \"rho_fk_full\": 0.2508, \"rho_logprob_full\": 0.3153, \"rho_sj_cond\": 0.3598, \"rho_fk_cond\": 0.2251, \"rho_logprob_cond\": 0.2927, \"sj_beats_fk\": true, \"rho_advantage\": 0.1262}, \"re\": {\"greedy_f1\": 0.4339, \"oracle_f1\": 0.6658, \"headroom\": 0.2319, \"rho_sj_full\": 0.2966, \"rho_fk_full\": 0.2871, \"rho_logprob_full\": 0.2986, \"rho_sj_cond\": 0.3975, \"rho_fk_cond\": 0.3774, \"rho_logprob_cond\": 0.2745, \"sj_beats_fk\": true, \"rho_advantage\": 0.0095}, \"verdict\": \"FAIL\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp008_re_n16/\", \"completed_at\": \"2026-05-14T12:28:39.268Z\", \"hypothesis\": \"RE N=16 initial evaluation: first relation extraction test with structural signals. Establishes baseline RE signal effectiveness before pipeline corrections.\"}, \"exp_001_ner_n16_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:46:06.430Z\", \"updated_at\": \"2026-05-17T02:58:18.225Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=3 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --output_dir output/exp001_n16_seed123 --num_test 9999 --collect_logprobs 2>&1 | tee output/exp001_n16_seed123_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"63407\", \"log_path\": \"output/exp001_n16_seed123_run.log\", \"submitted_at\": \"2026-05-14T12:46:06.234Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_count\": 551, \"data_path\": \"data/scierc/processed_data\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"checkpoint_path\": \"output/exp001_n16_seed123/\", \"wall_clock_seconds\": 2748.0, \"gpu_hours\": 0.76}, \"conclusion\": \"success\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.663, \"oracle_f1\": 0.809, \"headroom\": 0.146, \"rho_sj\": 0.423, \"rho_fk\": 0.29, \"rho_logprob\": 0.239, \"rho_sj_cond\": 0.423, \"rho_fk_cond\": 0.26}, \"re\": {\"greedy_f1\": 0.419, \"oracle_f1\": 0.625, \"headroom\": 0.206, \"rho_sj\": 0.267, \"rho_fk\": 0.315, \"rho_sj_cond\": 0.364, \"rho_fk_cond\": 0.331}, \"verdict\": \"FAIL\", \"verdict_note\": \"RE rho_sj=0.267 < 0.40; RE >30% samples F1=0\", \"n_instances\": 551, \"seed\": 123, \"N\": 16, \"T\": 1}, \"completed_at\": \"2026-05-14T13:31:54.232Z\", \"hypothesis\": \"SciERC NER N=16 seed=123: multi-seed validation at N=16. Tests seed stability for signal rankings with more samples.\"}, \"exp_007_ner_multi_model\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:20.748Z\", \"updated_at\": \"2026-05-17T02:58:16.747Z\", \"spec\": {\"command\": \"bash -c 'source env.sh && cd /root/autodl-tmp/struct_self_consist_ie && llamafactory-cli train train_config_llama.yaml'\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:0\"], \"pid\": \"60970\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_007_ner_multi_model.log\", \"submitted_at\": \"2026-05-14T12:43:09.108Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data\", \"data_count\": 1861, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": 42, \"log_file\": \"~/runs/struct_self_consist_ie/exp_007_ner_multi_model.log\", \"wall_clock_seconds\": 165.8, \"gpu_hours\": 0.05}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"started_at\": \"2026-05-14T11:43:50.977Z\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:45:54.952Z\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/llama3.1-8b-scierc-lora\", \"metrics\": {\"epoch\": 5, \"train_loss\": 0.0767, \"eval_loss\": 0.1049, \"train_runtime_sec\": 1494.5, \"train_samples_per_second\": 6.226, \"checkpoints\": [\"checkpoint-400\", \"checkpoint-500\", \"checkpoint-585\"], \"base_model\": \"Meta-Llama-3.1-8B-Instruct\", \"lora_r\": 32, \"lora_alpha\": 64, \"note\": \"EXIT_CODE=129 (SIGHUP) but training completed all 5 epochs before signal. Checkpoint fully intact.\"}, \"log_path\": \"~/runs/struct_self_consist_ie/exp_007_ner_multi_model.log\", \"hypothesis\": \"Multi-model NER comparison: evaluates signal effectiveness across Qwen and LLaMA on SciERC NER. Establishes cross-model generalization of structural>surface ranking.\"}, \"exp_003_ner_wnut17\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:17.544Z\", \"updated_at\": \"2026-05-17T02:58:14.928Z\", \"spec\": {\"merged_model_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-wnut17-merged\", \"pilot_command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-wnut17-merged --data_dir data/wnut17 --dataset wnut17 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp003_wnut17_pilot --num_test 9999 --collect_logprobs\", \"pilot_pid\": 71498, \"pilot_server\": \"autodl-5090\", \"pilot_started_at\": \"2026-05-14T21:36:00Z\", \"test_samples\": 1287}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:2\", \"started_at\": \"2026-05-14T11:43:50.537Z\", \"finished_at\": \"2026-05-14T12:53:13.262Z\", \"training_hours\": 1.16}, \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-14T12:53:14.768981+00:00\"}]}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-wnut17-merged\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.525, \"oracle_f1\": 0.664, \"headroom\": 0.139, \"rho_sj_full\": 0.082, \"rho_fk_full\": 0.124, \"rho_logprob_full\": -0.414, \"rho_sj_cond\": 0.275, \"rho_fk_cond\": 0.164, \"rho_logprob_cond\": 0.352, \"sj_beats_logprob_cond\": false}, \"n_instances\": 1287, \"n_gold_empty\": 598, \"sample_f1_mean\": 0.401, \"sample_f1_pct_zero\": 53.7, \"N\": 16, \"T\": 1, \"seed\": 42, \"verdict\": \"FAIL\", \"verdict_note\": \">30% samples F1=0; structural rho weak; logprob baseline stronger\"}, \"conclusion\": \"negative\", \"log_path\": \"output/exp003_wnut17_pilot/\", \"completed_at\": \"2026-05-14T13:40:20.979Z\", \"hypothesis\": \"WNUT-17 NER fine-tune + inference: initial attempt on social media domain. Tests if structural signals work when model capability is low on noisy text with novel entity types.\"}, \"exp_001_seed456_t10_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:27:41.067Z\", \"updated_at\": \"2026-05-17T02:58:12.996Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456}, \"reproduce\": {\"finished_at\": \"2026-05-14T13:44:05.416Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T13:44:05.021Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T13:44:10.317185+00:00\"}]}, \"metrics\": {\"ner\": {\"rho_sj\": 0.414, \"rho_fk\": 0.298}, \"re\": {\"rho_sj\": 0.268, \"rho_fk\": 0.26}, \"n_instances\": 551, \"N\": 16, \"T\": 1, \"seed\": 456, \"source\": \"reviewer_verified_report_json\"}, \"hypothesis\": \"SciERC NER seed=456 T=1.0 full: early multi-seed NER test before pipeline corrections. Preliminary evidence for seed stability.\"}, \"exp_001_seed123_t10_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:27:42.503Z\", \"updated_at\": \"2026-05-17T02:58:11.623Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123}, \"reproduce\": {\"finished_at\": \"2026-05-14T13:44:13.823Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T13:44:13.213Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T13:44:16.532801+00:00\"}]}, \"metrics\": {\"ner\": {\"rho_sj\": 0.417, \"rho_fk\": 0.283}, \"re\": {\"rho_sj\": 0.265, \"rho_fk\": 0.315}, \"n_instances\": 551, \"N\": 16, \"T\": 1, \"seed\": 123, \"source\": \"reviewer_verified_report_json\"}, \"hypothesis\": \"SciERC NER seed=123 T=1.0 full: early multi-seed NER test before pipeline corrections. Preliminary evidence for seed stability.\"}, \"exp_008_re_n16_t10_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:27:42.867Z\", \"updated_at\": \"2026-05-17T02:58:10.171Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42}, \"reproduce\": {\"finished_at\": \"2026-05-14T13:44:18.988Z\"}, \"failure_reason\": \"\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T13:44:19.577Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-14T13:44:21.528032+00:00\"}]}, \"metrics\": {\"ner\": {\"rho_sj\": 0.444}, \"re\": {\"rho_sj\": 0.248}, \"n_instances\": 551, \"N\": 16, \"T\": 1, \"seed\": 42, \"mode\": \"RE-only\", \"source\": \"director_corrected\"}, \"hypothesis\": \"RE N=16 T=1.0 full dataset: early RE evaluation attempt. Tests structural signals on relation extraction before pipeline corrections.\"}, \"exp_007_llama_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:54:48.055Z\", \"updated_at\": \"2026-05-17T02:58:03.014Z\", \"spec\": {\"command\": \"python run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp007_llama_inference/\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"75172\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_007_llama_inference.log\", \"submitted_at\": \"2026-05-14T13:54:47.962Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Meta-Llama-3.1-8B-Instruct (LoRA fine-tuned on SciERC)\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/llama3.1-8b-scierc-merged\", \"description\": \"LLaMA-3.1-8B SciERC joint inference (NER+RE) with 8 samples, T=1.0, logprobs collected.\", \"wall_clock_seconds\": 1038.5, \"gpu_hours\": 0.29}, \"log_path\": \"output/exp007_llama_inference/\", \"checkpoint_path\": \"N/A\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.66, \"oracle_f1\": 0.781, \"headroom\": 0.121, \"rho_fk\": 0.327, \"rho_sj\": 0.363, \"rho_fk_cond\": 0.226, \"rho_sj_cond\": 0.311, \"rho_logprob\": 0.183, \"rho_logprob_cond\": 0.109, \"structural_beats_surface\": true, \"sample_f1_pct_zero\": 11.6}, \"re\": {\"greedy_f1\": 0.434, \"oracle_f1\": 0.568, \"headroom\": 0.135, \"rho_fk\": 0.305, \"rho_sj\": 0.299, \"rho_fk_cond\": 0.259, \"rho_sj_cond\": 0.405, \"rho_logprob\": 0.288, \"rho_logprob_cond\": 0.092, \"structural_beats_surface\": false, \"sample_f1_pct_zero\": 41.2}, \"n_instances\": 551, \"N\": 8, \"T\": 1, \"seed\": 42, \"model\": \"LLaMA-3.1-8B-Instruct\", \"verdict\": \"FAIL\", \"verdict_note\": \"RE rho_sj_full=0.299 < 0.40; >30% RE samples F1=0\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T14:12:06.442Z\", \"hypothesis\": \"LLaMA SciERC N=8 baseline: first cross-model test. Verifies structural signal effectiveness generalizes from Qwen to LLaMA model family on SciERC NER.\"}, \"exp_003_wnut17_eval\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T13:47:34.654Z\", \"updated_at\": \"2026-05-17T02:58:01.627Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-wnut17-merged --data_dir data/wnut17 --dataset wnut17 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp003_wnut17_eval --num_test 9999 --collect_logprobs\", \"server\": \"autodl-5090\", \"data_path\": \"data/wnut17\", \"data_count\": 1287, \"model_name\": \"qwen3-8b-wnut17-merged\", \"seed\": 42}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T14:08:17.429Z\", \"metrics\": {\"greedy_f1\": 0.523, \"oracle_f1\": 0.664, \"headroom\": 0.141, \"rho_fk\": 0.125, \"rho_sj\": 0.089, \"rho_fk_cond\": 0.169, \"rho_sj_cond\": 0.288, \"rho_logprob_full\": -0.409, \"rho_logprob_cond\": 0.35, \"structural_beats_surface\": false, \"sample_f1_pct_zero\": 53.7, \"n_instances\": 1287, \"N\": 16, \"T\": 1, \"seed\": 42, \"model\": \"Qwen3-8B\", \"n_gold_empty_filtered\": 598, \"verdict\": \"FAIL\", \"verdict_note\": \"structural_beats_surface=false; >50% samples F1=0\"}, \"hypothesis\": \"WNUT-17 NER evaluation: initial test on noisy social media domain. Tests boundary conditions for structural signal effectiveness on out-of-domain text.\"}, \"exp_010_selection_curves\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:01:53.585Z\", \"updated_at\": \"2026-05-17T02:58:00.378Z\", \"spec\": {\"command\": \"python3 code/exp010_selection_curves.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_001_seed42_v2, output/exp_008_re_n16_v2, output/exp002_conll2003\", \"data_count\": \"551+397+3453 instances\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 42, \"description\": \"Best-of-N selection curves: F1 vs N for 7 signals across 3 datasets\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (analysis only)\", \"log_path\": \"/tmp/exp010.log\", \"completed_at\": \"2026-05-14T15:02:22.638Z\", \"metrics\": {\"scierc_ner\": {\"n_instances\": 551, \"greedy_f1\": 0.618, \"N16\": {\"oracle\": 0.787, \"SJ\": 0.62, \"FK\": 0.621, \"logprob\": 0.621, \"voting_conf\": 0.585, \"EM\": 0.606, \"random\": 0.595}, \"N8\": {\"oracle\": 0.752, \"SJ\": 0.614, \"FK\": 0.614, \"logprob\": 0.619, \"voting_conf\": 0.591, \"EM\": 0.603, \"random\": 0.589}, \"N4\": {\"oracle\": 0.714, \"SJ\": 0.607, \"FK\": 0.608, \"logprob\": 0.616, \"voting_conf\": 0.594, \"EM\": 0.6, \"random\": 0.587}}, \"scierc_re\": {\"n_instances\": 397, \"greedy_f1\": 0.403, \"N16\": {\"oracle\": 0.631, \"SJ\": 0.397, \"FK\": 0.396, \"logprob\": 0.41, \"voting_conf\": 0.408, \"EM\": 0.381, \"random\": 0.364}, \"N8\": {\"oracle\": 0.583, \"SJ\": 0.393, \"FK\": 0.394, \"logprob\": 0.413, \"voting_conf\": 0.398, \"EM\": 0.381, \"random\": 0.363}}, \"conll_ner\": {\"n_instances\": 3453, \"greedy_f1\": 0.725, \"N8\": {\"oracle\": 0.757, \"SJ\": 0.718, \"FK\": 0.717, \"logprob\": 0.716, \"voting_conf\": 0.714, \"EM\": 0.716, \"random\": 0.69}, \"N4\": {\"oracle\": 0.746, \"SJ\": 0.714, \"FK\": 0.714, \"logprob\": 0.715, \"voting_conf\": 0.714, \"EM\": 0.712, \"random\": 0.692}}}, \"hypothesis\": \"Selection curve analysis: plots selection F1 vs confidence threshold for each signal. Visualizes where correlation-selection gap emerges and at what confidence level signals become useful for filtering.\"}, \"exp_007_llama_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:08:50.628Z\", \"updated_at\": \"2026-05-17T02:57:59.595Z\", \"spec\": {\"description\": \"LLaMA 3.1-8B SciERC joint extraction, seed=456, cross-model robustness test\", \"hypothesis\": \"Structural consistency generalizes across model architectures (LLaMA vs Qwen)\", \"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs --output_dir output/exp_007_llama_seed456\", \"server\": \"bjb1-21071\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"llama3.1-8b-scierc-merged\", \"seed\": 456, \"gpu\": [\"cuda:2\"], \"backend\": \"tmux\", \"tmux_session\": \"exp007_s456\", \"account\": \"root\", \"log_path\": \"output/exp_007_llama_seed456/run.log\"}, \"conclusion\": \"negative\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed456/run.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed456/\", \"completed_at\": \"2026-05-14T15:19:20.693Z\", \"metrics\": {\"verdict\": \"FAIL\", \"ner\": {\"greedy_f1\": 0.6597, \"oracle_f1\": 0.7575, \"oracle_headroom\": 0.0978, \"fleiss_kappa\": 0.4543, \"soft_jaccard\": 0.7491, \"rho_kappa_f1\": 0.3115, \"rho_sj_f1\": 0.3663, \"structural_gt_surface\": true}, \"re\": {\"greedy_f1\": 0.4334, \"oracle_f1\": 0.5789, \"oracle_headroom\": 0.1455, \"fleiss_kappa\": 0.3791, \"soft_jaccard\": 0.6782, \"rho_kappa_f1\": 0.3013, \"rho_sj_f1\": 0.287, \"structural_gt_surface\": false}, \"logprob_ner\": {\"rho\": 0.1911, \"auroc\": 0.5989}, \"logprob_re\": {\"rho\": 0.3246, \"auroc\": 0.6678}, \"fail_reason\": \"RE rho_sj=0.2870 < 0.40 threshold; >30% samples F1=0\"}, \"hypothesis\": \"LLaMA SciERC seed=456: early cross-model multi-seed test. Verifies LLaMA NER signal pattern is reproducible across sampling seeds.\"}, \"exp_007_llama_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:08:50.157Z\", \"updated_at\": \"2026-05-17T02:57:58.879Z\", \"spec\": {\"description\": \"LLaMA 3.1-8B SciERC joint extraction, seed=123, cross-model robustness test\", \"hypothesis\": \"Structural consistency generalizes across model architectures (LLaMA vs Qwen)\", \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_007_llama_seed123\", \"server\": \"bjb1-21071\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"llama3.1-8b-scierc-merged\", \"seed\": 123, \"gpu\": [\"cuda:1\"], \"backend\": \"tmux\", \"tmux_session\": \"exp007_s123\", \"account\": \"root\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed123/run.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_007_llama_seed123/\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T15:19:43.424Z\", \"metrics\": {\"verdict\": \"FAIL\", \"ner\": {\"greedy_f1\": 0.6605, \"oracle_f1\": 0.7703, \"headroom\": 0.1098, \"fleiss_kappa\": 0.4553, \"soft_jaccard\": 0.7525, \"rho_kappa_f1\": 0.2143, \"rho_sj_f1\": 0.3371, \"structural_gt_surface\": true}, \"re\": {\"greedy_f1\": 0.433, \"oracle_f1\": 0.5719, \"headroom\": 0.1389, \"fleiss_kappa\": 0.3851, \"soft_jaccard\": 0.6911, \"rho_kappa_f1\": 0.2844, \"rho_sj_f1\": 0.268, \"structural_gt_surface\": false}, \"fail_reasons\": [\"RE rho_sj=0.2680 < 0.40 threshold\", \">30% samples F1=0 (RE: 41.0%)\", \"RE structural not > surface (delta=-0.0165)\"]}, \"hypothesis\": \"LLaMA SciERC seed=123: early cross-model multi-seed test. Verifies LLaMA NER signal pattern is reproducible across sampling seeds.\"}, \"exp_008_re_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:08:51.386Z\", \"updated_at\": \"2026-05-17T02:57:58.166Z\", \"spec\": {\"description\": \"RE N=16 on SciERC, seed=123, seed robustness test for relation extraction\", \"hypothesis\": \"Structural consistency correlates with per-instance RE F1, robust across seeds\", \"command\": \"CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask re --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_008_re_seed123\", \"server\": \"bjb1-21071\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"gpu\": [\"cuda:3\"], \"backend\": \"tmux\", \"tmux_session\": \"exp008_rs123\", \"account\": \"root\", \"log_path\": \"output/exp_008_re_seed123/run.log\"}, \"log_path\": \"output/exp_008_re_seed123/run.log\", \"conclusion\": \"negative\", \"metrics\": {\"greedy_f1\": 0.4229, \"oracle_f1\": 0.6244, \"oracle_headroom\": 0.2015, \"fleiss_kappa_mean\": 0.3455, \"soft_jaccard_mean\": 0.6126, \"sample_f1_mean\": 0.3594, \"sample_f1_std\": 0.3793, \"sample_f1_zero_pct\": 44.1, \"structural_gt_surface\": false, \"rho_kappa_f1_full\": 0.3174, \"rho_sj_f1_full\": 0.2835, \"rho_kappa_f1_cond\": 0.0766, \"rho_sj_f1_cond\": 0.2877, \"logprob_auroc_full\": 0.6499, \"logprob_auroc_cond\": 0.5265, \"verdict\": \"FAIL\"}, \"checkpoint_path\": \"N/A\", \"completed_at\": \"2026-05-14T15:21:39.591Z\", \"hypothesis\": \"RE seed=123 multi-seed: tests reproducibility of RE signal rankings. Hypothesis: RE signals weaker than NER due to higher zero-F1 rate, but ranking should be seed-stable.\"}, \"exp_001_seed42_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:34:02.350Z\", \"updated_at\": \"2026-05-17T02:57:57.324Z\", \"spec\": {\"description\": \"NER N=16 on SciERC, seed=42, ft_002_v2, with logprobs\", \"hypothesis\": \"Structural consistency (Fleiss kappa, Soft Jaccard) correlates with per-instance NER F1 on SciERC\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"ft_002_v2\", \"seed\": 42, \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed42_v2\", \"gpu\": [\"cuda:1\"], \"pid\": \"78728\", \"backend\": \"tmux\", \"account\": \"root\", \"log_path\": \"output/exp_001_seed42_v2/run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"sj_rho_full\": 0.428, \"sj_rho_cond\": 0.369, \"structural_minus_surface\": 0.147, \"conclusion_note\": \"NER seed42 robustness confirmed, structural>surface +0.147\"}, \"checkpoint_path\": \"N/A (inference)\", \"completed_at\": \"2026-05-14T15:23:34.091Z\", \"log_path\": \"output/exp_001_seed42_v2/\", \"hypothesis\": \"SciERC NER seed=42 v2: primary seed baseline under corrected pipeline. Establishes canonical signal rankings (SJ>FK>LP) for NER with gold-filtering.\"}, \"exp_001_seed123_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:34:04.210Z\", \"updated_at\": \"2026-05-17T02:57:42.106Z\", \"spec\": {\"description\": \"NER N=16 on SciERC, seed=123, ft_002_v2, with logprobs\", \"hypothesis\": \"Structural consistency (Fleiss kappa, Soft Jaccard) correlates with per-instance NER F1 on SciERC (seed robustness check)\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"ft_002_v2\", \"seed\": 123, \"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed123_v2\", \"gpu\": [\"cuda:2\"], \"pid\": \"78733\", \"backend\": \"tmux\", \"account\": \"root\", \"log_path\": \"output/exp_001_seed123_v2/run.log\"}, \"conclusion\": \"success\", \"metrics\": {\"sj_rho_full\": 0.424, \"sj_rho_cond\": 0.376, \"structural_minus_surface\": 0.149, \"conclusion_note\": \"NER seed123 robustness confirmed, structural>surface +0.149\"}, \"checkpoint_path\": \"N/A (inference)\", \"completed_at\": \"2026-05-14T15:23:35.076Z\", \"log_path\": \"output/exp_001_seed123_v2/\", \"hypothesis\": \"SciERC NER seed=123 v2: second seed for multi-seed validation. Establishes reproducibility of structural>surface signal ranking across random seeds.\"}, \"exp_008_re_n16_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:34:06.296Z\", \"updated_at\": \"2026-05-17T02:57:41.178Z\", \"spec\": {\"description\": \"RE N=16 on SciERC full set confirmation, ft_002_v2, with logprobs\", \"hypothesis\": \"Structural consistency correlates with per-instance RE F1 on SciERC full dataset\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"ft_002_v2\", \"seed\": 42, \"command\": \"CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask re --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_008_re_n16_v2\", \"gpu\": [\"cuda:3\"], \"pid\": \"78737\", \"backend\": \"tmux\", \"account\": \"root\", \"log_path\": \"output/exp_008_re_n16_v2/run.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"sj_rho_full\": 0.281, \"sj_rho_cond\": 0.308, \"f1_zero_pct\": 44.3, \"conclusion_note\": \"RE N=16 v2 negative: SJ weak, 44.3% F1=0\"}, \"checkpoint_path\": \"N/A (inference)\", \"completed_at\": \"2026-05-14T15:23:35.598Z\", \"log_path\": \"output/exp_008_re_n16_v2/\", \"hypothesis\": \"RE N=16 evaluation v2: tests structural signal effectiveness on relation extraction at higher sample count. Hypothesis: SJ/FK benefit from more samples on RE task where zero-F1 rate is high.\"}, \"exp_005_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:28:14.924Z\", \"updated_at\": \"2026-05-17T02:57:38.756Z\", \"spec\": {\"description\": \"Temperature sensitivity analysis: T=0.7 vs T=1.0 across 5 signals (SJ, FK, logprob, EM, voting_conf)\", \"command\": \"python code/analyze_exp005_v2_temperature.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/mvp_pilot_004 + output/mvp_pilot_005 + output/exp_012_logprob\", \"data_count\": 551, \"model_name\": \"Qwen3-8B-SciERC-LoRA\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp_005_v2_temperature/temperature_sensitivity_report.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:28:35.949Z\", \"hypothesis\": \"Selection F1 analysis v2: compute actual selection F1 (pick best sample by each signal) vs greedy and oracle. First evidence of correlation-selection gap under corrected pipeline.\"}, \"exp_006_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:30:02.348Z\", \"updated_at\": \"2026-05-17T02:57:36.914Z\", \"spec\": {\"command\": \"python3 code/exp_006_v2_selection.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_{001_seed42,001_seed123,002_conll,008_re}_v2/\", \"data_count\": 4952, \"model_name\": \"Qwen3-8B-SciERC-merged-v2\", \"seed\": 42}, \"conclusion\": \"negative\", \"checkpoint_path\": \"output/exp_006_v2/exp_006_v2_results.json\", \"log_path\": \"output/exp_006_v2_run.log\", \"completed_at\": \"2026-05-14T15:30:32.474Z\", \"metrics\": {\"NER_SciERC_s42\": {\"greedy\": 0.618, \"oracle\": 0.787, \"SJ\": 0.62, \"logprob\": 0.621, \"FK\": 0.621, \"EM\": 0.606, \"voting_conf\": 0.585, \"random\": 0.586}, \"NER_SciERC_s123\": {\"greedy\": 0.618, \"oracle\": 0.785, \"SJ\": 0.617, \"logprob\": 0.618, \"FK\": 0.621, \"EM\": 0.613, \"voting_conf\": 0.584, \"random\": 0.583}, \"NER_CoNLL\": {\"greedy\": 0.725, \"oracle\": 0.757, \"SJ\": 0.718, \"logprob\": 0.716, \"FK\": 0.717, \"EM\": 0.716, \"voting_conf\": 0.714, \"random\": 0.692}, \"RE_SciERC\": {\"greedy\": 0.403, \"oracle\": 0.631, \"SJ\": 0.397, \"logprob\": 0.41, \"FK\": 0.396, \"EM\": 0.381, \"voting_conf\": 0.408, \"random\": 0.364}}, \"hypothesis\": \"Temperature sensitivity v2: tests signal effectiveness at T=0.5,0.7,1.0,1.2. Hypothesis: structural signals are temperature-robust while LP degrades at extreme temperatures.\"}, \"exp_004_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:31:40.554Z\", \"updated_at\": \"2026-05-17T02:57:35.012Z\", \"conclusion\": \"success\", \"spec\": {\"command\": \"python code/analyze_exp004_v2_re_diagnostic.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_012_logprob/samples_with_logprobs.jsonl\", \"data_count\": 551, \"model_name\": \"Qwen3-8B-SciERC-merged-v2\", \"seed\": 42, \"checkpoint_path\": \"N/A\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp004v2_re_diagnostic/\"}, \"completed_at\": \"2026-05-14T15:32:04.966Z\", \"hypothesis\": \"N-ablation v2 (N=4,8,16,32): tests how sample count affects signal ρ and selection F1. Validates N-scaling curve for structural vs surface signals under corrected pipeline.\"}, \"exp_009_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:36:47.946Z\", \"updated_at\": \"2026-05-17T02:57:32.655Z\", \"spec\": {\"command\": \"python3 code/exp_009_v2_stratification.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_001_seed42_v2 + exp_001_seed123_v2 + exp_008_re_n16_v2\", \"data_count\": 551, \"model_name\": \"analysis\", \"seed\": 42}, \"checkpoint_path\": \"output/exp_009_v2/results.json\", \"log_path\": \"output/exp_009_v2_run.log\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:37:18.311Z\", \"metrics\": {\"ner_seed42_global\": {\"sj_rho\": 0.431, \"fk_rho\": 0.325, \"logprob_rho\": 0.203, \"voting_conf_rho\": 0.475, \"em_rho\": 0.292}, \"ner_seed123_global\": {\"sj_rho\": 0.422, \"fk_rho\": 0.315, \"logprob_rho\": 0.226, \"voting_conf_rho\": 0.438, \"em_rho\": 0.299}, \"re_seed42_global\": {\"sj_rho\": 0.063, \"fk_rho\": 0.226, \"logprob_rho\": 0.4, \"voting_conf_rho\": 0.22, \"em_rho\": -0.132}, \"ner_seed_stability_max_delta\": 0.037, \"independent_proxies\": [\"sent_len\", \"ent_count\", \"type_diversity\"], \"inverted_u_ner\": \"not confirmed (ρ stable across independent proxies)\", \"inverted_u_re\": \"monotonic increase with complexity, not inverted-U\"}, \"hypothesis\": \"Capability stratification v2: corrected stratification with gold-filtering and extended to NER conditional analysis. Tests which instance subpopulations drive overall signal effectiveness.\"}, \"exp_016_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:39:07.501Z\", \"updated_at\": \"2026-05-17T02:57:30.726Z\", \"spec\": {\"command\": \"python code/exp_016_v2_ensemble.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_001_seed42_v2 + exp_001_seed123_v2 + exp_008_re_n16_v2\", \"data_count\": 551, \"model_name\": \"analysis_only\", \"seed\": 42, \"checkpoint_path\": \"output/exp_016_v2/\", \"log_path\": \"/tmp/exp016v2.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:39:34.478Z\", \"metrics\": {\"ner_conditional\": {\"n\": 529, \"best_single_signal_rho\": {\"soft_jaccard\": 0.4412}, \"best_combo_rho\": {\"sj+vc_a0.55\": 0.4552}, \"ensemble_auroc\": 0.7141, \"best_single_auroc\": {\"soft_jaccard\": 0.7166}, \"selection_f1\": {\"greedy\": 0.6442, \"logprob_best\": 0.6505, \"ensemble_best\": 0.6475, \"sj_best\": 0.6471, \"oracle\": 0.8442}}, \"re_conditional\": {\"n\": 397, \"best_single_signal_rho\": {\"voting_confidence\": 0.3849}, \"best_combo_rho\": {\"logprob+vc_a0.25\": 0.3936}, \"ensemble_auroc\": 0.6916, \"best_single_auroc\": {\"voting_confidence\": 0.7023}, \"selection_f1\": {\"greedy\": 0.403, \"logprob_best\": 0.4097, \"ensemble_best\": 0.4227, \"oracle\": 0.6306}}, \"re_full\": {\"ensemble_auroc\": 0.8608, \"best_single_auroc\": {\"voting_confidence\": 0.8248}}}, \"hypothesis\": \"Bootstrap significance v2: corrected bootstrap test for NER selection F1 gap with proper gold-filtering and multiple signals. Establishes which selection improvements are statistically significant.\"}, \"exp_001_seed456_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:38:55.569Z\", \"updated_at\": \"2026-05-17T02:57:23.336Z\", \"spec\": {\"hypothesis\": \"NER/RE N=16 seed=456 robustness test, third seed for 3-seed stability\", \"plan_id\": \"exp-001\", \"command\": \"CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed456_v2\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456, \"metrics\": {\"full_rho_kappa_f1\": 0.3383, \"full_rho_sj_f1\": 0.2988, \"cond_rho_kappa_f1\": 0.233, \"cond_rho_sj_f1\": 0.3245, \"logprob_full_rho\": 0.3405, \"logprob_full_auroc\": 0.6694, \"logprob_cond_rho\": 0.0501, \"structural_gt_surface\": false}, \"note\": \"CRITICAL: Ran with --subtask joint instead of --subtask ner. seed42/seed123 v2 used --subtask ner. Results valid for joint-mode analysis but NOT comparable for NER 3-seed protocol. Need NER-only rerun.\", \"log_path\": \"output/exp_001_seed456_v2/run.log\", \"checkpoint_path\": \"output/exp_001_seed456_v2/\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T17:12:14.682Z\", \"hypothesis\": \"SciERC joint NER+RE seed=456 v2: early pipeline version. Tests multi-seed stability of signal rankings on joint extraction task.\"}, \"exp_017_llama_conll_infer\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:33:23.653Z\", \"updated_at\": \"2026-05-17T02:57:21.948Z\", \"spec\": {\"hypothesis\": \"LLaMA-3.1-8B CoNLL-2003 inference: cross-model cross-dataset validation of structural consistency signals\", \"plan_id\": \"exp-017\", \"parent\": \"exp_017_llama_conll\", \"command\": \"python code/run_llama_conll_infer.py\", \"server\": \"autodl-5090\", \"data_path\": \"conll2003 test\", \"data_count\": 3453, \"model_name\": \"LLaMA-3.1-8B-Instruct\", \"seed\": 42, \"n_samples\": 8, \"temperature\": 1, \"description\": \"LLaMA CoNLL-2003 NER inference N=8 (cross-model + cross-dataset validation)\"}, \"metrics\": {\"greedy_f1\": 0.9266, \"oracle_f1\": 0.9443, \"oracle_headroom\": 0.0177, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"N\": 8, \"full\": {\"SJ_rho\": 0.4314, \"FK_rho\": 0.4277, \"logprob_rho\": 0.3072, \"EM_rho\": 0.4306, \"voting_conf_rho\": 0.4256, \"SJ_AUROC\": 0.7039, \"FK_AUROC\": 0.7026, \"logprob_AUROC\": 0.761, \"EM_AUROC\": 0.7046, \"voting_conf_AUROC\": 0.7088, \"SJ_ECE\": 0.1137, \"FK_ECE\": 0.1053, \"logprob_ECE\": 0.129, \"EM_ECE\": 0.1094, \"voting_conf_ECE\": 0.0949}, \"conditional\": {\"SJ_rho\": 0.4356, \"FK_rho\": 0.431, \"logprob_rho\": 0.3282, \"EM_rho\": 0.4403, \"voting_conf_rho\": 0.3743, \"SJ_AUROC\": 0.7225, \"FK_AUROC\": 0.7208, \"logprob_AUROC\": 0.8102, \"EM_AUROC\": 0.7257, \"voting_conf_AUROC\": 0.6989, \"SJ_ECE\": 0.0829, \"FK_ECE\": 0.0796, \"logprob_ECE\": 0.0922, \"EM_ECE\": 0.0754, \"voting_conf_ECE\": 0.0784}}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/samples.jsonl\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_017_llama_conll_infer/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T17:55:33.476Z\", \"notes\": \"LLaMA CoNLL-2003 NER N=8 (not N=16, cost constraint: 3453 test instances). SJ ρ=0.431 > logprob ρ=0.307 (Δ=+0.124). ρ-AUROC dissociation: logprob AUROC=0.761 > SJ AUROC=0.704. All 4 structural signals ρ>0.42 vs logprob 0.31. Directly comparable to exp_002 (Qwen CoNLL N=8) and exp_007 (LLaMA SciERC N=8).\", \"hypothesis\": \"LLaMA CoNLL N=8 baseline inference: initial cross-model test on CoNLL before scaling to N=16. Establishes LLaMA can do CoNLL NER effectively.\"}, \"exp_003_wnut17_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:32:56.415Z\", \"updated_at\": \"2026-05-17T02:57:20.068Z\", \"spec\": {\"description\": \"WNUT-17 retrain: downsample gold-empty instances to ≤25%, fine-tune Qwen3-8B, inference N=16 T=1.0 with log-probs\", \"hypothesis\": \"After removing excess empty instances, structural consistency signals (SJ) will show stronger correlation on social media NER\", \"plan_id\": \"exp-003\", \"claim\": 1, \"model_name\": \"Qwen3-8B\", \"dataset\": \"WNUT-17 (downsampled)\", \"priority\": \"P0\", \"parent\": \"exp_003_ner_wnut17\", \"command\": \"CUDA_VISIBLE_DEVICES=1 llamafactory-cli train train_config_wnut17.yaml\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/wnut17/llmfactory_train_downsampled.json\", \"data_count\": 1637, \"seed\": 42, \"pid\": 92215, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/train_wnut17.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-wnut17-lora\", \"downsampling\": \"empty instances 63.8% -> 25.0%, total 3394 -> 1637\", \"metrics\": {\"train_loss\": 0.105, \"eval_loss\": 0.0836, \"epochs\": 5, \"train_time_min\": 16.37, \"train_samples_per_sec\": 8.33}, \"note\": \"D045: Training succeeded (train_loss=0.105) but inference FAIL: 54% F1=0, SJ rho=0.062 (p=0.106). WNUT-17 abandoned — model capability insufficient on social media NER. Paper reports as Claim 3 (capability boundary) evidence.\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T18:11:36.559Z\", \"hypothesis\": \"WNUT-17 NER evaluation v2: tests signal effectiveness on noisy social media text. Hypothesis: structural signals remain effective on noisy, informal text with high entity variation.\"}, \"exp_001_seed456_v2_ner\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T17:13:00.414Z\", \"updated_at\": \"2026-05-17T02:57:18.227Z\", \"spec\": {\"hypothesis\": \"NER N=16 seed=456 robustness test (NER-only rerun, fixing subtask mismatch from exp_001_seed456_v2)\", \"plan_id\": \"exp-001\", \"parent\": \"exp_001_seed456_v2\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --collect_logprobs --output_dir output/exp_001_seed456_v2_ner\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456, \"checkpoint_source\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"eval_data\": \"data/scierc/processed_data\", \"metrics\": {\"sj_rho\": 0.384, \"structural_gt_surface\": true, \"structural_surface_delta\": 0.16}, \"log_path\": \"output/exp_001_seed456_v2_ner.log\", \"checkpoint_path\": \"output/exp_001_seed456_v2_ner/\"}, \"log_path\": \"output/exp_001_seed456_v2_ner.log\", \"pid\": 96161, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T17:52:01.372Z\", \"metrics\": {\"full\": {\"SJ\": {\"rho\": 0.384, \"auroc\": 0.711}, \"FK\": {\"rho\": 0.223, \"auroc\": 0.577}, \"logprob\": {\"rho\": 0.232, \"auroc\": 0.594}, \"EM\": {\"rho\": 0.316, \"auroc\": 0.768}, \"voting_conf\": {\"rho\": 0.411, \"auroc\": 0.712}}, \"conditional\": {\"SJ\": {\"rho\": 0.349, \"auroc\": 0.699}, \"FK\": {\"rho\": 0.157, \"auroc\": 0.561}, \"logprob\": {\"rho\": 0.171, \"auroc\": 0.576}, \"EM\": {\"rho\": 0.406, \"auroc\": 0.78}, \"voting_conf\": {\"rho\": 0.346, \"auroc\": 0.694}}, \"3seed_mean_SJ_rho_full\": 0.412, \"3seed_sd_SJ_rho_full\": 0.025, \"structural_beats_surface\": true, \"verdict\": \"MARGINAL\"}, \"hypothesis\": \"SciERC NER seed=456 v2: corrected pipeline rerun with gold-filtering. Part of multi-seed validation protocol for NER signal ranking stability.\"}, \"exp_009_v2_re_rerun\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:56:31.535Z\", \"updated_at\": \"2026-05-17T02:57:16.383Z\", \"spec\": {\"command\": \"python code/exp_009_v2_re_rerun.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_008_re_n16_v2/samples.jsonl\", \"data_count\": 397, \"model_name\": \"cpu_analysis\", \"seed\": 42, \"checkpoint_source\": \"exp_008_re_n16_v2\", \"checkpoint_path\": \"output/exp_009_v2_re_rerun/results.json\", \"log_path\": \"/tmp/re_rerun.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T18:56:58.168Z\", \"hypothesis\": \"Capability stratification v2 (RE rerun): corrected stratification analysis for RE with proper gold-filtering. Fixes early pipeline bug affecting RE quartile ρ values.\"}, \"exp_007_llama_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T18:31:44.366Z\", \"updated_at\": \"2026-05-17T02:57:12.521Z\", \"spec\": {\"hypothesis\": \"LLaMA SciERC N=16: cross-model N-scaling validation. If SJ rho increases from N=8 (0.363) to N=16, N-scaling is model-agnostic.\", \"plan_id\": \"exp-007\", \"parent\": \"exp_007_llama_inference\", \"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_007_llama_n16\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"llama3.1-8b-scierc-merged\", \"seed\": 42, \"checkpoint_source\": \"checkpoints/llama3.1-8b-scierc-merged\", \"eval_data\": \"data/scierc/processed_data\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/exp_007_llama_n16/samples.jsonl\", \"log_path\": \"output/exp_007_llama_n16.log\", \"completed_at\": \"2026-05-14T19:03:39.163Z\", \"metrics\": {\"N\": 16, \"dataset\": \"scierc\", \"subtask\": \"ner\", \"n_instances\": 551, \"n_valid\": 529, \"n_conditional\": 478, \"greedy_f1\": 0.645, \"full\": {\"SJ_rho\": 0.3791, \"FK_rho\": 0.3081, \"logprob_rho\": 0.2041, \"EM_rho\": 0.3159, \"voting_conf_rho\": 0.4515, \"SJ_AUROC\": 0.717, \"FK_AUROC\": 0.6581, \"logprob_AUROC\": 0.5656, \"EM_AUROC\": 0.7686, \"voting_conf_AUROC\": 0.7266, \"SJ_ECE\": 0.1019, \"FK_ECE\": 0.1556, \"logprob_ECE\": 0.084, \"EM_ECE\": 0.1761, \"voting_conf_ECE\": 0.1365}, \"conditional\": {\"SJ_rho\": 0.3222, \"FK_rho\": 0.2182, \"logprob_rho\": 0.1286, \"EM_rho\": 0.3563, \"voting_conf_rho\": 0.3356, \"SJ_AUROC\": 0.7014, \"FK_AUROC\": 0.6392, \"logprob_AUROC\": 0.545, \"EM_AUROC\": 0.7708, \"voting_conf_AUROC\": 0.6988, \"SJ_ECE\": 0.1466, \"FK_ECE\": 0.1853, \"logprob_ECE\": 0.1141, \"EM_ECE\": 0.1887, \"voting_conf_ECE\": 0.2634}, \"n8_vs_n16_delta_rho_full\": {\"SJ\": 0.0161, \"FK\": -0.0185, \"logprob\": 0.0214, \"EM\": 0.0007, \"voting_conf\": 0.0184}}, \"hypothesis\": \"LLaMA SciERC N=16: cross-model NER signal evaluation at higher sample count. Tests if LLaMA shows same N-scaling benefit for structural signals as Qwen.\"}, \"exp_017_llama_conll_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:19:35.318Z\", \"updated_at\": \"2026-05-17T02:56:57.283Z\", \"spec\": {\"hypothesis\": \"LLaMA CoNLL N=16: complete the 2x2 matrix (model x dataset x N). If SJ N-scaling holds for LLaMA on CoNLL, the finding is fully cross-model cross-dataset.\", \"plan_id\": \"exp-017\", \"parent\": \"exp_017_llama_conll_infer\", \"model_name\": \"llama3.1-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"data_count\": 3453, \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --collect_logprobs --output_dir output/exp_017_llama_conll_n16\", \"data_path\": \"data/conll2003\", \"pid\": 106997, \"n_samples\": 16, \"temperature\": 1, \"checkpoint_source\": \"checkpoints/llama3.1-8b-conll2003-merged\", \"eval_data\": \"conll2003 test set\", \"checkpoint_path\": \"output/exp_017_llama_conll_n16/samples.jsonl\", \"log_path\": \"output/exp_017_llama_conll_n16/all_signals_report.json\"}, \"metrics\": {\"greedy_f1\": 0.9243, \"oracle_f1\": 0.9487, \"oracle_headroom\": 0.0244, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"structural_beats_surface\": true, \"full\": {\"SJ_rho\": 0.4642, \"SJ_AUROC\": 0.7391, \"SJ_ECE\": 0.1131, \"FK_rho\": 0.4566, \"FK_AUROC\": 0.736, \"FK_ECE\": 0.1071, \"logprob_rho\": 0.3058, \"logprob_AUROC\": 0.7594, \"logprob_ECE\": 0.1288, \"EM_rho\": 0.4613, \"EM_AUROC\": 0.7391, \"EM_ECE\": 0.1084, \"voting_conf_rho\": 0.4554, \"voting_conf_AUROC\": 0.7406, \"voting_conf_ECE\": 0.0844}, \"conditional\": {\"SJ_rho\": 0.4597, \"SJ_AUROC\": 0.7565, \"SJ_ECE\": 0.0846, \"FK_rho\": 0.4515, \"FK_AUROC\": 0.753, \"FK_ECE\": 0.0813, \"logprob_rho\": 0.3193, \"logprob_AUROC\": 0.8023, \"logprob_ECE\": 0.0921, \"EM_rho\": 0.4618, \"EM_AUROC\": 0.7589, \"EM_ECE\": 0.0757, \"voting_conf_rho\": 0.3978, \"voting_conf_AUROC\": 0.7287, \"voting_conf_ECE\": 0.0742}, \"best_of_n\": {\"greedy\": 0.9243, \"random_avg\": 0.9213, \"sj_best\": 0.9259, \"logprob_best\": 0.925, \"voting_conf_best\": 0.9268, \"oracle\": 0.9487}, \"n8_vs_n16_delta\": {\"full_SJ_rho_delta\": 0.0328, \"full_FK_rho_delta\": 0.0289, \"full_logprob_rho_delta\": -0.0014, \"full_EM_rho_delta\": 0.0307, \"full_voting_conf_rho_delta\": 0.0298, \"cond_SJ_rho_delta\": 0.0241, \"cond_FK_rho_delta\": 0.0205, \"cond_logprob_rho_delta\": -0.0089, \"cond_EM_rho_delta\": 0.0215, \"cond_voting_conf_rho_delta\": 0.0235}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T19:45:16.265Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=42 (original): cross-model validation on CoNLL. First evidence that structural>surface ranking generalizes from Qwen to LLaMA model family.\"}, \"exp_015_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T15:34:23.336Z\", \"updated_at\": \"2026-05-17T02:56:55.830Z\", \"spec\": {\"command\": \"python code/analyze_exp015_v2_metrics.py\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/ (10 datasets)\", \"data_count\": 9148, \"model_name\": \"Qwen3-8B + LLaMA (multi-model)\", \"seed\": \"42,123,456 (multi-seed)\", \"checkpoint_path\": \"N/A (analysis only)\", \"log_path\": \"/tmp/exp015_v2.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T15:34:56.741Z\", \"metrics\": {\"scierc_ner_avg\": {\"sj_auroc\": 0.7394, \"fk_auroc\": 0.6172, \"em_auroc\": 0.7873, \"voting_auroc\": 0.7367, \"logprob_auroc\": 0.5918}, \"scierc_re_avg\": {\"sj_auroc\": 0.6746, \"fk_auroc\": 0.5939, \"em_auroc\": 0.715, \"voting_auroc\": 0.7234, \"logprob_auroc\": 0.5849}}, \"hypothesis\": \"Metrics expansion v2: corrected evaluation with proper conditional filtering. Updates exp_015 with gold-filtered pipeline to fix RE conditional ρ values that used wrong filter criterion.\"}, \"exp_001_n16_seed456\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-14T12:10:30.350Z\", \"updated_at\": \"2026-05-17T02:56:53.526Z\", \"completed_at\": \"2026-05-14T12:28:38.721Z\", \"extra\": {\"previous_failure\": {\"conclusion\": \"success\", \"metrics\": {\"ner\": {\"greedy_f1\": 0.6577, \"oracle_f1\": 0.8129, \"headroom\": 0.1553, \"rho_sj_full\": 0.3297, \"rho_fk_full\": 0.2578, \"rho_logprob_full\": 0.2866, \"rho_sj_cond\": 0.3394, \"rho_fk_cond\": 0.2721, \"rho_logprob_cond\": 0.2567, \"sj_beats_fk\": true, \"rho_advantage\": 0.0719}, \"re\": {\"greedy_f1\": 0.4312, \"oracle_f1\": 0.6737, \"headroom\": 0.2425, \"rho_sj_full\": 0.285, \"rho_fk_full\": 0.2372, \"rho_logprob_full\": 0.2626, \"rho_sj_cond\": 0.3525, \"rho_fk_cond\": 0.2614, \"rho_logprob_cond\": 0.1927, \"sj_beats_fk\": true, \"rho_advantage\": 0.0478}, \"verdict\": \"FAIL\"}}}, \"spec\": {\"hypothesis\": \"N=16 seed456 multi-seed robustness verification for SciERC NER+RE\", \"plan_id\": \"exp-001\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"seed\": 456, \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --output_dir output/exp001_n16_seed456 --collect_logprobs\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"174595\", \"log_path\": \"output/exp001_n16_seed456_run.log\", \"tmux_session\": \"exp_001_n16_seed456\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (inference-only)\", \"metrics\": {\"instance_count\": 551, \"n_valid\": 529, \"n_gold_empty\": 22, \"parse_rate\": 1, \"ner_greedy_f1\": 0.6617, \"ner_oracle_f1\": 0.8075, \"re_greedy_f1\": 0.4215, \"re_oracle_f1\": 0.4748, \"rho_sj_ner\": 0.4098, \"rho_fk_ner\": 0.2723, \"rho_vc_ner\": 0.4449, \"rho_em_ner\": 0.3363, \"rho_lp_ner\": 0.2415, \"rho_sj_re\": 0.2835, \"rho_fk_re\": 0.2929, \"auroc_sj_ner\": 0.6823, \"auroc_fk_ner\": 0.6179, \"auroc_vc_ner\": 0.6981, \"auroc_em_ner\": 0.649, \"auroc_lp_ner\": 0.5885, \"rho_note\": \"CORRECTED 2026-05-15: old values (rho_fk=0.3448,rho_sj=0.4134) included 22 gold-empty instances. Now uses gold-filtered pipeline (n=529).\"}, \"log_path\": \"output/exp001_n16_seed456_run.log\", \"hypothesis\": \"SciERC N=16 seed=456: early multi-seed validation of structural signal rankings at N=16 sample count. Establishes seed stability for SJ/FK/VC/EM ordering.\"}, \"exp_011_ood_scierc_to_conll\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:36:07.210Z\", \"updated_at\": \"2026-05-17T02:56:29.417Z\", \"spec\": {\"hypothesis\": \"SCS structural signals remain effective under domain shift (SciERC model on CoNLL data)\", \"plan_id\": \"exp-011\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"data_path\": \"data/conll2003\", \"seed\": 42, \"pid\": 179761, \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --dataset conll2003 --data_dir data/conll2003 --subtask ner --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 42 --collect_logprobs --output_dir output/exp_011_ood_scierc_to_conll\", \"data_count\": 3500}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/exp_011_ood_scierc_to_conll/samples.jsonl\", \"log_path\": \"output/exp_011_ood_scierc_to_conll/report.json\", \"completed_at\": \"2026-05-15T11:47:47.953Z\", \"metrics\": {\"greedy_ner_f1\": 0.522, \"rho_vc\": 0.469, \"rho_sj\": 0.378, \"rho_em\": 0.3, \"rho_fk\": 0.285, \"rho_lp\": 0.246}, \"hypothesis\": \"Out-of-domain transfer: SciERC-trained model on CoNLL data. Tests if confidence signals work under partial schema overlap (SciERC has Organization/Person which overlap with CoNLL ORG/PER). Complement to exp_011_ood_conll_to_scierc.\"}, \"exp_qwen3_4b_scierc_finetune_v4\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:26:25.512Z\", \"updated_at\": \"2026-05-17T02:56:24.418Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && llamafactory-cli train train_config_scierc_4b.yaml\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"pid\": \"227123\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen3_4b_scierc_finetune_v4.log\", \"submitted_at\": \"2026-05-15T19:26:31.444Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"wall_clock_seconds\": 1668.8, \"gpu_hours\": 0.46}, \"conclusion\": \"success\", \"metrics\": {\"total_steps\": 585, \"completed_steps\": 585, \"best_checkpoint\": \"checkpoint-400\", \"best_eval_loss\": 0.0898, \"epochs\": 5}, \"checkpoint_path\": \"checkpoints/qwen3-4b-scierc-merged/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen3_4b_scierc_finetune_v4.log\", \"completed_at\": \"2026-05-15T19:54:20.255Z\", \"hypothesis\": \"Qwen3-4B SciERC LoRA fine-tune v4: training the smaller 4B model to complete the 2x2 scale matrix (4B×SciERC cell). Validates that fine-tuning convergence patterns hold across model scales.\"}, \"exp_011_ood_conll_to_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T11:36:08.325Z\", \"updated_at\": \"2026-05-17T02:56:14.242Z\", \"spec\": {\"hypothesis\": \"SCS structural signals remain effective under domain shift (CoNLL model on SciERC data, joint NER+RE)\", \"plan_id\": \"exp-011\", \"model_name\": \"qwen3-8b-conll2003-merged\", \"data_path\": \"data/scierc/processed_data\", \"seed\": 42, \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"pid\": 181723, \"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --dataset scierc --data_dir data/scierc/processed_data --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 42 --collect_logprobs --output_dir output/exp_011_ood_conll_to_scierc\", \"data_count\": 551}, \"conclusion\": \"negative\", \"checkpoint_path\": \"output/exp_011_ood_conll_to_scierc/samples.jsonl\", \"log_path\": \"output/exp_011_ood_conll_to_scierc/report.json\", \"completed_at\": \"2026-05-15T11:50:21.969Z\", \"metrics\": {\"greedy_ner_f1\": 0.009, \"greedy_re_f1\": 0.001, \"avg_structural_rho\": -0.05, \"verdict\": \"FAIL\", \"reason\": \"schema_incompatibility\", \"direction\": \"CoNLL_model_to_SciERC_data\", \"sample_f1_pct_zero_ner\": 98.06, \"rho_sj_ner\": -0.186, \"rho_fk_ner\": -0.069, \"note\": \"Schema incompatibility (CoNLL PER/ORG/LOC/MISC vs SciERC Task/Method/Material) causes catastrophic failure. Cannot evaluate confidence signals.\"}, \"hypothesis\": \"Out-of-domain transfer test: CoNLL-trained model on SciERC data. Tests if confidence signals retain correlation with quality under severe schema mismatch (CoNLL PER/ORG/LOC/MISC vs SciERC Task/Method/Material).\"}, \"exp_freeform_seed789_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:24:26.805Z\", \"updated_at\": \"2026-05-17T02:56:11.818Z\", \"spec\": {\"log_path\": \"~/runs/struct_self_consist_ie/exp_freeform_seed789_v3.log\", \"checkpoint_path\": \"results/exp_freeform_ablation_seed789/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:30:51.048Z\", \"metrics\": {\"n_instances\": 551, \"n_samples\": 8, \"parse_rate_pct\": 100, \"elapsed_seconds\": 229.7, \"freeform_ner_selection_gap\": 0.0028, \"freeform_re_selection_gap\": 0.0219, \"freeform_lp_std\": 0.0183, \"freeform_lp_range\": 0.054908, \"freeform_tied_pct\": 59, \"re_lp_flip_positive\": true, \"variance_ratio_std\": 0.89, \"variance_ratio_range\": 0.88}, \"hypothesis\": \"Free-form SciERC seed=789 v3 (bugfix rerun): corrected version of free-form inference after fixing parsing/generation issues in v1/v2. Provides clean data point for 4-seed free-form analysis.\"}, \"exp_freeform_seed789\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:38:29.851Z\", \"updated_at\": \"2026-05-17T02:56:09.888Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python run_freeform_inference.py --seed 789 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation_seed789\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"216722\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_freeform_seed789.log\", \"submitted_at\": \"2026-05-15T18:58:46.406Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 92.2, \"gpu_hours\": 0.03}, \"notes\": \"Rerun with fixed seed-passing code on cuda:3. Original run was killed for GPU reallocation. Parse rate 100%, 227.5s elapsed. LP compression confirmed: tied_pct=59.0% (vs constrained 59.7%), variance_ratio=0.89x.\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:00:18.576Z\", \"metrics\": {\"inference\": {\"n_instances\": 551, \"n_samples\": 8, \"total_samples\": 4408, \"total_parsed\": 4408, \"parse_rate_pct\": 100, \"elapsed_seconds\": 227.5}, \"freeform\": {\"selection_ner\": {\"greedy\": 0.6205, \"selected\": 0.6232, \"gap\": 0.0027}, \"selection_re\": {\"greedy\": 0.2909, \"selected\": 0.31, \"gap\": 0.0191}, \"logprob_variance\": {\"mean_std\": 0.0183, \"mean_range\": 0.054908, \"tied_pct\": 59}, \"qe_ner\": {\"n\": 529, \"SJ\": {\"rho\": 0.393995, \"auroc\": 0.734474}, \"FK\": {\"rho\": 0.312292, \"auroc\": 0.794384}, \"LP\": {\"rho\": 0.247096, \"auroc\": 0.677824}, \"EM\": {\"rho\": 0.320383, \"auroc\": 0.527033}, \"VC\": {\"rho\": 0.420625, \"auroc\": 0.768111}}, \"qe_re\": {\"n\": 397, \"SJ\": {\"rho\": 0.201746, \"auroc\": 0.574388}, \"FK\": {\"rho\": 0.2202, \"auroc\": 0.633014}, \"LP\": {\"rho\": 0.295765, \"auroc\": 0.687067}, \"EM\": {\"rho\": 0.103633, \"auroc\": 0.474737}, \"VC\": {\"rho\": 0.306868, \"auroc\": 0.642197}}}, \"constrained_ref\": {\"selection_ner\": {\"greedy\": 0.6182, \"selected\": 0.6241, \"gap\": 0.0059}, \"selection_re\": {\"greedy\": 0.2913, \"selected\": 0.2845, \"gap\": -0.0068}, \"logprob_variance\": {\"mean_std\": 0.020589, \"mean_range\": 0.062305, \"tied_pct\": 59.7}}, \"comparison\": {\"variance_ratio_std\": 0.89, \"variance_ratio_range\": 0.88, \"tied_reduction_pp\": 0.7}}, \"hypothesis\": \"Free-form SciERC seed=789: multi-seed replication of free-form ablation. Validates LP compression persistence and structural signal robustness across sampling seeds under unconstrained generation.\"}, \"exp_freeform_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:14:48.842Z\", \"updated_at\": \"2026-05-17T02:56:09.256Z\", \"spec\": {\"hypothesis\": \"Multi-seed free-form ablation (seed=456): verify RE LP flip and NER gap stability\", \"command\": \"python run_freeform_inference.py --seed 456 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation_seed456\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 456, \"gpu\": \"cuda:2\", \"tmux_session\": \"exp_freeform_seed456\", \"log_path\": \"results/exp_freeform_ablation_seed456/run_summary.json\", \"checkpoint_path\": \"results/exp_freeform_ablation_seed456\"}, \"metrics\": {\"inference\": {\"n_instances\": 551, \"n_samples\": 8, \"total_samples\": 4408, \"total_parsed\": 4407, \"parse_rate_pct\": 99.98, \"elapsed_seconds\": 232.4}, \"freeform\": {\"selection_ner\": {\"greedy\": 0.6198, \"selected\": 0.6205, \"gap\": 0.0007}, \"selection_re\": {\"greedy\": 0.2908, \"selected\": 0.3108, \"gap\": 0.02}, \"logprob_variance\": {\"mean_std\": 0.018631, \"mean_range\": 0.056792, \"tied_pct\": 58.4}, \"qe_ner\": {\"n\": 529, \"SJ\": {\"rho\": 0.378498, \"auroc\": 0.707769}, \"FK\": {\"rho\": 0.286163, \"auroc\": 0.754779}, \"LP\": {\"rho\": 0.227089, \"auroc\": 0.672081}, \"EM\": {\"rho\": 0.319997, \"auroc\": 0.47789}, \"VC\": {\"rho\": 0.416853, \"auroc\": 0.756543}}, \"qe_re\": {\"n\": 397, \"SJ\": {\"rho\": 0.211331, \"auroc\": 0.572335}, \"FK\": {\"rho\": 0.259074, \"auroc\": 0.652998}, \"LP\": {\"rho\": 0.306382, \"auroc\": 0.70134}, \"EM\": {\"rho\": 0.1043, \"auroc\": 0.461641}, \"VC\": {\"rho\": 0.301507, \"auroc\": 0.628873}}}, \"constrained_ref\": {\"selection_ner\": {\"greedy\": 0.6182, \"selected\": 0.6241, \"gap\": 0.0059}, \"selection_re\": {\"greedy\": 0.2913, \"selected\": 0.2845, \"gap\": -0.0068}, \"logprob_variance\": {\"mean_std\": 0.020589, \"mean_range\": 0.062305, \"tied_pct\": 59.7}}, \"comparison\": {\"variance_ratio_std\": 0.9, \"variance_ratio_range\": 0.91, \"tied_reduction_pp\": 1.3}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:12:29.413Z\", \"hypothesis\": \"Free-form SciERC seed=456: multi-seed replication of free-form ablation. Validates LP compression persistence and structural signal robustness across sampling seeds under unconstrained generation.\"}, \"exp_freeform_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T17:14:47.765Z\", \"updated_at\": \"2026-05-17T02:56:06.903Z\", \"spec\": {\"hypothesis\": \"Multi-seed free-form ablation (seed=123): verify RE LP flip and NER gap stability\", \"command\": \"python run_freeform_inference.py --seed 123 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation_seed123\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"gpu\": \"cuda:1\", \"tmux_session\": \"exp_freeform_seed123\", \"log_path\": \"results/exp_freeform_ablation_seed123/run_summary.json\", \"checkpoint_path\": \"results/exp_freeform_ablation_seed123\"}, \"metrics\": {\"inference\": {\"n_instances\": 551, \"n_samples\": 8, \"total_samples\": 4408, \"total_parsed\": 4406, \"parse_rate_pct\": 99.95, \"elapsed_seconds\": 228.1}, \"freeform\": {\"selection_ner\": {\"greedy\": 0.6194, \"selected\": 0.6222, \"gap\": 0.0028}, \"selection_re\": {\"greedy\": 0.2874, \"selected\": 0.305, \"gap\": 0.0176}, \"logprob_variance\": {\"mean_std\": 0.019881, \"mean_range\": 0.059864, \"tied_pct\": 57.7}, \"qe_ner\": {\"n\": 529, \"SJ\": {\"rho\": 0.384214, \"auroc\": 0.748728}, \"FK\": {\"rho\": 0.323956, \"auroc\": 0.766039}, \"logprob\": {\"rho\": 0.217297, \"auroc\": 0.701657}, \"EM\": {\"rho\": 0.326887, \"auroc\": 0.52533}, \"voting_conf\": {\"rho\": 0.407893, \"auroc\": 0.799676}}, \"qe_re\": {\"n\": 397, \"SJ\": {\"rho\": 0.272776, \"auroc\": 0.614056}, \"FK\": {\"rho\": 0.314429, \"auroc\": 0.678534}, \"logprob\": {\"rho\": 0.309673, \"auroc\": 0.70414}, \"EM\": {\"rho\": 0.137216, \"auroc\": 0.487342}, \"voting_conf\": {\"rho\": 0.316667, \"auroc\": 0.647442}}}, \"constrained_ref\": {\"selection_ner\": {\"greedy\": 0.6182, \"selected\": 0.6241, \"gap\": 0.0059}, \"selection_re\": {\"greedy\": 0.2913, \"selected\": 0.2845, \"gap\": -0.0068}}, \"comparison\": {\"variance_ratio_std\": 0.97, \"variance_ratio_range\": 0.96, \"tied_reduction_pp\": 2}}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-15T19:29:48.939Z\", \"hypothesis\": \"Free-form SciERC seed=123: multi-seed replication of free-form ablation. Validates LP compression persistence and structural signal robustness across sampling seeds under unconstrained generation.\"}, \"exp_009_capability_stratification\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T14:59:24.201Z\", \"updated_at\": \"2026-05-17T02:56:02.685Z\", \"spec\": {\"command\": \"python code/exp009_stratification_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp001_n16_seed42 + output/exp008_re_n16 + output/exp002_conll2003\", \"data_count\": 4555, \"model_name\": \"analysis_only\", \"seed\": 42}, \"conclusion\": \"success\", \"checkpoint_path\": \"output/exp009_stratification_results.json\", \"log_path\": \"/tmp/exp009.log\", \"completed_at\": \"2026-05-14T14:59:46.463Z\", \"metrics\": {\"scierc_ner\": {\"n\": 551, \"sj_rho_overall\": 0.398, \"by_greedy_f1\": {\"hard_0_25_sj_rho\": 0.159, \"med_low_sj_rho\": 0.139, \"med_high_sj_rho\": 0.09, \"easy_sj_rho\": 0.23}, \"by_sent_len\": {\"Q1_sj_rho\": 0.461, \"Q2_sj_rho\": 0.401, \"Q3_sj_rho\": 0.296, \"Q4_sj_rho\": 0.382}, \"by_ent_count\": {\"0_sj_rho\": 0.689, \"1_2_sj_rho\": 0.415, \"3_5_sj_rho\": 0.353, \"6plus_sj_rho\": 0.547}}, \"scierc_re\": {\"n\": 551, \"by_greedy_f1\": {\"hard_0_25_sj_rho\": -0.043, \"easy_sj_rho\": 0.21}, \"by_sent_len\": {\"Q1_sj_rho\": 0.447, \"Q4_sj_rho\": 0.54}, \"by_rel_count\": {\"0_sj_rho\": 0.62, \"1_2_sj_rho\": 0.275, \"6plus_sj_rho\": 0.527}}, \"conll_ner\": {\"n\": 3453, \"by_sent_len\": {\"Q1_sj_rho\": 0.334, \"Q3_sj_rho\": 0.518}}, \"proxy_independence\": {\"scierc_ner_f1_vs_slen\": -0.021, \"scierc_ner_f1_vs_ecnt\": 0.007, \"scierc_re_f1_vs_slen\": -0.147}}, \"notes\": \"Registry metrics are PRE-gold-filter (n=551). Paper uses exp_009_v2_re_rerun (gold-filtered n=397): RE Q1_sj_rho=0.110, Q4_sj_rho=0.473. Registry values (Q1=0.447, Q4=0.540) are SUPERSEDED.\", \"hypothesis\": \"Capability stratification analysis: test if SJ signal effectiveness varies with instance difficulty (greedy F1 quartiles), sentence length, and entity/relation count. Identifies which instance subpopulations benefit most from structural consistency signals.\"}, \"exp_023_lora_rank8\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T10:29:59.501Z\", \"updated_at\": \"2026-05-17T02:55:50.540Z\", \"spec\": {\"hypothesis\": \"LoRA rank=8 ablation: does reducing rank from 32 to 8 significantly affect correlation-selection patterns?\", \"model_name\": \"Qwen/Qwen3-8B\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/llmfactory_train.json\", \"data_count\": 1861, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_002_v2\", \"method\": \"LoRA r=8 alpha=16, 5 epochs, batch=2 grad_accum=8 gradient_checkpointing=true\", \"gpu\": \"cuda:2\", \"pid\": 288382, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/logs/exp023_rank8_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-lora-rank8\", \"command\": \"CUDA_VISIBLE_DEVICES=2 llamafactory-cli train train_config_rank8.yaml\", \"trainable_params\": \"21.8M\", \"total_steps\": 585, \"estimated_runtime\": \"26min\"}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.1018, \"eval_loss\": 0.0776, \"train_runtime\": \"28m45s\", \"ner_full\": {\"n\": 529, \"greedy_f1\": 0.6397, \"oracle_f1\": 0.7998, \"oracle_headroom\": 0.1601, \"degeneracy_rate\": 0.072, \"SJ_rho\": 0.3649, \"FK_rho\": 0.2838, \"VC_rho\": 0.394, \"EM_rho\": 0.2562, \"LP_rho\": 0.2105, \"SJ_auroc\": 0.689, \"FK_auroc\": 0.6002, \"VC_auroc\": 0.6886, \"EM_auroc\": 0.7265, \"LP_auroc\": 0.6054, \"sel_SJ\": 0.6306, \"sel_FK\": 0.6265, \"sel_VC\": 0.5919, \"sel_EM\": 0.6073, \"sel_LP\": 0.635}, \"ner_cond\": {\"n\": 477, \"SJ_rho\": 0.3056, \"FK_rho\": 0.1452, \"VC_rho\": 0.3191, \"EM_rho\": 0.3558, \"LP_rho\": 0.169}, \"re_full\": {\"n\": 397, \"greedy_f1\": 0.3712, \"oracle_f1\": 0.609, \"oracle_headroom\": 0.2378, \"degeneracy_rate\": 0.217, \"SJ_rho\": 0.2244, \"FK_rho\": 0.3448, \"VC_rho\": 0.3617, \"EM_rho\": 0.068, \"LP_rho\": 0.2737, \"SJ_auroc\": 0.7092, \"FK_auroc\": 0.6469, \"VC_auroc\": 0.7533, \"EM_auroc\": 0.7306, \"LP_auroc\": 0.6325, \"sel_SJ\": 0.3584, \"sel_FK\": 0.3498, \"sel_VC\": 0.3715, \"sel_EM\": 0.3291, \"sel_LP\": 0.3606}, \"re_cond\": {\"n\": 242, \"SJ_rho\": 0.3601, \"FK_rho\": 0.2343, \"VC_rho\": 0.3703, \"EM_rho\": 0.4613, \"LP_rho\": 0.1809}}, \"completed_at\": \"2026-05-16T11:22:34.576Z\", \"hypothesis\": \"LoRA rank=8 ablation on SciERC: test if reduced model capacity (rank 8 vs 32) changes signal effectiveness ranking or correlation-selection gap pattern. Verifies findings are not rank-specific artifacts.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_022_seed789\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T10:08:27.375Z\", \"updated_at\": \"2026-05-17T02:55:49.870Z\", \"hypothesis\": \"3rd seed SciERC inference (seed=789) with ft_002_v2 (Qwen3-8B). N=8, T=1.0, joint NER+RE, logprobs collected. Complements seed42 (exp_012_rerun_1024) and seed123/456 for multi-seed analysis.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 789 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_022_seed789/\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Qwen3-8B (qwen3-8b-scierc-merged-v2)\", \"seed\": 789, \"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"log_path\": \"output/exp_022_seed789/run.log\", \"gpu\": \"cuda:0\", \"pid\": 286743, \"account\": \"root\", \"backend\": \"tmux\", \"tmux_session\": \"exp_022_seed789\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T14:25:17.461Z\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_025_n32\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T13:38:26.420Z\", \"updated_at\": \"2026-05-17T02:55:46.212Z\", \"spec\": {\"checkpoint_path\": \"checkpoints/qwen3-8b-scierc-merged-v2\", \"log_path\": \"output/exp_025_n32/run.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T14:25:39.849Z\", \"metrics\": {\"n_samples\": 32, \"degeneracy_pct\": 4, \"lp_range\": 0.0781, \"oracle_f1\": 0.8412, \"greedy_f1\": 0.6615, \"oracle_gap\": 0.1797, \"selection_f1_lp_delta\": 0.54, \"selection_f1_sj_delta\": 0.16, \"selection_f1_fk_delta\": 0.6, \"selection_f1_em_delta\": 0.68, \"selection_f1_vc_delta\": -5.21, \"best_signal\": \"EM\", \"best_delta\": 0.68, \"metric_space\": \"micro_f1_filtered_529inst\", \"note\": \"corrected via n_ablation_fixed.py, greedy from inst['greedy'] field\"}, \"hypothesis\": \"N=32 sample ablation on SciERC: test if increasing samples from 8→32 reduces degeneracy and improves selection F1, particularly for structural signals. Validates whether sample count is the bottleneck for signal effectiveness.\", \"parent\": \"exp_012_rerun_1024\"}, \"exp_021_fewnerd_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T16:33:44.079Z\", \"updated_at\": \"2026-05-17T02:55:45.560Z\", \"hypothesis\": \"Full Few-NERD LoRA fine-tune (rank=32, α=64, 3 epochs) on SUPERVISED coarse 8-type NER (131k train). 4-GPU DDP on autodl-5090. Post-training: N=8 inference on full test set, T=1.0, seed=42, collect logprobs for SCS metrics.\", \"spec\": {\"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\", \"gpu_count\": 4, \"training_mode\": \"DDP\", \"checkpoint_path\": \"output/exp_021_fewnerd_full/checkpoint-6177\", \"log_path\": \"output/exp_021_inference/\"}, \"conclusion\": \"success\", \"metrics\": {\"total_steps\": 6177, \"train_loss\": 0.048, \"eval_loss\": 0.0275, \"train_runtime\": \"3h57m\", \"epochs\": 3, \"final_checkpoint\": \"output/exp_021_fewnerd_full/checkpoint-6177\", \"adapter_path\": \"output/exp_021_fewnerd_full/adapter_model.safetensors\", \"inference_instances\": 37648, \"inference_filtered\": 32565, \"inference_n_samples\": 8, \"greedy_macro_f1\": 0.7478, \"oracle_macro_f1\": 0.8719, \"headroom\": 0.124, \"zero_f1_rate\": 0.119, \"degeneracy_rate\": 0.101, \"lp_within_range_mean\": 0.0879, \"lp_within_range_median\": 0.0662, \"lp_global_rho\": 0.4215, \"lp_cond_rho\": 0.4225, \"sj_global_rho\": 0.3002, \"sj_cond_rho\": 0.2937, \"fk_global_rho\": 0.3132, \"fk_cond_rho\": 0.3093, \"em_global_rho\": 0.2871, \"em_cond_rho\": 0.271, \"vc_global_rho\": 0.3858, \"vc_cond_rho\": 0.3234, \"lp_selection_delta_pp\": 1.36, \"vc_selection_delta_pp\": -1.79, \"sj_selection_delta_pp\": -2.14, \"fk_selection_delta_pp\": -2.26, \"em_selection_delta_pp\": -3.85, \"lp_bootstrap_ci_95_pp\": [1.18, 1.53], \"lp_sample_auroc\": 0.5782, \"vc_sample_auroc\": 0.5354, \"fk_sample_auroc\": 0.521, \"sj_sample_auroc\": 0.5197, \"em_sample_auroc\": 0.5137, \"scenario\": \"A_partial\", \"note\": \"Full analysis (gold-filtered n=32565). Prior simplified analysis used unfiltered data with different metrics.\"}, \"completed_at\": \"2026-05-16T22:04:16.683Z\", \"parent\": \"exp_020_fewnerd_smoke\"}, \"exp_015_metrics_expansion\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:47:36.569Z\", \"updated_at\": \"2026-05-17T02:55:35.391Z\", \"spec\": {\"hypothesis\": \"Comprehensive evaluation of all 5 confidence signals with extended metrics\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_012_logprob/samples_with_logprobs.jsonl\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"exp_012_logprob_baseline\", \"method\": \"CPU-only analysis: 6 metrics x 5 signals x 2 subtasks (NER+RE)\", \"command\": \"python code/analyze_exp015_metrics_expansion.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp015_metrics_expansion\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:22:32.661Z\", \"metrics\": {\"data_source\": \"exp_012_logprob/samples_with_logprobs.jsonl\", \"config\": \"N=8, T=1.0, seed=42, model=qwen3-8b-scierc-merged-v2\", \"ner\": {\"n_valid\": 529, \"n_cond\": 501, \"voting_rho_full\": 0.5018, \"voting_rho_cond\": 0.4497, \"voting_auroc\": 0.7279, \"voting_tau\": 0.3766, \"sj_rho_full\": 0.3565, \"sj_rho_cond\": 0.412, \"sj_auroc\": 0.6656, \"sj_tau\": 0.2658, \"em_rho_full\": 0.2566, \"em_rho_cond\": 0.3427, \"em_auroc\": 0.623, \"em_tau\": 0.1924, \"fk_rho_full\": 0.2651, \"fk_rho_cond\": 0.306, \"fk_auroc\": 0.6243, \"fk_tau\": 0.2027, \"logprob_rho_full\": 0.1396, \"logprob_rho_cond\": 0.1627, \"logprob_auroc\": 0.5585, \"logprob_tau\": 0.1006}, \"re\": {\"n_valid\": 397, \"n_cond\": 296, \"voting_rho_full\": 0.4217, \"voting_rho_cond\": 0.463, \"voting_auroc\": 0.7162, \"voting_tau\": 0.327, \"sj_rho_full\": 0.2112, \"sj_rho_cond\": 0.3683, \"sj_auroc\": 0.5816, \"sj_tau\": 0.1619, \"em_rho_full\": 0.1002, \"em_rho_cond\": 0.3607, \"em_auroc\": 0.5036, \"em_tau\": 0.0839, \"fk_rho_full\": 0.2528, \"fk_rho_cond\": 0.3168, \"fk_auroc\": 0.6308, \"fk_tau\": 0.1967, \"logprob_rho_full\": 0.2467, \"logprob_rho_cond\": 0.1457, \"logprob_auroc\": 0.6354, \"logprob_tau\": 0.1808}, \"diagnosis\": \"Unified 5-signal evaluation on single data source. Voting leads NER full (ρ=0.502), SJ retains strength in NER cond (ρ=0.412). All structural signals beat logprob on NER. RE: voting leads both full and cond.\"}, \"notes\": \"RE logprob_rho_cond=0.1457 uses WRONG conditional filter (any sample F1>0, n=331). Correct value: 0.0112 from exp_012_rerun_1024 (greedy_f1>0, n=238). This entry's RE cond values are DEPRECATED.\", \"hypothesis\": \"Unified 5-signal evaluation (SJ/FK/EM/VC/LP) on single canonical data source (exp_012 logprobs). Establishes complete signal ranking with ρ, AUROC, and τ metrics for both NER and RE under consistent conditions.\"}, \"exp_020_fewnerd_smoke\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T10:29:25.272Z\", \"updated_at\": \"2026-05-16T16:33:59.109Z\", \"spec\": {\"checkpoint_path\": \"checkpoints/ft_fewnerd_smoke\", \"log_path\": \"checkpoints/fewnerd_train.log\"}, \"hypothesis\": \"1-epoch LoRA (r16) fine-tune Qwen3-8B on Few-NERD INTRA coarse 8-type (131k train), then N=8 T=1.0 pilot inference on 200 test instances. Re-started training 2026-05-16 18:29 CST on cuda:1, PID 288683. ETA ~22:55 CST.\", \"conclusion\": \"success\", \"metrics\": {\"final_loss\": 0.031, \"total_steps\": 8236, \"training_time\": \"5h54m\", \"pilot_greedy_f1\": 0.8037, \"pilot_instances\": 200, \"merged_model_path\": \"checkpoints/qwen3-8b-fewnerd-merged\"}, \"completed_at\": \"2026-05-16T16:33:59.109Z\"}, \"exp_vc_lp_cascade_selection\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:44:02.658Z\", \"updated_at\": \"2026-05-16T06:31:26.755Z\", \"hypothesis\": \"VC-filtered LP selection cascade: test if combining VC (pre-filter) + LP (rank) improves selection F1 over single-signal selection. Addresses SF3 reviewer suggestion. Pure analysis on existing data.\", \"conclusion\": \"killed\", \"spec\": {\"command\": \"N/A - cancelled before execution\", \"server\": \"N/A\", \"data_path\": \"N/A\", \"data_count\": 0, \"model_name\": \"N/A\", \"seed\": 0, \"checkpoint_path\": \"N/A\", \"log_path\": \"N/A\"}, \"completed_at\": \"2026-05-16T06:31:26.755Z\"}, \"exp_tacred_re_benchmark\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:43:59.002Z\", \"updated_at\": \"2026-05-16T06:31:25.273Z\", \"hypothesis\": \"TACRED RE benchmark: replicate SciERC RE experiment flow on second RE dataset. Verify correlation-selection gap generalizes beyond SciERC. D104 highest priority — addresses R11 MF1 consensus weakness.\", \"conclusion\": \"killed\", \"spec\": {\"command\": \"N/A - cancelled before execution\", \"server\": \"N/A\", \"data_path\": \"N/A\", \"data_count\": 0, \"model_name\": \"N/A\", \"seed\": 0, \"checkpoint_path\": \"N/A\", \"log_path\": \"N/A\"}, \"completed_at\": \"2026-05-16T06:31:25.273Z\"}, \"exp_vc_quartile_analysis\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T04:48:35.263Z\", \"updated_at\": \"2026-05-16T05:00:36.736Z\", \"hypothesis\": \"VC quartile stratification: split instances by VC score into Q1-Q4, compute LP selection F1 per quartile. Test if LP selection ability recovers in high-VC instances. Addresses SF3.\", \"spec\": {\"command\": \"python vc_quartile_analysis.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_012_rerun_1024/samples.jsonl + output/exp_002_conll_n8_seed42/samples.jsonl\", \"data_count\": 3682, \"model_name\": \"analysis_only (Qwen3-8B data)\", \"seed\": 42}, \"conclusion\": \"success\", \"checkpoint_path\": \"artifacts/vc_quartile_analysis/results.json\", \"log_path\": \"artifacts/vc_quartile_analysis/report.md\", \"completed_at\": \"2026-05-16T05:00:30.439Z\", \"metrics\": {\"scierc_ner\": {\"Q1_lp_delta\": 0.016, \"Q2_lp_delta\": -0.006, \"Q3_lp_delta\": 0.02, \"Q4_lp_delta\": -0.004, \"Q4_mean_vc\": 0.921, \"Q1_headroom\": 0.169, \"Q4_headroom\": 0.048, \"overall_lp_delta\": 0.006, \"n\": 529}, \"scierc_re\": {\"Q1_lp_delta\": -0.036, \"Q2_lp_delta\": -0.021, \"Q3_lp_delta\": -0.022, \"Q4_lp_delta\": 0.04, \"Q4_mean_vc\": 0.894, \"Q1_headroom\": 0.211, \"Q4_headroom\": 0.145, \"overall_lp_delta\": -0.009, \"n\": 397}, \"conll_ner\": {\"Q1_lp_delta\": -0.037, \"Q2_lp_delta\": -0.005, \"Q3_lp_delta\": 0, \"Q4_lp_delta\": 0, \"overall_lp_delta\": -0.01, \"n\": 2756, \"note\": \"Q3/Q4 degenerate (VC=1.0, all samples identical)\"}, \"conclusion\": \"VC stratification does not solve LP compression for NER. RE Q4 is only exception (+0.040).\"}}, \"exp_llama3b_scierc_ablation\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:45:23.638Z\", \"updated_at\": \"2026-05-16T03:59:26.005Z\", \"hypothesis\": \"Cross-family scale ablation: LLaMA 3.2-3B on SciERC NER. Verify correlation-selection gap generalizes across model families AND scales. Compare with LLaMA 8B results.\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.2-3b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/review_round9_experiments/llama3b_scierc/\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"LLaMA-3.2-3B-Instruct (LoRA r=32 SciERC fine-tuned)\", \"seed\": 42, \"checkpoint_path\": \"checkpoints/llama3.2-3b-scierc-merged\", \"log_path\": \"output/review_round9_experiments/llama3b_scierc/inference.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T03:59:16.198Z\", \"metrics\": {\"ner_full\": {\"SJ_rho\": 0.3754, \"FK_rho\": 0.2676, \"LP_rho\": 0.2662, \"EM_rho\": 0.3341, \"VC_rho\": 0.4602, \"SJ_auroc\": 0.7383, \"FK_auroc\": 0.6714, \"LP_auroc\": 0.633, \"EM_auroc\": 0.7763, \"VC_auroc\": 0.7429, \"n\": 529}, \"ner_cond\": {\"SJ_rho\": 0.3445, \"FK_rho\": 0.2125, \"LP_rho\": 0.2099, \"EM_rho\": 0.3952, \"VC_rho\": 0.3815, \"SJ_auroc\": 0.7292, \"FK_auroc\": 0.66, \"LP_auroc\": 0.6156, \"EM_auroc\": 0.7822, \"VC_auroc\": 0.7222, \"n\": 476}, \"greedy_f1\": 0.6267, \"oracle_f1\": 0.763, \"oracle_headroom\": 0.1363, \"selection_f1_SJ\": 0.6328, \"selection_f1_VC\": 0.6113, \"selection_f1_FK\": 0.6295, \"selection_f1_EM\": 0.6174, \"selection_f1_LP\": 0.6279, \"n_gold_empty\": 22, \"structural_beats_surface\": true, \"rho_advantage_SJ_over_FK\": 0.1078}}, \"exp_freeform_conll_4seed\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-16T02:45:17.133Z\", \"updated_at\": \"2026-05-16T03:04:49.550Z\", \"hypothesis\": \"Free-form CoNLL NER 4-seed ablation: verify LP compression is cross-dataset intrinsic (not SciERC-specific). 4 seeds × N=8, T=1.0 on CoNLL, compare LP range distribution with constrained decoding.\", \"spec\": {\"command\": \"python run_freeform_conll.py --seed {42,123,456,789} --gpu {0,1,2,3} --n_samples 8 --temperature 1.0\", \"server\": \"autodl-4x5090\", \"data_path\": \"data/conll2003/test.jsonl\", \"data_count\": 3453, \"model_name\": \"checkpoints/qwen3-8b-conll2003-merged\", \"seed\": \"42,123,456,789\"}, \"checkpoint_path\": \"N/A (inference-only experiment)\", \"log_path\": \"output/review_round9_experiments/freeform_conll/\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-16T03:04:40.278Z\", \"metrics\": {\"greedy_f1\": \"0.9035±0.0004\", \"oracle_f1\": \"0.9460±0.0023\", \"lp_range_median\": \"0.0581±0.0072\", \"rho_sj\": \"0.4606±0.0188\", \"rho_fk\": \"0.4372±0.0209\", \"rho_em\": \"0.4714±0.0168\", \"rho_vc\": \"0.4606±0.0138\", \"rho_lp\": \"0.3262±0.0120\", \"sel_f1_sj\": \"0.8994±0.0014\", \"sel_f1_vc\": \"0.9006±0.0026\", \"sel_f1_lp\": \"0.8958±0.0009\", \"seeds\": [42, 123, 456, 789], \"n_samples\": 8, \"temperature\": 1, \"instances\": 2756, \"gold_empty_filtered\": 697}}, \"exp_qwen3_4b_conll_merge_inference_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:42:42.107Z\", \"updated_at\": \"2026-05-15T20:07:12.593Z\", \"hypothesis\": \"CoNLL 4B checkpoint-4200 (best from resume training) merge + SCS inference. Replaces v1 which used checkpoint-3800 merged model. Cross-scale evidence for correlation-selection gap.\", \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-4b-conll2003-merged-ckpt4200 --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_qwen3_4b_conll_merge_inference_v2\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"Qwen3-4B (LoRA merged, ckpt-4200)\", \"seed\": 42, \"checkpoint_source\": \"exp_qwen3_4b_conll_finetune_resume (checkpoint-4200)\"}, \"checkpoint_path\": \"N/A - duplicate\", \"log_path\": \"N/A - duplicate\", \"conclusion\": \"killed\", \"notes\": \"Superseded by exp_qwen3_4b_conll_scs_inference_v2. Output was empty (dead experiment), functionally duplicate.\", \"completed_at\": \"2026-05-15T20:03:47.431Z\"}, \"exp_qwen3_4b_scierc_merge_inference\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:42:43.332Z\", \"updated_at\": \"2026-05-15T20:04:15.433Z\", \"hypothesis\": \"SciERC 4B best checkpoint merge + SCS inference. Complete 2x2 scale matrix (4B SciERC cell). Cross-scale + cross-task evidence for correlation-selection gap.\", \"checkpoint_path\": \"N/A - superseded\", \"log_path\": \"N/A - superseded\", \"conclusion\": \"killed\", \"notes\": \"Superseded by exp_qwen3_4b_scierc_scs_inference. Never launched (stuck in PREPARING). Killed during registry cleanup.\", \"completed_at\": \"2026-05-15T20:04:15.433Z\"}, \"exp_qwen3_4b_scierc_finetune_v3\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:24:45.518Z\", \"updated_at\": \"2026-05-15T19:39:04.438Z\", \"spec\": {\"command\": \"llamafactory-cli train train_config_scierc_4b.yaml\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"226610\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen3_4b_scierc_finetune_v3.log\", \"submitted_at\": \"2026-05-15T19:24:55.461Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"wall_clock_seconds\": 849.0, \"gpu_hours\": 0.24}, \"conclusion\": \"failed\", \"notes\": \"OOM on cuda:2 — freeform inference (seed789, 8B) 占满 GPU 2。未实际训练。重启为 v4 on cuda:0。\", \"completed_at\": \"2026-05-15T19:39:04.438Z\"}, \"exp_qwen3_4b_conll_finetune_resume\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:38:19.388Z\", \"updated_at\": \"2026-05-15T19:38:43.468Z\", \"hypothesis\": \"CoNLL 4B NER LoRA fine-tune resume from checkpoint-3800. Cross-scale evidence for correlation-selection gap.\", \"spec\": {\"hypothesis\": \"CoNLL2003 NER LoRA fine-tune with Qwen3-4B, resume from checkpoint-3800 to complete 5 epochs\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && llamafactory-cli train train_config_conll2003_4b_resume.yaml\\\"\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"data_path\": \"data/conll2003/llmfactory_train.json\", \"data_count\": 14042, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"resume_from\": \"checkpoint-3800\", \"lora_rank\": 32, \"lora_alpha\": 64, \"num_train_epochs\": 5, \"learning_rate\": 0.0002, \"batch_size\": \"2 x 8 grad_accum\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-4b-conll2003-lora\", \"best_checkpoint\": \"checkpoint-4200\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-4b-conll2003-lora/trainer_state.json\"}, \"conclusion\": \"success\", \"metrics\": {\"train_loss\": 0.001136, \"eval_loss\": 0.0225, \"best_global_step\": 4200, \"best_metric_eval_loss\": 0.0225, \"total_steps\": 4390, \"epochs\": 5, \"train_runtime_sec\": 1185.8, \"train_samples_per_second\": 59.2, \"resumed_from_step\": 3800}, \"completed_at\": \"2026-05-15T19:38:43.468Z\"}, \"exp_qwen3_4b_scierc_finetune_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:03:49.204Z\", \"updated_at\": \"2026-05-15T19:24:32.466Z\", \"spec\": {\"command\": \"llamafactory-cli train train_config_scierc_4b.yaml\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:3\", \"pid\": \"219830\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen3_4b_scierc_finetune_v2.log\", \"submitted_at\": \"2026-05-15T19:05:31.524Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 1861, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"plan_id\": \"D096\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-4b-scierc-lora/\", \"wall_clock_seconds\": 1122.6, \"gpu_hours\": 0.31}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T19:24:14.124Z\", \"notes\": \"PID 219830 已死，仅完成 step 10，无 checkpoint。需彻底重启。\"}, \"exp_qwen3_4b_conll_finetune\": {\"status\": \"DONE\", \"retry_count\": 1, \"created_at\": \"2026-05-15T17:18:35.501Z\", \"updated_at\": \"2026-05-15T19:10:24.822Z\", \"hypothesis\": \"Scale ablation: Qwen3-4B CoNLL NER LoRA fine-tune to provide cross-scale evidence (vs 8B). Verify correlation-selection gap, SJ>FK ordering, and LP compression generalize across model scale.\", \"reproduce\": {\"finished_at\": \"2026-05-15T18:45:42.215Z\"}, \"failure_reason\": \"\", \"completed_at\": \"2026-05-15T18:45:43.672Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T18:45:49.686191+00:00\"}], \"previous_failure\": {\"conclusion\": \"failed\"}}, \"spec\": {\"command\": \"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 llamafactory-cli train train_config_conll2003_4b.yaml\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"data_path\": \"data/conll2003\", \"data_count\": 14041, \"model_name\": \"Qwen3-4B\", \"seed\": 42, \"plan_id\": \"D096\", \"log_path\": \"checkpoints/qwen3-4b-conll2003-lora/trainer_log.jsonl\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-4b-conll2003-lora\", \"lora_config\": {\"trainable_params\": \"66M / 4.09B (1.62%)\", \"target_modules\": \"q_proj, k_proj, v_proj, o_proj, gate_proj, up_proj, down_proj\", \"epochs\": 5, \"batch_size\": 16, \"total_steps\": 4390, \"enable_thinking\": false}}, \"conclusion\": \"success\", \"notes\": \"Training stopped at step 3920/4390 (89.3%, epoch 4.46/5). No error log or tmux session found. checkpoint-3800 is valid (adapter_model.safetensors 264MB, eval_loss=0.023). Proceeding with checkpoint-3800 for merge+inference.\", \"metrics\": {\"final_loss\": 0.0086, \"total_steps_completed\": 3920, \"total_steps_target\": 4390, \"epochs_completed\": 4.46, \"epochs_target\": 5, \"best_checkpoint\": \"checkpoint-3800\", \"note\": \"Training stopped at 89.3% completion (no error log found). Using checkpoint-3800 (loss ~0.01) for merge.\"}}, \"exp_freeform_seed789_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T19:02:03.813Z\", \"updated_at\": \"2026-05-15T19:06:44.537Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && python run_freeform_inference.py --seed 789 --num_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir results/exp_freeform_ablation_seed789\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"218882\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_freeform_seed789_v2.log\", \"submitted_at\": \"2026-05-15T19:02:03.527Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"hypothesis\": \"Multi-seed free-form ablation (seed=789): third seed for 3-seed mean±σ statistical significance. Verify RE LP flip and NER gap stability.\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 789, \"wall_clock_seconds\": 274.9, \"gpu_hours\": 0.08}, \"reproduce\": {\"finished_at\": \"2026-05-15T19:06:37.887Z\"}, \"failure_reason\": \"EXIT_CODE=143 (SIGTERM — graceful kill)\", \"conclusion\": \"failed\", \"completed_at\": \"2026-05-15T19:06:38.388Z\", \"extra\": {\"hook_events\": [{\"event\": \"on_failed\", \"action\": \"agent\", \"ts\": \"2026-05-15T19:06:53.109123+00:00\"}]}}, \"exp_qwen3_4b_scierc_finetune\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T18:58:58.948Z\", \"updated_at\": \"2026-05-15T19:03:05.505Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 llamafactory-cli train train_config_scierc_4b.yaml\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"218258\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_qwen3_4b_scierc_finetune.log\", \"submitted_at\": \"2026-05-15T19:00:10.234Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 175.3, \"gpu_hours\": 0.05}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T19:03:05.505Z\"}, \"exp_lp_t07_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:34:12.094Z\", \"updated_at\": \"2026-05-15T16:30:35.531Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 8 --temperature 0.7 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_lp_t07_scierc\\\"\", \"server\": \"autodl-5090\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"Qwen3-8B (LoRA fine-tuned on SciERC, ft_002_v2 merged)\", \"seed\": 42, \"gpu\": \"cuda:1\", \"hyperparams\": {\"n_samples\": 8, \"temperature\": 0.7, \"max_tokens\": 1024}}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T16:28:29.563Z\"}, \"exp_lp_scierc_t07\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:34:06.918Z\", \"updated_at\": \"2026-05-15T16:03:13.881Z\", \"hypothesis\": \"LP T=0.7 推理：验证低温下 LP score compression 是否依然存在，强化 \\\"LP compression is model/task intrinsic\\\" claim。对比 T=1.0 的 LP range 分布。\", \"spec\": {\"command\": \"python run_sc_ie.py --dataset scierc --subtask ner --model qwen --n_samples 8 --temperature 0.7 --use_logprob --output_dir /root/autodl-tmp/struct_self_consist_ie/output/exp_lp_scierc_t07\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:1\"], \"pid\": \"196993\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_lp_scierc_t07/\", \"submitted_at\": \"2026-05-15T15:35:31.692Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"SciERC\", \"data_count\": 500, \"model_name\": \"Qwen3-8B\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_lp_scierc_t07/report.json\", \"wall_clock_seconds\": 1206.2, \"gpu_hours\": 0.34}, \"conclusion\": \"success\", \"metrics\": {\"ner_greedy_f1\": 0.662, \"ner_oracle_f1\": 0.764, \"ner_headroom_pp\": 10.2, \"ner_rho_sj_full\": 0.365, \"ner_rho_sj_cond\": 0.363, \"ner_rho_fk_full\": 0.289, \"ner_rho_fk_cond\": 0.255, \"lp_rho_full\": 0.249, \"lp_rho_cond\": 0.185, \"ner_rho_advantage\": 0.076, \"zero_f1_pct\": 11, \"full_n\": 529, \"cond_n\": 477, \"verdict\": \"success_supports_LP_compression_claim\"}, \"completed_at\": \"2026-05-15T15:55:37.889Z\"}, \"exp_re_scierc_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:40:40.607Z\", \"updated_at\": \"2026-05-15T15:55:41.890Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 456 --num_test 9999 --collect_logprobs --output_dir output/exp_re_scierc_seed456\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:3\"], \"pid\": \"199161\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_re_scierc_seed456/\", \"submitted_at\": \"2026-05-15T15:40:59.585Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"SciERC\", \"data_count\": 500, \"model_name\": \"Qwen3-8B (SciERC merged)\", \"seed\": 456, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_re_scierc_seed456/report.json\", \"wall_clock_seconds\": 882.3, \"gpu_hours\": 0.25}, \"hypothesis\": \"SciERC RE 多种子验证 (seed456): 解决 R4-W1/R7-C1 single-seed RE 弱点。与 seed42 (exp_012_rerun_1024) 对齐，joint subtask N=8 T=1.0。目标: 3-seed RE selection F1 mean±σ。\", \"conclusion\": \"negative\", \"metrics\": {\"ner_greedy_f1\": 0.664, \"ner_oracle_f1\": 0.775, \"ner_headroom_pp\": 11.1, \"ner_rho_sj_cond\": 0.283, \"ner_rho_fk_cond\": 0.145, \"re_greedy_f1\": 0.417, \"re_oracle_f1\": 0.581, \"re_headroom_pp\": 16.3, \"re_rho_sj_cond\": 0.315, \"re_rho_fk_cond\": 0.123, \"re_zero_f1_pct\": 45.3, \"verdict\": \"FAIL_re_rho_sj_below_040\"}, \"completed_at\": \"2026-05-15T15:55:41.890Z\"}, \"exp_re_scierc_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:40:38.271Z\", \"updated_at\": \"2026-05-15T15:55:40.000Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --seed 123 --num_test 9999 --collect_logprobs --output_dir output/exp_re_scierc_seed123\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:2\"], \"pid\": \"199021\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_re_scierc_seed123/\", \"submitted_at\": \"2026-05-15T15:40:58.073Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"data_path\": \"SciERC\", \"data_count\": 500, \"model_name\": \"Qwen3-8B (SciERC merged)\", \"seed\": 123, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp_re_scierc_seed123/report.json\", \"wall_clock_seconds\": 881.9, \"gpu_hours\": 0.24}, \"hypothesis\": \"SciERC RE 多种子验证 (seed123): 解决 R4-W1/R7-C1 single-seed RE 弱点。与 seed42 (exp_012_rerun_1024) 对齐，joint subtask N=8 T=1.0。目标: 3-seed RE selection F1 mean±σ。\", \"conclusion\": \"negative\", \"metrics\": {\"ner_greedy_f1\": 0.663, \"ner_oracle_f1\": 0.786, \"ner_headroom_pp\": 12.3, \"ner_rho_sj_cond\": 0.404, \"ner_rho_fk_cond\": 0.182, \"re_greedy_f1\": 0.42, \"re_oracle_f1\": 0.593, \"re_headroom_pp\": 17.3, \"re_rho_sj_cond\": 0.277, \"re_rho_fk_cond\": 0.063, \"re_zero_f1_pct\": 43.6, \"verdict\": \"FAIL_re_rho_sj_below_040\"}, \"completed_at\": \"2026-05-15T15:55:40.000Z\"}, \"exp_017_llama_conll_n8_t07\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T15:29:34.595Z\", \"updated_at\": \"2026-05-15T15:46:22.722Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 0.7 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n8_t07\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"195927\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_017_llama_conll_n8_t07.log\", \"submitted_at\": \"2026-05-15T15:31:17.989Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 881.3, \"gpu_hours\": 0.24}, \"hypothesis\": \"LLaMA CoNLL N=8 T=0.7 防御性实验：填补\\\"LLaMA 仅在 SciERC 上测过\\\"的弱点，验证 cross-model consistency（vs Qwen CoNLL）。T=0.7 低温下 confidence signals 的 correlation-selection gap 是否依然存在。\", \"parent\": \"exp_017_llama_conll\", \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-15T15:31:15.772Z\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 0.7 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_017_llama_conll_n8_t07\\\"\", \"finished_at\": \"2026-05-15T15:40:02.605Z\", \"training_hours\": 0.15}, \"pid\": \"195927\", \"log_path\": \"/root/runs/struct_self_consist_ie/exp_017_llama_conll_n8_t07.log\", \"extra\": {\"hook_events\": [{\"event\": \"on_complete\", \"action\": \"agent\", \"ts\": \"2026-05-15T15:40:08.277684+00:00\"}]}, \"metrics\": {\"n_valid\": 2756, \"greedy_f1\": 0.9242, \"oracle_f1\": 0.9391, \"lp_range_median\": 1.1e-05, \"lp_tied_fraction_005\": 0.9579, \"signals\": {\"SJ\": {\"rho\": 0.3934, \"auroc\": 0.6506}, \"FK\": {\"rho\": 0.3879, \"auroc\": 0.6488}, \"VC\": {\"rho\": 0.375, \"auroc\": 0.6551}, \"EM\": {\"rho\": 0.3888, \"auroc\": 0.6494}, \"LP\": {\"rho\": 0.2951, \"auroc\": 0.7509}}, \"selection_f1\": {\"SJ\": 0.9247, \"FK\": 0.9254, \"VC\": 0.9264, \"EM\": 0.9255, \"LP\": 0.9248}}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A (inference-only)\", \"completed_at\": \"2026-05-15T15:45:59.311Z\"}, \"exp008_re_n16\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:09:50.987Z\", \"updated_at\": \"2026-05-15T12:41:39.774Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && mkdir -p output/exp008_re_n16 && CUDA_VISIBLE_DEVICES=2 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp008_re_n16 --collect_logprobs 2>&1 | tee output/exp008_re_n16/run.log\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:2\"], \"pid\": \"53600\", \"log_path\": \"~/runs/struct_self_consist_ie/exp008_re_n16.log\", \"submitted_at\": \"2026-05-14T12:15:14.917Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_008_re_n16_v2 (full 551-instance run on autodl-5090)\", \"wall_clock_seconds\": 87984.9, \"gpu_hours\": 24.44}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T12:41:39.774Z\"}, \"exp001_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:09:48.078Z\", \"updated_at\": \"2026-05-15T12:41:32.192Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && mkdir -p output/exp001_n16_seed456 && CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --output_dir output/exp001_n16_seed456 --collect_logprobs 2>&1 | tee output/exp001_n16_seed456/run.log\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:1\"], \"pid\": \"50302\", \"log_path\": \"~/runs/struct_self_consist_ie/exp001_seed456.log\", \"submitted_at\": \"2026-05-14T12:12:41.206Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed456_v2_ner (NER-only on autodl-5090)\", \"wall_clock_seconds\": 88131.0, \"gpu_hours\": 24.48}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\", \"completed_at\": \"2026-05-15T12:41:32.192Z\"}, \"exp001_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:09:45.739Z\", \"updated_at\": \"2026-05-15T12:41:31.168Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && mkdir -p output/exp001_n16_seed123 && CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --output_dir output/exp001_n16_seed123 --collect_logprobs 2>&1 | tee output/exp001_n16_seed123/run.log\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:0\"], \"pid\": \"48530\", \"log_path\": \"~/runs/struct_self_consist_ie/exp001_seed123.log\", \"submitted_at\": \"2026-05-14T12:09:45.674Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed123_v2 (NER-only, 551 instances on autodl-5090)\", \"wall_clock_seconds\": 88305.5, \"gpu_hours\": 24.53}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\", \"completed_at\": \"2026-05-15T12:41:31.168Z\"}, \"exp_001_n16_seed456_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:44:31.348Z\", \"updated_at\": \"2026-05-15T12:41:30.065Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --num_test 9999 --output_dir output/exp001_n16_seed456/\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:1\"], \"pid\": \"62170\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_001_n16_seed456_full.log\", \"submitted_at\": \"2026-05-14T12:44:31.087Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed456_v2_ner (NER-only on autodl-5090)\", \"wall_clock_seconds\": 86219.0, \"gpu_hours\": 23.95}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\", \"completed_at\": \"2026-05-15T12:41:30.065Z\"}, \"exp_001_n16_seed123_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:43:47.915Z\", \"updated_at\": \"2026-05-15T12:41:29.068Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --num_test 9999 --output_dir output/exp001_n16_seed123_full/\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:0\"], \"pid\": \"61812\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_001_n16_seed123_full.log\", \"submitted_at\": \"2026-05-14T12:44:06.059Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_001_seed123_v2 (NER-only on autodl-5090)\", \"wall_clock_seconds\": 86243.0, \"gpu_hours\": 23.96}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by v2\", \"completed_at\": \"2026-05-15T12:41:29.068Z\"}, \"exp_007_ner_llama\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:21.510Z\", \"updated_at\": \"2026-05-15T12:41:27.410Z\", \"spec\": {\"description\": \"Fine-tune LLaMA-3.1-8B on SciERC + NER pilot (N=8, T=0.7). Model-agnostic validation.\", \"hypothesis\": \"SJ advantage is model-agnostic, not Qwen3-specific\", \"plan_id\": \"exp-007\", \"claim\": 1, \"model_name\": \"llama-3.1-8b-instruct (new fine-tune)\", \"dataset\": \"SciERC\", \"priority\": \"P0\", \"failure_reason\": \"Superseded by exp_007_ner_multi_model + exp_007_llama_inference (completed on autodl-5090)\"}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by exp_007_llama_inference (DONE)\", \"notes\": \"Completed as exp_007_llama_n16 on autodl-5090. Registry status corrected.\", \"completed_at\": \"2026-05-15T12:41:27.410Z\"}, \"exp_002_merge_conll2003\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:25:56.211Z\", \"updated_at\": \"2026-05-15T12:41:26.419Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 llamafactory-cli export export_config_conll2003.yaml > /tmp/merge_conll2003.log 2>&1 && echo 'MERGE_DONE' >> /tmp/merge_conll2003.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"57524\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_002_merge_conll2003.log\", \"submitted_at\": \"2026-05-14T12:25:56.139Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"failure_reason\": \"Superseded by exp_002_ner_conll2003 (completed on autodl-5090)\", \"wall_clock_seconds\": 87330.3, \"gpu_hours\": 24.26}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by exp_002_ner_conll2003 (DONE)\", \"notes\": \"Completed as exp_002_conll_n16 on autodl-5090. Registry status corrected.\", \"completed_at\": \"2026-05-15T12:41:26.419Z\"}, \"exp_019_supervised_verifier\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T10:08:54.395Z\", \"updated_at\": \"2026-05-15T12:40:53.995Z\", \"spec\": {\"hypothesis\": \"Supervised verifier (DeBERTa-v3-large) can close the correlation-selection gap, proving the gap is closable with supervision\", \"plan_id\": \"exp-019\", \"model_name\": \"microsoft/deberta-v3-large\", \"data_path\": \"output/exp_012_rerun_1024/samples.jsonl\", \"data_count\": 551, \"seed\": 42}, \"conclusion\": \"killed\", \"notes\": \"Cancelled by Director: DDL risk too high (3-4 days for implementation+training+eval+paper), scope creep for analytical paper, free-form ablation already provides sufficient mechanistic evidence\", \"completed_at\": \"2026-05-15T12:40:53.995Z\"}, \"exp_018_llama_scierc_seed456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-15T06:07:15.150Z\", \"updated_at\": \"2026-05-15T06:22:40.868Z\", \"spec\": {\"hypothesis\": \"Multi-seed robustness: LLaMA SciERC N=8 seed=456, max_tokens=1024. Fresh inference (D066 decision: replace exp_007 re-analysis with independent replication).\", \"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --seed 456 --max_tokens 1024 --num_test 9999 --collect_logprobs --output_dir output/exp_018_llama_scierc_seed456_r1024\\\"\", \"server\": \"autodl-5090\", \"seed\": 456, \"model_name\": \"LLaMA-3.1-8B-SciERC-merged\", \"model_path\": \"checkpoints/llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"subtask\": \"joint\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"N\": 8, \"T\": 1, \"max_tokens\": 1024, \"is_new_inference\": true, \"checkpoint_path\": \"output/exp_018_llama_scierc_seed456_r1024/\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_018_llama_scierc_seed456_r1024.log\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T06:08:05.756Z\", \"notes\": \"SUPERSEDED by exp_018_llama_scierc_seed456_r1024 (D066). Original data was re-analysis of exp_007_llama_seed456, not independent inference. Fresh rerun with explicit max_tokens=1024 now canonical.\"}, \"exp_002_conll_n16_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:57.682Z\", \"updated_at\": \"2026-05-15T01:20:53.108Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen CoNLL N=16.\", \"parent\": \"exp_002_conll_n16\", \"model_name\": \"qwen3-8b-conll2003-merged\", \"dataset\": \"CoNLL-2003\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_002_conll_n16_r1024\", \"data_path\": \"data/conll2003\", \"data_count\": 3453}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:53.108Z\"}, \"exp_007_llama_n16_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:59.685Z\", \"updated_at\": \"2026-05-15T01:20:52.194Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on LLaMA SciERC N=16.\", \"parent\": \"exp_007_llama_n16\", \"model_name\": \"llama3.1-8b-scierc-merged\", \"dataset\": \"SciERC\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=3 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-scierc-merged --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_007_llama_n16_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 9999}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:52.194Z\"}, \"exp_001_seed123_v2_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:54.442Z\", \"updated_at\": \"2026-05-15T01:20:49.812Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen SciERC N=16 seed123.\", \"parent\": \"exp_001_seed123_v2\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"seed\": 123, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_001_seed123_v2_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 529}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:49.812Z\"}, \"exp_001_seed456_v2_ner_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:55.975Z\", \"updated_at\": \"2026-05-15T01:20:48.914Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen SciERC N=16 seed456.\", \"parent\": \"exp_001_seed456_v2_ner\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"seed\": 456, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=1 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_001_seed456_v2_ner_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 9999}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-15T01:20:48.914Z\"}, \"exp_001_seed42_v2_r1024\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T22:16:52.571Z\", \"updated_at\": \"2026-05-14T22:28:53.686Z\", \"spec\": {\"hypothesis\": \"D054 rerun: max_tokens=1024. Verify truncation impact on Qwen SciERC N=16 seed42.\", \"parent\": \"exp_001_seed42_v2\", \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"dataset\": \"SciERC\", \"seed\": 42, \"server\": \"autodl-5090\", \"command\": \"CUDA_VISIBLE_DEVICES=0 PYTHONPATH=code python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask ner --n_samples 16 --temperature 1.0 --seed 42 --num_test 9999 --max_tokens 1024 --collect_logprobs --output_dir output/exp_001_seed42_v2_r1024\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 9999}, \"conclusion\": \"killed\", \"metrics\": {\"greedy_f1\": 0.6647, \"oracle_f1\": 0.8106, \"softjaccard_rho_full\": 0.3928, \"fleiss_rho_full\": 0.2489, \"logprob_rho_full\": 0.2136, \"softjaccard_rho_cond\": 0.3455, \"fleiss_rho_cond\": 0.163, \"logprob_rho_cond\": 0.1624, \"verdict\": \"MARGINAL\"}, \"checkpoint_path\": \"output/exp_001_seed42_v2_r1024\", \"log_path\": \"output/exp_001_seed42_v2_r1024/run.log\", \"completed_at\": \"2026-05-14T22:27:43.836Z\"}, \"exp_017_llama_conll_n16_s456\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:23:21.987Z\", \"updated_at\": \"2026-05-14T20:24:45.875Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=456: structural>surface ranking preserved across seeds, complementing Qwen SciERC 3-seed protocol\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 456 --collect_logprobs --num_test 9999 --output_dir output/exp_017_llama_conll_n16_s456\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"llama3.1-8b-conll2003-merged\", \"seed\": 456}, \"metrics\": {\"greedy_f1\": 0.9243, \"oracle_f1\": 0.9488, \"oracle_headroom\": 0.0245, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"structural_beats_surface\": true, \"full\": {\"SJ_rho\": 0.4552, \"SJ_AUROC\": 0.7288, \"SJ_ECE\": 0.1134, \"FK_rho\": 0.4478, \"FK_AUROC\": 0.7248, \"FK_ECE\": 0.109, \"logprob_rho\": 0.3078, \"logprob_AUROC\": 0.7612, \"logprob_ECE\": 0.1289, \"EM_rho\": 0.452, \"EM_AUROC\": 0.7275, \"EM_ECE\": 0.1082, \"voting_conf_rho\": 0.4571, \"voting_conf_AUROC\": 0.7348, \"voting_conf_ECE\": 0.0863}, \"conditional\": {\"SJ_rho\": 0.4505, \"SJ_AUROC\": 0.7449, \"SJ_ECE\": 0.0826, \"FK_rho\": 0.4422, \"FK_AUROC\": 0.7401, \"FK_ECE\": 0.0835, \"logprob_rho\": 0.3242, \"logprob_AUROC\": 0.8067, \"logprob_ECE\": 0.0921, \"EM_rho\": 0.451, \"EM_AUROC\": 0.745, \"EM_ECE\": 0.0756, \"voting_conf_rho\": 0.3962, \"voting_conf_AUROC\": 0.7202, \"voting_conf_ECE\": 0.0746}, \"best_of_n\": {\"greedy\": 0.9243, \"random_avg\": 0.9215, \"sj_best\": 0.9243, \"logprob_best\": 0.9243, \"voting_conf_best\": 0.9243, \"oracle\": 0.9488}, \"n8_vs_n16_delta\": {\"full_SJ_rho_delta\": 0.0238, \"full_FK_rho_delta\": 0.0201, \"full_logprob_rho_delta\": 0.0006, \"full_EM_rho_delta\": 0.0214, \"full_voting_conf_rho_delta\": 0.0315, \"cond_SJ_rho_delta\": 0.0149, \"cond_FK_rho_delta\": 0.0112, \"cond_logprob_rho_delta\": -0.004, \"cond_EM_rho_delta\": 0.0107, \"cond_voting_conf_rho_delta\": 0.0219}}, \"checkpoint_path\": \"output/exp_017_llama_conll_n16_s456/samples.jsonl\", \"log_path\": \"output/exp_017_llama_conll_n16_s456/all_signals_report.json\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T20:24:45.875Z\"}, \"exp_017_llama_conll_n16_s123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T19:23:21.084Z\", \"updated_at\": \"2026-05-14T19:43:06.607Z\", \"hypothesis\": \"LLaMA CoNLL N=16 seed=123: structural>surface ranking preserved across seeds, complementing Qwen SciERC 3-seed protocol\", \"spec\": {\"hypothesis\": \"LLaMA CoNLL-2003 NER N=16 seed=123: cross-seed robustness check against N=8 seed=42 baseline (exp_017_llama_conll_infer)\", \"command\": \"CUDA_VISIBLE_DEVICES=1 python code/run_mvp_pilot.py --model_path checkpoints/llama3.1-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs --num_test 9999 --output_dir output/exp_017_llama_conll_n16_s123\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/conll2003\", \"data_count\": 3453, \"model_name\": \"llama3.1-8b-conll2003-merged\", \"seed\": 123, \"checkpoint_source\": \"checkpoints/llama3.1-8b-conll2003-merged\", \"eval_data\": \"data/conll2003\", \"checkpoint_path\": \"output/exp_017_llama_conll_n16_s123/samples.jsonl\", \"log_path\": \"output/exp_017_llama_conll_n16_s123.log\"}, \"metrics\": {\"greedy_f1\": 0.9266, \"oracle_f1\": 0.9497, \"oracle_headroom\": 0.0231, \"n_instances\": 3453, \"n_valid\": 2756, \"n_conditional\": 2642, \"structural_beats_surface\": true, \"full\": {\"SJ_rho\": 0.4698, \"SJ_AUROC\": 0.7402, \"SJ_ECE\": 0.1135, \"FK_rho\": 0.4594, \"FK_AUROC\": 0.7351, \"FK_ECE\": 0.1114, \"logprob_rho\": 0.3161, \"logprob_AUROC\": 0.768, \"logprob_ECE\": 0.129, \"EM_rho\": 0.4676, \"EM_AUROC\": 0.7399, \"EM_ECE\": 0.1082, \"voting_conf_rho\": 0.4612, \"voting_conf_AUROC\": 0.7429, \"voting_conf_ECE\": 0.0832}, \"conditional\": {\"SJ_rho\": 0.4712, \"SJ_AUROC\": 0.7609, \"SJ_ECE\": 0.0828, \"FK_rho\": 0.4595, \"FK_AUROC\": 0.7547, \"FK_ECE\": 0.0858, \"logprob_rho\": 0.3314, \"logprob_AUROC\": 0.8134, \"logprob_ECE\": 0.0922, \"EM_rho\": 0.4732, \"EM_AUROC\": 0.7626, \"EM_ECE\": 0.075, \"voting_conf_rho\": 0.4086, \"voting_conf_AUROC\": 0.7338, \"voting_conf_ECE\": 0.0706}, \"best_of_n\": {\"greedy\": 0.9242, \"random_avg\": 0.9216, \"sj_best\": 0.9247, \"logprob_best\": 0.9253, \"voting_conf_best\": 0.9255, \"oracle\": 0.9486}, \"n8_vs_n16_delta\": {\"full_SJ_rho_delta\": 0.0384, \"full_FK_rho_delta\": 0.0317, \"full_logprob_rho_delta\": 0.0089, \"full_SJ_AUROC_delta\": 0.0363, \"full_FK_AUROC_delta\": 0.0325, \"full_logprob_AUROC_delta\": 0.007, \"cond_SJ_rho_delta\": 0.0356, \"cond_FK_rho_delta\": 0.0285, \"cond_logprob_rho_delta\": 0.0032}}, \"log_path\": \"output/exp_017_llama_conll_n16_s123.log\", \"checkpoint_path\": \"output/exp_017_llama_conll_n16_s123/samples.jsonl\", \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T19:43:06.607Z\"}, \"exp_008_re_n16_full\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:45:10.852Z\", \"updated_at\": \"2026-05-14T17:51:43.957Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=2 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask re --n_samples 16 --temperature 1.0 --seed 42 --collect_logprobs --num_test 9999 --output_dir output/exp008_re_n16/\\\"\", \"server\": \"gpu-5090-4x-2\", \"gpu\": [\"cuda:2\"], \"pid\": \"62585\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_008_re_n16_full.log\", \"submitted_at\": \"2026-05-14T12:45:10.764Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\", \"wall_clock_seconds\": 18393.2, \"gpu_hours\": 5.11}, \"conclusion\": \"killed\", \"failure_reason\": \"superseded by exp_008_re_n16_t10_full (full 551-instance RE-only run on autodl-5090)\", \"completed_at\": \"2026-05-14T17:51:43.957Z\"}, \"exp_001_n16_seed123\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:10:29.393Z\", \"updated_at\": \"2026-05-14T12:42:58.393Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 123 --collect_logprobs\", \"server\": \"gpu-5090-4x-2\", \"data_path\": \"data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged-v2\", \"seed\": 123, \"num_instances\": 200, \"partial\": true, \"note\": \"Only 200/551 instances due to --num_test default bug. Needs full rerun.\"}, \"metrics\": {\"ner\": {\"greedy_f1\": 0.655, \"oracle_f1\": 0.8028, \"headroom\": 0.1478, \"rho_sj_full\": 0.4076, \"rho_fk_full\": 0.2799, \"rho_logprob_full\": 0.3189, \"rho_sj_cond\": 0.4271, \"rho_fk_cond\": 0.2743, \"rho_logprob_cond\": 0.2835, \"sj_beats_fk\": true, \"rho_advantage\": 0.1277}, \"re\": {\"greedy_f1\": 0.4243, \"oracle_f1\": 0.6771, \"headroom\": 0.2528, \"rho_sj_full\": 0.2943, \"rho_fk_full\": 0.2657, \"rho_logprob_full\": 0.3005, \"rho_sj_cond\": 0.4003, \"rho_fk_cond\": 0.313, \"rho_logprob_cond\": 0.2317, \"sj_beats_fk\": true, \"rho_advantage\": 0.0286}, \"verdict\": \"FAIL\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp001_n16_seed123/\", \"completed_at\": \"2026-05-14T12:28:38.104Z\"}, \"exp_016_signal_ensemble\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:15:23.771Z\", \"updated_at\": \"2026-05-14T12:42:55.931Z\", \"spec\": {\"command\": \"python code/analyze_exp016_ensemble.py\", \"server\": \"autodl-5090\", \"data_path\": \"output/exp_012_logprob/samples_with_logprobs.jsonl\", \"data_count\": 551, \"model_name\": \"N/A (CPU-only analysis)\", \"seed\": 42, \"checkpoint_source\": \"N/A\", \"eval_data\": \"pilot_004\", \"checkpoint_path\": \"N/A\", \"log_path\": \"output/exp016_signal_ensemble/\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:15:53.341Z\", \"metrics\": {\"sj_logprob_pearson_ner\": 0.57, \"sj_logprob_pearson_re\": 0.42, \"best_linear_ner\": {\"combo\": \"SJ+voting_conf\", \"alpha\": 0.3, \"rho\": 0.489}, \"best_linear_re\": {\"combo\": \"voting_conf+logprob\", \"alpha\": 0.6, \"rho\": 0.429}, \"ensemble_ner_auroc\": 0.735, \"ensemble_re_auroc\": 0.719, \"best_single_ner_auroc\": 0.7, \"best_single_re_auroc\": 0.721, \"ensemble_ner_delta\": 0.035, \"selection_f1_ner\": {\"greedy\": 0.609, \"logprob\": 0.609, \"sj\": 0.604, \"ensemble\": 0.604, \"voting\": 0.596, \"random\": 0.58, \"oracle\": 0.769}, \"selection_f1_re\": {\"logprob\": 0.397, \"greedy\": 0.374, \"sj\": 0.368, \"ensemble\": 0.367, \"voting\": 0.338, \"random\": 0.338, \"oracle\": 0.561}, \"diagnosis\": \"SJ+voting_conf linear combo boosts NER ρ to 0.489 (+23%). RE: logprob-best is ONLY method beating greedy (0.397 vs 0.374). Ensemble AUROC +0.035 on NER. Oracle gap still huge.\"}}, \"exp_001_ner_n16_scierc\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:10.898Z\", \"updated_at\": \"2026-05-14T12:42:49.592Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 16 --temperature 1.0 --seed 42 --output_dir output/exp001_n16_seed42 --num_test 9999 --collect_logprobs 2>&1 | tee output/exp001_n16_seed42_run.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"54357\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_001_ner_n16_scierc.log\", \"submitted_at\": \"2026-05-14T12:15:46.646Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:0\", \"started_at\": \"2026-05-14T11:43:48.643Z\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:55:45.664Z\", \"metrics\": {\"n_instances\": 551, \"ner_n\": 529, \"re_n\": 397, \"N\": 16, \"T\": 1, \"seed\": 42, \"full_test_set\": true, \"ner_voting_conf_rho\": 0.399, \"ner_sj_rho\": 0.398, \"ner_em_rho\": 0.339, \"ner_fk_rho\": 0.288, \"ner_logprob_rho\": 0.237, \"ner_voting_conf_auroc\": 0.704, \"ner_sj_auroc\": 0.697, \"ner_cond_em_rho\": 0.414, \"ner_cond_sj_rho\": 0.349, \"ner_cond_vc_rho\": 0.34, \"re_voting_conf_rho\": 0.38, \"re_logprob_rho\": 0.293, \"re_fk_rho\": 0.281, \"re_sj_rho\": 0.277, \"re_em_rho\": 0.148, \"re_voting_conf_auroc\": 0.699, \"re_cond_em_rho\": 0.475, \"re_cond_sj_rho\": 0.318, \"re_cond_vc_rho\": 0.35, \"re_cond_em_auroc\": 0.742, \"diagnosis\": \"551 instances T=1.0: voting_conf best on full set (NER 0.399, RE 0.380). EM SURPRISE best on conditional set (NER cond 0.414, RE cond 0.475). RE full FAIL (SJ 0.277 < 0.40). Previous N-scaling 'breakthrough' was artifact of 200 instances + T=0.7.\"}}, \"exp_002\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T12:39:53.226Z\", \"updated_at\": \"2026-05-14T12:40:17.202Z\", \"spec\": {\"command\": \"python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --collect_logprobs --num_test 99999\", \"server\": \"autodl-5090\", \"data_path\": \"data/conll2003\", \"data_count\": 3453, \"model_name\": \"qwen3-8b-conll2003-lora-merged\", \"seed\": 42, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-conll2003-merged\", \"log_path\": \"/tmp/pilot_conll2003.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T12:40:08.402Z\", \"metrics\": {\"sj_rho_full\": 0.4357, \"sj_tau_full\": 0.3851, \"sj_auroc_full\": 0.8008, \"sj_rho_cond\": 0.4511, \"fk_rho_full\": 0.3998, \"fk_tau_full\": 0.3568, \"fk_auroc_full\": 0.7741, \"fk_rho_cond\": 0.4064, \"logprob_rho_full\": 0.3157, \"logprob_tau_full\": 0.2469, \"logprob_auroc_full\": 0.7532, \"logprob_rho_cond\": 0.3562, \"em_rho_full\": 0.4507, \"em_tau_full\": 0.4002, \"em_auroc_full\": 0.8156, \"em_rho_cond\": 0.4799, \"ev_rho_full\": 0.4237, \"ev_tau_full\": 0.3777, \"ev_auroc_full\": 0.7889, \"ev_rho_cond\": 0.4127, \"greedy_f1\": 0.9123, \"oracle_f1\": 0.9543, \"voting_f1\": 0.9141, \"oracle_headroom\": 0.042, \"sj_vs_logprob_delta_rho\": 0.12, \"sj_vs_logprob_ci_low\": 0.0881, \"sj_vs_logprob_ci_high\": 0.154, \"sj_vs_logprob_significant\": true, \"n_instances\": 3453, \"n_valid\": 2756, \"n_samples\": 8, \"temperature\": 1}}, \"exp_002_ner_conll2003\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:42:15.223Z\", \"updated_at\": \"2026-05-14T12:27:35.413Z\", \"spec\": {\"command\": \"bash -c \\\"source /root/miniconda3/etc/profile.d/conda.sh && conda activate base && cd /root/autodl-tmp/struct_self_consist_ie && CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-conll2003-merged --data_dir data/conll2003 --dataset conll2003 --subtask ner --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/exp002_conll2003 --num_test 99999 --seed 42 --collect_logprobs 2>&1 | tee /tmp/pilot_conll2003.log\\\"\", \"server\": \"autodl-5090\", \"gpu\": [\"cuda:0\"], \"pid\": \"58208\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_002_ner_conll2003.log\", \"submitted_at\": \"2026-05-14T12:27:35.337Z\", \"submitted_via\": \"submit_training_job\", \"backend\": \"tmux\", \"account\": \"root\"}, \"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"account\": \"root\", \"reproduce\": {\"server\": \"autodl-5090\", \"gpu\": \"cuda:1\", \"started_at\": \"2026-05-14T11:43:49.959Z\"}, \"conclusion\": \"success\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-conll2003-lora\", \"log_path\": \"~/runs/struct_self_consist_ie/exp_002_ner_conll2003.log\", \"completed_at\": \"2026-05-14T12:18:04.097Z\"}, \"exp_004_re_diagnostic\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:49:44.497Z\", \"updated_at\": \"2026-05-14T11:50:24.620Z\", \"spec\": {\"hypothesis\": \"RE diagnostic: per-relation-type breakdown reveals which types drive low RE rho; error propagation and threshold sensitivity clarify the gap between NER and RE consistency signals\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Per-relation-type SJ/FK/voting rho, error propagation classification, threshold sensitivity, bootstrap CI, Fisher z-test NER vs RE\", \"command\": \"python3 code/analyze_exp004_re_diagnostic.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp004_re_diagnostic\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/exp004_re_diagnostic/\", \"checkpoint_source\": \"mvp_pilot_004\", \"eval_data\": \"scierc_test_551\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:50:04.662Z\", \"metrics\": {\"per_relation_type\": {\"HYPONYM-OF\": {\"n\": 36, \"rho_sj\": 0.545, \"rho_fk\": 0.646, \"rho_vc\": 0.628, \"mean_f1\": 0.513}, \"CONJUNCTION\": {\"n\": 86, \"rho_sj\": 0.383, \"rho_fk\": 0.35, \"rho_vc\": 0.484, \"mean_f1\": 0.48}, \"USED-FOR\": {\"n\": 299, \"rho_sj\": 0.236, \"rho_fk\": 0.255, \"rho_vc\": 0.286, \"mean_f1\": 0.422}, \"PART-OF\": {\"n\": 44, \"rho_sj\": 0.239, \"rho_fk\": 0.348, \"rho_vc\": 0.283, \"mean_f1\": 0.297}, \"EVALUATE-FOR\": {\"n\": 62, \"rho_sj\": 0.172, \"rho_fk\": 0.255, \"rho_vc\": 0.226, \"mean_f1\": 0.365}, \"COMPARE\": {\"n\": 35, \"rho_sj\": 0.168, \"rho_fk\": 0.184, \"rho_vc\": 0.18, \"mean_f1\": 0.453}, \"FEATURE-OF\": {\"n\": 50, \"rho_sj\": 0.004, \"rho_fk\": 0.052, \"rho_vc\": 0.014, \"mean_f1\": 0.254}}, \"error_propagation\": {\"total_fn\": 553, \"tail_error_pct\": 21.9, \"full_error_pct\": 21.7, \"head_error_pct\": 17.7, \"head_tail_error_pct\": 15.9, \"type_error_pct\": 8.3, \"worst_consistency\": \"head_type_error (sj=0.411)\", \"best_consistency\": \"head_error (sj=0.613)\"}, \"threshold_sensitivity\": {\"thr_0.00_rho_sj\": 0.3161, \"thr_0.00_rho_vc\": 0.3841, \"thr_0.00_n\": 313, \"thr_0.05_rho_sj\": 0.2682, \"thr_0.05_rho_vc\": 0.2364, \"thr_0.05_n\": 239}, \"bootstrap_ci_95\": {\"ner_sj\": [0.2946, 0.4586], \"ner_voting_conf\": [0.3048, 0.4656], \"re_sj\": [0.1422, 0.3391], \"re_voting_conf\": [0.1818, 0.3721], \"re_cond_sj\": [0.2161, 0.4102], \"re_cond_voting_conf\": [0.2825, 0.474]}, \"fisher_z_ner_vs_re\": {\"sj_z\": 2.31, \"sj_p\": 0.0209, \"sj_significant\": true, \"fk_z\": -0.31, \"fk_p\": 0.756, \"fk_significant\": false, \"voting_z\": 1.914, \"voting_p\": 0.0556, \"voting_significant\": false}, \"diagnosis\": \"FEATURE-OF is near-zero rho across all signals (n=50, F1=0.254). HYPONYM-OF strongest (rho_fk=0.646). Entity span errors (head+tail) account for 55.5% of RE FN. NER rho_sj significantly > RE rho_sj (p=0.021). Voting_conf is best RE signal in conditional set (rho=0.384).\"}}, \"exp_005\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T11:45:16.360Z\", \"updated_at\": \"2026-05-14T11:45:38.570Z\", \"spec\": {\"hypothesis\": \"Temperature sensitivity: systematic comparison of T=0.7 vs T=1.0 on all 5 confidence signals\", \"method\": \"CPU-only analysis from checkpoint metrics (pilot_004 T=1.0, pilot_005 T=0.7, exp_012/013/014)\", \"data_count\": 551, \"model_name\": \"Qwen3-8B-SciERC-LoRA-v2\", \"data_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/exp005_temperature/\", \"server\": \"local\", \"seed\": 42, \"parent\": \"mvp_pilot_004,mvp_pilot_005\", \"command\": \"python3 analyze_exp005_temperature.py\", \"checkpoint_path\": \"/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/exp005_temperature/\", \"log_path\": \"N/A\", \"checkpoint_source\": \"pilot_004+pilot_005 checkpoint metrics\", \"eval_data\": \"SciERC test set (n=551)\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:45:38.570Z\"}, \"exp_014_entity_majority_voting\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:53:21.203Z\", \"updated_at\": \"2026-05-14T11:33:30.085Z\", \"spec\": {\"hypothesis\": \"Entity-level majority voting confidence beats SJ as correlation signal\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Per-entity voting across N=8 samples, consensus construction, confidence = mean voting rate\", \"command\": \"python code/analyze_entity_voting.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/exp014_entity_voting_report.json\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:18:09.468Z\", \"metrics\": {\"ner_full_rho\": 0.3915, \"ner_full_p\": 8.1e-21, \"ner_full_tau\": 0.2906, \"ner_full_auroc\": 0.7039, \"re_full_rho\": 0.3403, \"re_full_p\": 3.21e-12, \"re_full_tau\": 0.256, \"re_full_auroc\": 0.6668, \"ner_voting_f1\": 0.6246, \"ner_greedy_f1\": 0.6483, \"ner_oracle_f1\": 0.7793, \"re_voting_f1\": 0.3577, \"re_greedy_f1\": 0.4022, \"re_oracle_f1\": 0.5886, \"diagnosis\": \"Voting confidence BEATS SJ on both NER (rho 0.392 vs 0.383) and RE (0.340 vs 0.244). But voting as selection strategy LOSES to greedy.\"}}, \"exp_013_exact_match_voting\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:53:18.753Z\", \"updated_at\": \"2026-05-14T11:33:22.644Z\", \"spec\": {\"hypothesis\": \"Exact-match voting rate correlates with F1\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Count exact-match duplicates across N=8 samples\", \"command\": \"python code/analyze_exact_match_voting.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/exp013_exact_match_report.json\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T11:18:09.026Z\", \"metrics\": {\"ner_full_rho\": 0.2941, \"ner_full_p\": 5.12e-12, \"ner_full_tau\": 0.2181, \"ner_full_auroc\": 0.6398, \"re_full_rho\": 0.1562, \"re_full_p\": 0.0018, \"re_full_tau\": 0.1185, \"re_full_auroc\": 0.5863, \"diagnosis\": \"EM between SJ and FK on NER, weakest on RE. Too coarse-grained.\"}}, \"exp_012_logprob_baseline\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T10:53:16.166Z\", \"updated_at\": \"2026-05-14T11:13:30.240Z\", \"spec\": {\"hypothesis\": \"Log-probability baseline: mean sequence log-prob correlates with F1 as well as or better than SJ\", \"model_name\": \"ft_002_v2 (qwen3-8b-scierc-merged-v2)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"vLLM forward pass for log-probs + Spearman rho + AUROC + Kendall tau\", \"command\": \"python3 code/extract_logprobs.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/logprob_analysis.log\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T11:06:42.542Z\", \"metrics\": {\"ner_full_rho_sj\": 0.3565, \"ner_full_rho_fk\": 0.2651, \"ner_full_rho_logprob\": 0.1396, \"ner_full_rho_greedy_logprob\": 0.1615, \"ner_full_tau_sj\": 0.2658, \"ner_full_tau_logprob\": 0.1006, \"ner_full_auroc_sj\": 0.6892, \"ner_full_auroc_fk\": 0.6292, \"ner_full_auroc_logprob\": 0.5907, \"ner_full_n\": 529, \"ner_sj_vs_logprob_delta\": 0.2169, \"re_full_rho_sj\": 0.2112, \"re_full_rho_fk\": 0.2528, \"re_full_rho_logprob\": 0.2467, \"re_full_auroc_sj\": 0.5916, \"re_full_auroc_fk\": 0.6262, \"re_full_auroc_logprob\": 0.6186, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3683, \"re_cond_rho_fk\": 0.3168, \"re_cond_rho_logprob\": 0.1457, \"re_cond_auroc_sj\": 0.6839, \"re_cond_auroc_logprob\": 0.5487, \"re_cond_n\": 296, \"diagnosis\": \"NER: SJ crushes logprob (rho +0.217). RE full: logprob slightly ahead. RE cond: SJ crushes logprob (rho +0.223). SJ unique value CONFIRMED.\"}}, \"mvp_pilot_005\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:14:09.456Z\", \"updated_at\": \"2026-05-14T09:47:06.597Z\", \"spec\": {\"hypothesis\": \"T=0.7 降低 RE zero rate，恢复 SJ>FK，rho_sj 可能 ≥ 0.30 (MARGINAL threshold)\", \"model_name\": \"Qwen3-8B-SciERC-LoRA-v2 (ft_002_v2 final)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_002_v2\", \"method\": \"N=8 sampling T=0.7 + XGrammar + span realignment + max_tokens=1024 + gold-empty filter + conditional rho\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 0.7 --max_tokens 1024 --output_dir output/mvp_pilot_005 --num_test 551 --seed 42 --tensor_parallel 1\", \"gpu\": \"cuda:0\", \"pid\": 32456, \"tmux_session\": \"mvp_pilot_005\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_005/train.log\"}, \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_005\", \"metrics\": {\"ner_greedy_f1\": 0.6619, \"ner_oracle_f1\": 0.7585, \"ner_headroom\": 0.0966, \"ner_fleiss_kappa_mean\": 0.4722, \"ner_soft_jaccard_mean\": 0.7757, \"ner_full_rho_sj\": 0.3875, \"ner_full_rho_fk\": 0.3211, \"ner_full_n\": 529, \"ner_cond_rho_sj\": 0.3868, \"ner_cond_rho_fk\": 0.305, \"ner_cond_n\": 504, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_rho_advantage\": 0.0664, \"ner_sample_f1_mean\": 0.6243, \"ner_sample_f1_std\": 0.3131, \"ner_sample_f1_pct_zero\": 11.2, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 25, \"re_greedy_f1\": 0.4219, \"re_oracle_f1\": 0.5532, \"re_headroom\": 0.1313, \"re_fleiss_kappa_mean\": 0.3829, \"re_soft_jaccard_mean\": 0.687, \"re_full_rho_sj\": 0.2343, \"re_full_rho_fk\": 0.1835, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3716, \"re_cond_rho_fk\": 0.2533, \"re_cond_n\": 301, \"re_sj_beats_fk_full\": true, \"re_sj_beats_fk_cond\": true, \"re_rho_advantage\": 0.0508, \"re_sample_f1_mean\": 0.3782, \"re_sample_f1_std\": 0.3845, \"re_sample_f1_pct_zero\": 42.4, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 96, \"parse_failures\": 0, \"verdict\": \"FAIL\", \"verdict_note\": \"RE full rho_sj=0.234 < 0.40; RE cond rho_sj=0.372 passes conditional but not full threshold\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T09:47:06.597Z\"}, \"e1_component_wise_re_sj\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T09:15:17.262Z\", \"updated_at\": \"2026-05-14T09:23:38.818Z\", \"spec\": {\"hypothesis\": \"RE SJ 乘性惩罚是 root cause：分解后 head_sj ρ ≈ NER ρ (~0.38)，tail_sj 和乘性组合拖低整体 ρ\", \"model_name\": \"N/A (reuse pilot_004 samples)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"data_count\": 397, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"mvp_pilot_004\", \"method\": \"Component-wise decomposition: head_sj, tail_sj, type_match 分别计算 Spearman ρ vs per-instance RE F1\", \"command\": \"python3 code/analyze_component_wise_re.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/e1_component_analysis.log\"}, \"conclusion\": \"negative\", \"metrics\": {\"full_head_sj_rho\": 0.21, \"full_tail_sj_rho\": 0.201, \"full_type_match_rho\": 0.201, \"full_multiplicative_rho\": 0.244, \"full_additive_rho\": 0.243, \"full_fleiss_kappa_rho\": 0.278, \"cond_head_sj_rho\": 0.27, \"cond_tail_sj_rho\": 0.259, \"cond_type_match_rho\": 0.252, \"cond_multiplicative_rho\": 0.316, \"cond_additive_rho\": 0.306, \"cond_fleiss_kappa_rho\": 0.307, \"n_full\": 397, \"n_conditional\": 313, \"diagnosis\": \"head_sj rho=0.210 FAR from NER rho=0.383. Multiplicative penalty hypothesis REJECTED. Problem is fundamental: span-level SJ lacks discriminative power for RE.\"}, \"completed_at\": \"2026-05-14T09:22:26.155Z\"}, \"mvp_pilot_004\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:51:38.203Z\", \"updated_at\": \"2026-05-14T09:10:40.918Z\", \"spec\": {\"hypothesis\": \"With improved RE quality (F1=41.8%), structural self-consistency (soft Jaccard) correlates with per-instance F1 better than surface Fleiss Kappa, reaching rho_sj >= 0.40 on RE\", \"model_name\": \"Qwen3-8B-SciERC-LoRA-v2 (ft_002_v2 final)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_002_v2\", \"method\": \"N=8 sampling T=1.0 + XGrammar + span realignment + max_tokens=1024 + gold-empty filter + conditional rho\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-merged-v2 --data_dir data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir output/mvp_pilot_004 --num_test 551 --seed 42 --tensor_parallel 1\", \"gpu\": \"cuda:0\", \"pid\": 31041, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004/mvp_pilot_004.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_004\"}, \"metrics\": {\"ner_greedy_f1\": 0.6671, \"ner_oracle_f1\": 0.7756, \"ner_headroom\": 0.1085, \"ner_fleiss_kappa_mean\": 0.4048, \"ner_soft_jaccard_mean\": 0.7008, \"ner_full_rho_fk\": 0.259, \"ner_full_rho_sj\": 0.3825, \"ner_full_n\": 529, \"ner_cond_rho_fk\": 0.2352, \"ner_cond_rho_sj\": 0.3762, \"ner_cond_n\": 508, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_sample_f1_mean\": 0.6084, \"ner_sample_f1_std\": 0.3174, \"ner_sample_f1_pct_zero\": 12.19, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 21, \"re_greedy_f1\": 0.4208, \"re_oracle_f1\": 0.5882, \"re_headroom\": 0.1674, \"re_fleiss_kappa_mean\": 0.2996, \"re_soft_jaccard_mean\": 0.6114, \"re_full_rho_fk\": 0.2782, \"re_full_rho_sj\": 0.2441, \"re_full_n\": 397, \"re_cond_rho_fk\": 0.3067, \"re_cond_rho_sj\": 0.3161, \"re_cond_n\": 313, \"re_sj_beats_fk_full\": false, \"re_sj_beats_fk_cond\": true, \"re_sample_f1_mean\": 0.3612, \"re_sample_f1_std\": 0.383, \"re_sample_f1_pct_zero\": 44.3, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 84, \"parse_failures\": 0, \"verdict\": \"FAIL\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T09:10:40.918Z\"}, \"ft_002_v2\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:28:40.861Z\", \"updated_at\": \"2026-05-14T08:51:32.405Z\", \"spec\": {\"hypothesis\": \"Extended training (5 epochs, LoRA r=32) with OOM fix improves RE F1 above 40% threshold\", \"model_name\": \"Qwen/Qwen3-8B\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/llmfactory_train.json\", \"data_count\": 1861, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"LoRA r=32 alpha=64, 5 epochs, batch=2 grad_accum=8 gradient_checkpointing=true\", \"gpu\": \"cuda:1\", \"pid\": 24947, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/ft_002v2_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-lora-v2\", \"command\": \"CUDA_VISIBLE_DEVICES=1 llamafactory-cli train train_config_v2.yaml\"}, \"conclusion\": \"success\", \"metrics\": {\"epoch\": 5, \"train_loss\": 0.0806, \"eval_loss\": 0.089, \"train_runtime\": \"28m41s\", \"train_samples_per_second\": 5.407, \"train_steps_per_second\": 0.34, \"total_steps\": 585, \"checkpoints\": [\"checkpoint-400\", \"checkpoint-500\", \"checkpoint-585\"], \"gate0_final_ner_f1\": 0.6615, \"gate0_final_re_f1\": 0.4177, \"gate0_final_parse_failures\": 0, \"gate0_final_ner_pass\": true, \"gate0_final_re_pass\": true, \"gate0_final_pass\": true, \"gate0_ckpt400_ner_f1\": 0.6475, \"gate0_ckpt400_re_f1\": 0.3793, \"gate0_ckpt400_parse_failures\": 0, \"gate0_ckpt400_verdict\": \"FAIL\", \"gate0_ckpt400_re_sample_f1_pct_zero\": 58.8, \"gate0_ckpt400_warning\": \">30% samples F1=0\"}, \"completed_at\": \"2026-05-14T08:51:32.405Z\"}, \"mvp_pilot_002\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:02:16.991Z\", \"updated_at\": \"2026-05-14T08:48:14.040Z\", \"spec\": {\"hypothesis\": \"Structural self-consistency (soft Jaccard) correlates with per-instance F1 better than surface Fleiss Kappa on fine-tuned Qwen3-8B SciERC\", \"model_name\": \"Qwen3-8B-SciERC-LoRA (ft_001)\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"N=8 sampling T=1.0 + XGrammar + span realignment + gold-empty filter + conditional rho\", \"gpu\": \"cuda:0\", \"note\": \"Rerun of mvp_pilot_001 which crashed silently\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/run_mvp_pilot.py --model_path checkpoints/qwen3-8b-scierc-lora --data_dir data/scierc --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 512 --output_dir output/mvp_pilot_001 --num_test 551 --seed 42 --tensor_parallel 1\", \"failure_reason\": \"Worker used LoRA adapter path instead of merged model path; vLLM cannot load LoRA adapter directly\"}, \"conclusion\": \"failed\", \"completed_at\": \"2026-05-14T08:48:14.040Z\"}, \"ft_002\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:39:18.640Z\", \"updated_at\": \"2026-05-14T08:28:00.590Z\", \"spec\": {\"hypothesis\": \"Extended training (5 epochs, LoRA r=32) improves RE F1 above 40% threshold\", \"model_name\": \"Qwen/Qwen3-8B\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/llmfactory_train.json\", \"data_count\": 1861, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"LoRA r=32 alpha=64, 5 epochs, relation direction hint\", \"command\": \"llamafactory-cli train /root/autodl-tmp/struct_self_consist_ie/train_config_v2.yaml\", \"gpu\": \"cuda:1\", \"pid\": 19666, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/ft_002_train.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-lora-v2\", \"total_steps\": 585, \"trainable_params\": \"87.3M\", \"estimated_runtime\": \"29min\"}, \"conclusion\": \"killed\", \"completed_at\": \"2026-05-14T08:02:30.390Z\", \"metrics\": {\"last_step\": 70, \"total_steps\": 585, \"progress_pct\": 11.97, \"last_loss\": 0.1134, \"last_lr\": 0.00019982, \"elapsed\": \"3m32s\", \"failure_reason\": \"OOM at step 73, batch_size=4 too large for 32GB RTX 5090\"}}, \"ft_001\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T06:04:28.030Z\", \"updated_at\": \"2026-05-14T08:27:58.182Z\", \"spec\": {\"hypothesis\": \"Fine-tuned Qwen3-8B on SciERC UIE can achieve NER F1 >= 73 and serve as base model for structural consistency MVP\", \"model_name\": \"Qwen/Qwen3-8B\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc\", \"data_count\": 1861, \"server\": \"autodl-5090\", \"seed\": 42, \"method\": \"LoRA r=16 alpha=32\", \"framework\": \"LLaMA Factory 0.9.4\", \"command\": \"sft training qwen3-8b on scierc with lora\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-lora/\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/ft_001_train.log\", \"train_loss\": 0.1099, \"eval_loss\": 0.0771, \"epoch\": 3, \"train_runtime\": \"0:17:49\", \"note\": \"gate0: NER PASS 60.4% / RE FAIL 33.8%\"}, \"conclusion\": \"success\", \"completed_at\": \"2026-05-14T06:30:32.889Z\", \"metrics\": {\"train_loss\": 0.1099, \"eval_loss\": 0.0771, \"gate0_ner_f1_strict\": 0.1143, \"gate0_re_f1_strict\": 0.0125, \"gate0_ner_f1_text\": 0.606, \"gate0_re_f1_text\": 0.3392, \"gate0_offset_accuracy\": 0.1665, \"gate0_parse_failures\": 43, \"gate0_pass\": false, \"gate0_realigned_ner_f1\": 0.6045, \"gate0_realigned_re_f1\": 0.338, \"gate0_realigned_entity_offset_accuracy\": 1, \"gate0_realigned_relation_offset_accuracy\": 1, \"gate0_realigned_ner_pass\": true, \"gate0_realigned_re_pass\": false, \"gate0_realigned_pass\": false, \"gate0_ner_f1_delta_realign\": 0.4901, \"gate0_re_f1_delta_realign\": 0.3255, \"verdict_note\": \"partial: NER PASS (60.4%) / RE FAIL (33.8% < 40%)\"}}, \"mvp_pilot_003\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T08:21:09.847Z\", \"updated_at\": \"2026-05-14T08:21:44.983Z\", \"spec\": {\"command\": \"CUDA_VISIBLE_DEVICES=0 python code/run_mvp_pilot.py --model_path /root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged --data_dir /root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data --dataset scierc --subtask joint --n_samples 8 --temperature 1.0 --max_tokens 1024 --output_dir /root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_003 --num_test 551 --seed 42 --tensor_parallel 1\", \"server\": \"autodl-5090\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/scierc/processed_data\", \"data_count\": 551, \"model_name\": \"qwen3-8b-scierc-merged\", \"seed\": 42}, \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/mvp_pilot_003.log\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_003\", \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T08:21:30.319Z\", \"metrics\": {\"ner_greedy_f1\": 0.6362, \"ner_oracle_f1\": 0.792, \"ner_headroom\": 0.1559, \"ner_fleiss_kappa_mean\": 0.2488, \"ner_soft_jaccard_mean\": 0.5066, \"ner_full_rho_sj\": 0.3808, \"ner_full_rho_fk\": 0.3362, \"ner_full_p_sj\": 1.07e-19, \"ner_full_p_fk\": 1.93e-15, \"ner_full_n\": 529, \"ner_cond_rho_sj\": 0.3836, \"ner_cond_rho_fk\": 0.3187, \"ner_cond_p_sj\": 1.83e-19, \"ner_cond_p_fk\": 1.33e-13, \"ner_cond_n\": 514, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_rho_advantage\": 0.0446, \"ner_sample_f1_mean\": 0.5153, \"ner_sample_f1_std\": 0.3334, \"ner_sample_f1_pct_zero\": 19.9, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 15, \"re_greedy_f1\": 0.3774, \"re_oracle_f1\": 0.5939, \"re_headroom\": 0.2165, \"re_fleiss_kappa_mean\": 0.0879, \"re_soft_jaccard_mean\": 0.3958, \"re_full_rho_sj\": 0.2367, \"re_full_rho_fk\": 0.2221, \"re_full_p_sj\": 1.85e-06, \"re_full_p_fk\": 7.92e-06, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3004, \"re_cond_rho_fk\": 0.2374, \"re_cond_p_sj\": 2.25e-08, \"re_cond_p_fk\": 1.19e-05, \"re_cond_n\": 333, \"re_sj_beats_fk_full\": true, \"re_sj_beats_fk_cond\": true, \"re_rho_advantage\": 0.0146, \"re_sample_f1_mean\": 0.1977, \"re_sample_f1_std\": 0.3251, \"re_sample_f1_pct_zero\": 67.6, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 64, \"parse_failures_stochastic\": 0, \"parse_failures_greedy\": 0, \"total_stochastic_samples\": 4408, \"total_greedy\": 551, \"verdict\": \"FAIL\", \"verdict_reason\": \"RE full rho_sj=0.2367 < 0.40 threshold; strong signal exists but below PASS bar\"}}, \"mvp_pilot_001\": {\"status\": \"DONE\", \"retry_count\": 0, \"created_at\": \"2026-05-14T07:39:16.313Z\", \"updated_at\": \"2026-05-14T08:05:34.348Z\", \"spec\": {\"hypothesis\": \"Structural self-consistency (soft Jaccard) correlates with per-instance F1 better than surface Fleiss Kappa on fine-tuned Qwen3-8B SciERC\", \"model_name\": \"qwen3-8b-scierc-merged\", \"data_path\": \"/root/autodl-tmp/struct_self_consist_ie/data/test.jsonl\", \"data_count\": 551, \"server\": \"autodl-5090\", \"seed\": 42, \"parent\": \"ft_001\", \"method\": \"N=8 sampling T=1.0 + XGrammar + span realignment\", \"command\": \"CUDA_VISIBLE_DEVICES=0 python3 code/mvp_pilot.py\", \"checkpoint_path\": \"/root/autodl-tmp/struct_self_consist_ie/checkpoints/qwen3-8b-scierc-merged\", \"log_path\": \"/root/autodl-tmp/struct_self_consist_ie/output/mvp_pilot_001.log\"}, \"conclusion\": \"negative\", \"completed_at\": \"2026-05-14T07:52:47.006Z\", \"metrics\": {\"ner_greedy_f1\": 0.611, \"ner_oracle_f1\": 0.78, \"ner_headroom\": 0.169, \"ner_fleiss_kappa_mean\": 0.2449, \"ner_soft_jaccard_mean\": 0.5041, \"ner_full_rho_sj\": 0.3616, \"ner_full_rho_fk\": 0.3515, \"ner_full_n\": 529, \"ner_cond_rho_sj\": 0.3688, \"ner_cond_rho_fk\": 0.3569, \"ner_cond_n\": 510, \"ner_sj_beats_fk_full\": true, \"ner_sj_beats_fk_cond\": true, \"ner_sample_f1_pct_zero\": 20.4, \"ner_gold_empty_filtered\": 22, \"ner_all_zero_filtered\": 19, \"re_greedy_f1\": 0.355, \"re_oracle_f1\": 0.572, \"re_headroom\": 0.217, \"re_fleiss_kappa_mean\": 0.0681, \"re_soft_jaccard_mean\": 0.3635, \"re_full_rho_sj\": 0.2535, \"re_full_rho_fk\": 0.2885, \"re_full_n\": 397, \"re_cond_rho_sj\": 0.3515, \"re_cond_rho_fk\": 0.3107, \"re_cond_n\": 320, \"re_sj_beats_fk_full\": false, \"re_sj_beats_fk_cond\": true, \"re_sample_f1_pct_zero\": 58.3, \"re_gold_empty_filtered\": 154, \"re_all_zero_filtered\": 77, \"parse_failures_stochastic\": 164, \"parse_failures_greedy\": 29, \"total_stochastic_samples\": 4408, \"total_greedy\": 551, \"verdict\": \"FAIL\", \"verdict_reason\": \"RE full rho_sj=0.2535 < 0.40; SJ does not beat FK on RE full set\"}}}, \"count\": 171, \"total\": 171, \"baseline\": null}, \"error\": null, \"metadata\": {\"elapsed_seconds\": 0.4883}}"
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
The registry is very large. Let me read the paper sections first, and then process the registry data for the specific experiments mentioned in the task. Let me start reading the paper sections and also the registry data for specific experiments.

Let me first check what paper files exist, and also start reading the registry data.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "96067d3c-d7bd-4a2f-bbe0-cb9c4e307f48",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NNzTMNGm7eNWUz7HtPo2zi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13178,
      "cache_read_input_tokens": 25722,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13178
      },
      "output_tokens": 10,
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

Registry 数据量大，需要分块读取。先并行读取论文各章节和 registry 中的关键实验。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "5cabfbe0-dd8a-44c4-a709-427b08f71a73",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NNzTMNGm7eNWUz7HtPo2zi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13178,
      "cache_read_input_tokens": 25722,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13178
      },
      "output_tokens": 10,
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

<details open><summary>🔧 Tool call — Glob · `toolu_01CW8rvejJ9o13ekZY8di26j`</summary>

```json
{
  "pattern": "**/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "b43f7902-e773-40ca-a908-23acce9e4e40",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NNzTMNGm7eNWUz7HtPo2zi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13178,
      "cache_read_input_tokens": 25722,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13178
      },
      "output_tokens": 10,
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

_source line 17 · 2026-05-19T13:33:43.271Z_

<details><summary>↩ Tool result · `toolu_01CW8rvejJ9o13ekZY8di26j`</summary>

```text
artifacts/dream_reports/dream_20260514T093336/best/paper.tex
artifacts/dream_reports/dream_20260514T093336/median/paper.tex
artifacts/dream_reports/dream_20260514T093336/worst/paper.tex
artifacts/dream_reports/dream_20260514T105303/best/paper.tex
artifacts/dream_reports/dream_20260514T105303/median/paper.tex
artifacts/dream_reports/dream_20260514T105303/worst/paper.tex
artifacts/_project/paper/related_work.tex
artifacts/dream_reports/dream_20260514T203201/best/paper.tex
artifacts/dream_reports/dream_20260514T203201/median/paper.tex
artifacts/dream_reports/dream_20260514T203201/worst/paper.tex
artifacts/bootstrap_ci_tables.tex
artifacts/dream_reports/dream_20260515T092545/best/paper.tex
artifacts/dream_reports/dream_20260515T092545/median/paper.tex
artifacts/dream_reports/dream_20260515T092545/worst/paper.tex
artifacts/_project/paper/freeform_ablation_appendix_table.tex
artifacts/freeform_ablation_appendix_table.tex
artifacts/_project/paper/n_scaling_appendix_tables_44b000.tex
artifacts/n_scaling_appendix_tables.tex
artifacts/_project/paper/method.tex
artifacts/_project/paper/n_scaling_appendix_tables.tex
artifacts/_project/paper/introduction.tex
artifacts/_project/paper/discussion.tex
artifacts/_project/paper/limitations.tex
artifacts/_project/paper/conclusion.tex
artifacts/_project/paper/abstract.tex
artifacts/_project/paper/experiments.tex
artifacts/dream_reports/dream_20260516T092241/best/paper.tex
artifacts/dream_reports/dream_20260516T092241/median/paper.tex
artifacts/dream_reports/dream_20260516T092241/worst/paper.tex
artifacts/dream_reports/dream_20260516T113255/best/paper.tex
artifacts/dream_reports/dream_20260516T113255/median/paper.tex
artifacts/dream_reports/dream_20260516T113255/worst/paper.tex
artifacts/per_type_lp_table.tex
artifacts/exp_021_fewnerd_full/paper/per_type_lp_table.tex
docs/paper/sections/checklist.tex
docs/paper/main.tex
docs/paper/sections/appendix.tex
docs/paper/sections/method.tex
docs/paper/sections/related_work.tex
docs/paper/sections/introduction.tex
code/scale_table.tex
docs/paper/sections/abstract.tex
docs/paper/sections/limitations.tex
docs/paper/sections/discussion.tex
docs/paper/sections/conclusion.tex
docs/paper/sections/experiments.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "07cc06cc-ae3d-4782-aeb3-6b529f5be703",
  "tool_use_result": {
    "filenames": [
      "artifacts/dream_reports/dream_20260514T093336/best/paper.tex",
      "artifacts/dream_reports/dream_20260514T093336/median/paper.tex",
      "artifacts/dream_reports/dream_20260514T093336/worst/paper.tex",
      "artifacts/dream_reports/dream_20260514T105303/best/paper.tex",
      "artifacts/dream_reports/dream_20260514T105303/median/paper.tex",
      "artifacts/dream_reports/dream_20260514T105303/worst/paper.tex",
      "artifacts/_project/paper/related_work.tex",
      "artifacts/dream_reports/dream_20260514T203201/best/paper.tex",
      "artifacts/dream_reports/dream_20260514T203201/median/paper.tex",
      "artifacts/dream_reports/dream_20260514T203201/worst/paper.tex",
      "artifacts/bootstrap_ci_tables.tex",
      "artifacts/dream_reports/dream_20260515T092545/best/paper.tex",
      "artifacts/dream_reports/dream_20260515T092545/median/paper.tex",
      "artifacts/dream_reports/dream_20260515T092545/worst/paper.tex",
      "artifacts/_project/paper/freeform_ablation_appendix_table.tex",
      "artifacts/freeform_ablation_appendix_table.tex",
      "artifacts/_project/paper/n_scaling_appendix_tables_44b000.tex",
      "artifacts/n_scaling_appendix_tables.tex",
      "artifacts/_project/paper/method.tex",
      "artifacts/_project/paper/n_scaling_appendix_tables.tex",
      "artifacts/_project/paper/introduction.tex",
      "artifacts/_project/paper/discussion.tex",
      "artifacts/_project/paper/limitations.tex",
      "artifacts/_project/paper/conclusion.tex",
      "artifacts/_project/paper/abstract.tex",
      "artifacts/_project/paper/experiments.tex",
      "artifacts/dream_reports/dream_20260516T092241/best/paper.tex",
      "artifacts/dream_reports/dream_20260516T092241/median/paper.tex",
      "artifacts/dream_reports/dream_20260516T092241/worst/paper.tex",
      "artifacts/dream_reports/dream_20260516T113255/best/paper.tex",
      "artifacts/dream_reports/dream_20260516T113255/median/paper.tex",
      "artifacts/dream_reports/dream_20260516T113255/worst/paper.tex",
      "artifacts/per_type_lp_table.tex",
      "artifacts/exp_021_fewnerd_full/paper/per_type_lp_table.tex",
      "docs/paper/sections/checklist.tex",
      "docs/paper/main.tex",
      "docs/paper/sections/appendix.tex",
      "docs/paper/sections/method.tex",
      "docs/paper/sections/related_work.tex",
      "docs/paper/sections/introduction.tex",
      "code/scale_table.tex",
      "docs/paper/sections/abstract.tex",
      "docs/paper/sections/limitations.tex",
      "docs/paper/sections/discussion.tex",
      "docs/paper/sections/conclusion.tex",
      "docs/paper/sections/experiments.tex"
    ],
    "durationMs": 29,
    "numFiles": 46,
    "truncated": false
  }
}
```

</details>

---


### Tool call

_source line 18_

<details open><summary>🔧 Tool call — Glob · `toolu_01AV3y9BcyBDTZuyb4Z2exYL`</summary>

```json
{
  "pattern": "**/sections/*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "48b36168-64a8-4c51-9289-eab6a24e499d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NNzTMNGm7eNWUz7HtPo2zi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13178,
      "cache_read_input_tokens": 25722,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13178
      },
      "output_tokens": 10,
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

_source line 19 · 2026-05-19T13:33:43.637Z_

<details><summary>↩ Tool result · `toolu_01AV3y9BcyBDTZuyb4Z2exYL`</summary>

```text
docs/paper/sections/checklist.tex
docs/paper/sections/appendix.tex
docs/paper/sections/method.tex
docs/paper/sections/related_work.tex
docs/paper/sections/introduction.tex
docs/paper/sections/abstract.tex
docs/paper/sections/limitations.tex
docs/paper/sections/discussion.tex
docs/paper/sections/conclusion.tex
docs/paper/sections/experiments.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "9d14ee6e-af9c-461b-8acd-c9fff191a41f",
  "tool_use_result": {
    "filenames": [
      "docs/paper/sections/checklist.tex",
      "docs/paper/sections/appendix.tex",
      "docs/paper/sections/method.tex",
      "docs/paper/sections/related_work.tex",
      "docs/paper/sections/introduction.tex",
      "docs/paper/sections/abstract.tex",
      "docs/paper/sections/limitations.tex",
      "docs/paper/sections/discussion.tex",
      "docs/paper/sections/conclusion.tex",
      "docs/paper/sections/experiments.tex"
    ],
    "durationMs": 25,
    "numFiles": 10,
    "truncated": false
  }
}
```

</details>

---


### Tool call

_source line 20_

<details open><summary>🔧 Tool call — Glob · `toolu_01WZQ6eoS6jefmvU6u6HDZEj`</summary>

```json
{
  "pattern": "**/*.md",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts/_project/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "9c9622b5-cfbf-4ff9-a34e-bc4a7d43219a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NNzTMNGm7eNWUz7HtPo2zi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13178,
      "cache_read_input_tokens": 25722,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13178
      },
      "output_tokens": 10,
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

_source line 21 · 2026-05-19T13:33:44.616Z_

<details><summary>↩ Tool result · `toolu_01WZQ6eoS6jefmvU6u6HDZEj`</summary>

```text
No files found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "3dcefb32-cb61-4723-9516-b5d8d7f459ae",
  "tool_use_result": {
    "filenames": [],
    "durationMs": 5,
    "numFiles": 0,
    "truncated": false
  }
}
```

</details>

---


### Assistant

_source line 22_

<details><summary>Logged reasoning block</summary>

```text
The paper sections are in `docs/paper/sections/`. Let me read all the key sections. Also, I need to read the registry data. Let me read all sections in parallel and also start extracting specific experiment data from the registry.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "cb2206a6-b7dd-47e2-91e3-f0592263a651",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Aqkjj9hxgV8pX4f8kaENzc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1290,
      "cache_read_input_tokens": 38900,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1290
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

_source line 23_

论文编译版本在 `docs/paper/sections/`。并行读取所有章节。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "1a6e9c83-5b69-4eda-aa9c-917097a81b30",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Aqkjj9hxgV8pX4f8kaENzc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1290,
      "cache_read_input_tokens": 38900,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1290
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

_source line 24_

<details open><summary>🔧 Tool call — Read · `toolu_017UqY3FDNscViUp2B3fKNEa`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "826ca1a3-62a0-4d2d-a476-0ed3e259671e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Aqkjj9hxgV8pX4f8kaENzc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1290,
      "cache_read_input_tokens": 38900,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1290
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

_source line 25 · 2026-05-19T13:33:48.980Z_

<details><summary>↩ Tool result · `toolu_017UqY3FDNscViUp2B3fKNEa`</summary>

```text
1	\begin{abstract}
2	Self-consistency yields large gains on discrete-answer tasks, but named entity recognition (NER) produces \textit{sets} of entities with partial overlap, where no majority vote analog exists.
3	We evaluate five confidence signals for quality estimation (QE) and sample selection on four NER benchmarks using fine-tuned 4B\textendash 8B models.
4	All signals achieve reliable QE ($\rho$ up to 0.45 on CoNLL-2003, area under the ROC curve [AUROC] up to 0.82), enabling selective prediction ($+5$--$8$\,pp F1 at 80\% coverage).
5	For instance-level selection, log-probability (LP) succeeds only where LP-quality alignment is strong, and gains are absent elsewhere despite large oracle headroom (the \textbf{correlation-selection gap}).
6	We identify three qualitative factors: instance degeneracy, oracle headroom, and LP-quality alignment; degeneracy causally modulates LP within fixed settings but does not predict cross-dataset direction.
7	The diagnostic naturally motivates entity-level \textit{construction}, adapting entity voting to stochastic sampling: LP-weighted aggregation improves F1 by $+1.40$\,pp on Few-NERD and $+1.02$\,pp on SciERC (multi-seed mean, $p{<}0.005$). Construction and LP selection are complementary, governed by LP-quality alignment.
8	\end{abstract}
9	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "d50693da-4aa7-42d1-8fc1-ca91c906b605",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/abstract.tex",
      "content": "\\begin{abstract}\nSelf-consistency yields large gains on discrete-answer tasks, but named entity recognition (NER) produces \\textit{sets} of entities with partial overlap, where no majority vote analog exists.\nWe evaluate five confidence signals for quality estimation (QE) and sample selection on four NER benchmarks using fine-tuned 4B\\textendash 8B models.\nAll signals achieve reliable QE ($\\rho$ up to 0.45 on CoNLL-2003, area under the ROC curve [AUROC] up to 0.82), enabling selective prediction ($+5$--$8$\\,pp F1 at 80\\% coverage).\nFor instance-level selection, log-probability (LP) succeeds only where LP-quality alignment is strong, and gains are absent elsewhere despite large oracle headroom (the \\textbf{correlation-selection gap}).\nWe identify three qualitative factors: instance degeneracy, oracle headroom, and LP-quality alignment; degeneracy causally modulates LP within fixed settings but does not predict cross-dataset direction.\nThe diagnostic naturally motivates entity-level \\textit{construction}, adapting entity voting to stochastic sampling: LP-weighted aggregation improves F1 by $+1.40$\\,pp on Few-NERD and $+1.02$\\,pp on SciERC (multi-seed mean, $p{<}0.005$). Construction and LP selection are complementary, governed by LP-quality alignment.\n\\end{abstract}\n",
      "numLines": 9,
      "startLine": 1,
      "totalLines": 9
    }
  }
}
```

</details>

---


### Tool call

_source line 26_

<details open><summary>🔧 Tool call — Read · `toolu_013Q4FAyM3U1iRGZHryiqBh4`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "5691fe6c-04e3-4d44-971f-56b87b60bb66",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Aqkjj9hxgV8pX4f8kaENzc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1290,
      "cache_read_input_tokens": 38900,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1290
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

_source line 27 · 2026-05-19T13:33:49.347Z_

<details><summary>↩ Tool result · `toolu_013Q4FAyM3U1iRGZHryiqBh4`</summary>

```text
1	\section{Introduction}\label{sec:introduction}
2	
3	Self-consistency (majority voting over multiple samples) yields large gains on discrete-answer reasoning \citep{wang2023selfconsistency}, and test-time compute scaling has emerged as a complementary axis to model scaling \cite{snell2025scaling, brown2024monkeys}.
4	But named entity recognition (NER) poses a structurally different challenge: the output is a \textit{set} of entities, two samples may extract overlapping but non-identical sets, and there is no obvious majority to vote on.
5	
6	Prior work on confidence estimation for LLM-based IE has conflated \textit{quality estimation} (which inputs does the model handle reliably?) with \textit{sample selection} (which of $N$ outputs is best?).
7	Existing self-consistency methods \cite{wang2023selfconsistency, chen2024usc, taubenfeld2025cisc, kang2025selfcertainty} assume outputs can be grouped by equivalence, an assumption that breaks for entity sets with partial overlap.
8	Unlike \citet{yao2026consistency}, who demonstrate that self-consistency correlates with task accuracy, we provide the first systematic empirical characterization of \textit{when and why} LP-based selection succeeds or fails for structured prediction, diagnosing degeneracy and compression as the two blocking mechanisms.
9	Our experiments use fine-tuned models, the dominant deployment paradigm for production NER, and separate quality estimation from best-of-$N$ selection.
10	
11	A key distinction structures our analysis: four of five signals (Soft Jaccard, voting confidence, Fleiss' $\kappa$, exact match) are instance-level aggregates that assign identical scores to all $N$ candidates for a given input; only log-probability (LP) is natively per-sample.
12	All signals achieve reliable quality estimation ($\rho$ up to 0.45, AUROC up to 0.82; Figure~\ref{fig:overview}), supporting selective prediction.
13	For selection, LP achieves $+1.39$~pp on Few-NERD ($p{<}0.001$) in settings where both low instance degeneracy and adequate alignment are present, with gains scaling with $N$.
14	On SciERC, the observed LP gain ($+0.2$~pp, $p{=}0.29$) falls below the minimum detectable effect (${\approx}$1.5~pp at 80\% power, $n{=}529$) despite 13~pp oracle headroom. We term this disparity between quality estimation strength and selection effectiveness the \textbf{correlation-selection gap}.
15	Three factors qualitatively shape this gap: (a)~\textit{instance degeneracy} (13\textendash 87\% across our benchmarks) compresses the candidate space; (b)~\textit{oracle headroom} bounds the achievable gain; (c)~\textit{LP-quality alignment} (within-instance $\rho(\text{LP}, \text{F1})$) determines whether LP can discriminate candidates in non-degenerate instances (\S\ref{sec:selection_gap}).
16	Our diagnosis is complementary to minimum Bayes risk (MBR) utility misalignment \cite{eikema2025structured}: where MBR failures in structured prediction stem from poorly chosen utility functions, we find that degeneracy eliminates candidate diversity before utility alignment matters.
17	Within non-degenerate instances, MBR utility correlates positively with F1 ($\rho{=}0.52$; \S\ref{sec:discussion}).
18	Both mechanisms intensify with model capability: degeneracy rises with scale and training convergence (\S\ref{sec:discussion}). This creates a tension between model quality and test-time improvability.
19	
20	\begin{figure*}[t]
21	\centering
22	\includegraphics[width=\textwidth]{fig_overview}
23	\caption{Overview of the correlation-selection gap and its mitigation. \textbf{Left}: consistency signals reliably estimate instance-level quality ($\rho$ up to 0.45 on CoNLL; Table~\ref{tab:quality_estimation}). \textbf{Center}: instance-level signals assign identical scores to all samples from the same input, so best-of-$N$ selection cannot outperform greedy. \textbf{Right}: entity-level construction aggregates entities across samples via majority vote ($\theta{=}2/N$), bypassing the selection bottleneck ($+1.40$\,pp on Few-NERD, multi-seed mean; \S\ref{sec:prescriptive}).}
24	\label{fig:overview}
25	\end{figure*}
26	
27	We evaluate five signals from three families (structural, surface, and model-internal) on SciERC \cite{luan2018scierc} as a primary medium-difficulty test bed, with Few-NERD \cite{ding2021fewnerd} (low-degeneracy contrast), CoNLL-2003 \cite{tjongkimsang2003conll} (ceiling-effect control), and WNUT-17 \cite{derczynski2017wnut} (signal-collapse boundary), using two 8B models (Qwen3-8B, LLaMA-3.1-8B) with a 4B ablation (Qwen3-4B).
28	We vary candidate pool size ($N{\in}\{2,\ldots,32\}$), signal sophistication, and model capacity within the 4B\textendash 8B range; behavior at 70B+ scales remains an open question.
29	An exploratory extension to relation extraction is reported in Appendix~\ref{app:re_extension}.
30	Our contributions:
31	\begin{enumerate}
32	    \item \textbf{Quality estimation framework and selective prediction.}
33	    Five signals from three families evaluated on four NER benchmarks, two model families, and a 4B ablation, achieving reliable quality estimation ($\rho$ up to 0.45, AUROC up to 0.82).
34	    QE enables selective prediction: filtering low-confidence instances at 80\% coverage yields $+5$--$8$\,pp F1 (area under the precision-recall curve [AUPRC] 0.70--0.92, VC strongest; \S\ref{sec:prescriptive}).
35	
36	    \item \textbf{Diagnostic of the correlation-selection gap.}
37	    For fine-tuned 4B--8B models, LP-quality alignment (within-instance $\rho(\text{LP}, \text{F1})$) is the primary predictor of selection success: LP achieves $+1.39$~pp on Few-NERD ($p{<}0.001$) where alignment is strong, but not on benchmarks with weak alignment.
38	    Instance degeneracy causally modulates LP within fixed settings (epoch and temperature ablations), but does not predict cross-dataset direction ($\rho{=}0.052$, 23 configurations); structural signals fail by construction; supervised combinations and hidden state probes (Appendix~\ref{app:hidden_probe}) confirm the gap persists.
39	
40	    \item \textbf{Entity-level construction as a diagnostic-motivated mitigation.}
41	    The diagnostic naturally motivates entity-level aggregation, adapting entity voting from ensemble NER \cite{florian2003named} to stochastic sampling: LP-weighted construction yields $+1.40$\,pp on Few-NERD and $+1.02$\,pp on SciERC (multi-seed mean, $p{<}0.005$; \S\ref{sec:prescriptive}).
42	    Construction and LP selection are complementary on two informative datasets, governed by LP-quality alignment; a simple alignment-based gating protocol correctly routes datasets.
43	\end{enumerate}
44	
45	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "757e7cb7-1ed0-4a8a-978a-1ad3f76a12c3",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/introduction.tex",
      "content": "\\section{Introduction}\\label{sec:introduction}\n\nSelf-consistency (majority voting over multiple samples) yields large gains on discrete-answer reasoning \\citep{wang2023selfconsistency}, and test-time compute scaling has emerged as a complementary axis to model scaling \\cite{snell2025scaling, brown2024monkeys}.\nBut named entity recognition (NER) poses a structurally different challenge: the output is a \\textit{set} of entities, two samples may extract overlapping but non-identical sets, and there is no obvious majority to vote on.\n\nPrior work on confidence estimation for LLM-based IE has conflated \\textit{quality estimation} (which inputs does the model handle reliably?) with \\textit{sample selection} (which of $N$ outputs is best?).\nExisting self-consistency methods \\cite{wang2023selfconsistency, chen2024usc, taubenfeld2025cisc, kang2025selfcertainty} assume outputs can be grouped by equivalence, an assumption that breaks for entity sets with partial overlap.\nUnlike \\citet{yao2026consistency}, who demonstrate that self-consistency correlates with task accuracy, we provide the first systematic empirical characterization of \\textit{when and why} LP-based selection succeeds or fails for structured prediction, diagnosing degeneracy and compression as the two blocking mechanisms.\nOur experiments use fine-tuned models, the dominant deployment paradigm for production NER, and separate quality estimation from best-of-$N$ selection.\n\nA key distinction structures our analysis: four of five signals (Soft Jaccard, voting confidence, Fleiss' $\\kappa$, exact match) are instance-level aggregates that assign identical scores to all $N$ candidates for a given input; only log-probability (LP) is natively per-sample.\nAll signals achieve reliable quality estimation ($\\rho$ up to 0.45, AUROC up to 0.82; Figure~\\ref{fig:overview}), supporting selective prediction.\nFor selection, LP achieves $+1.39$~pp on Few-NERD ($p{<}0.001$) in settings where both low instance degeneracy and adequate alignment are present, with gains scaling with $N$.\nOn SciERC, the observed LP gain ($+0.2$~pp, $p{=}0.29$) falls below the minimum detectable effect (${\\approx}$1.5~pp at 80\\% power, $n{=}529$) despite 13~pp oracle headroom. We term this disparity between quality estimation strength and selection effectiveness the \\textbf{correlation-selection gap}.\nThree factors qualitatively shape this gap: (a)~\\textit{instance degeneracy} (13\\textendash 87\\% across our benchmarks) compresses the candidate space; (b)~\\textit{oracle headroom} bounds the achievable gain; (c)~\\textit{LP-quality alignment} (within-instance $\\rho(\\text{LP}, \\text{F1})$) determines whether LP can discriminate candidates in non-degenerate instances (\\S\\ref{sec:selection_gap}).\nOur diagnosis is complementary to minimum Bayes risk (MBR) utility misalignment \\cite{eikema2025structured}: where MBR failures in structured prediction stem from poorly chosen utility functions, we find that degeneracy eliminates candidate diversity before utility alignment matters.\nWithin non-degenerate instances, MBR utility correlates positively with F1 ($\\rho{=}0.52$; \\S\\ref{sec:discussion}).\nBoth mechanisms intensify with model capability: degeneracy rises with scale and training convergence (\\S\\ref{sec:discussion}). This creates a tension between model quality and test-time improvability.\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_overview}\n\\caption{Overview of the correlation-selection gap and its mitigation. \\textbf{Left}: consistency signals reliably estimate instance-level quality ($\\rho$ up to 0.45 on CoNLL; Table~\\ref{tab:quality_estimation}). \\textbf{Center}: instance-level signals assign identical scores to all samples from the same input, so best-of-$N$ selection cannot outperform greedy. \\textbf{Right}: entity-level construction aggregates entities across samples via majority vote ($\\theta{=}2/N$), bypassing the selection bottleneck ($+1.40$\\,pp on Few-NERD, multi-seed mean; \\S\\ref{sec:prescriptive}).}\n\\label{fig:overview}\n\\end{figure*}\n\nWe evaluate five signals from three families (structural, surface, and model-internal) on SciERC \\cite{luan2018scierc} as a primary medium-difficulty test bed, with Few-NERD \\cite{ding2021fewnerd} (low-degeneracy contrast), CoNLL-2003 \\cite{tjongkimsang2003conll} (ceiling-effect control), and WNUT-17 \\cite{derczynski2017wnut} (signal-collapse boundary), using two 8B models (Qwen3-8B, LLaMA-3.1-8B) with a 4B ablation (Qwen3-4B).\nWe vary candidate pool size ($N{\\in}\\{2,\\ldots,32\\}$), signal sophistication, and model capacity within the 4B\\textendash 8B range; behavior at 70B+ scales remains an open question.\nAn exploratory extension to relation extraction is reported in Appendix~\\ref{app:re_extension}.\nOur contributions:\n\\begin{enumerate}\n    \\item \\textbf{Quality estimation framework and selective prediction.}\n    Five signals from three families evaluated on four NER benchmarks, two model families, and a 4B ablation, achieving reliable quality estimation ($\\rho$ up to 0.45, AUROC up to 0.82).\n    QE enables selective prediction: filtering low-confidence instances at 80\\% coverage yields $+5$--$8$\\,pp F1 (area under the precision-recall curve [AUPRC] 0.70--0.92, VC strongest; \\S\\ref{sec:prescriptive}).\n\n    \\item \\textbf{Diagnostic of the correlation-selection gap.}\n    For fine-tuned 4B--8B models, LP-quality alignment (within-instance $\\rho(\\text{LP}, \\text{F1})$) is the primary predictor of selection success: LP achieves $+1.39$~pp on Few-NERD ($p{<}0.001$) where alignment is strong, but not on benchmarks with weak alignment.\n    Instance degeneracy causally modulates LP within fixed settings (epoch and temperature ablations), but does not predict cross-dataset direction ($\\rho{=}0.052$, 23 configurations); structural signals fail by construction; supervised combinations and hidden state probes (Appendix~\\ref{app:hidden_probe}) confirm the gap persists.\n\n    \\item \\textbf{Entity-level construction as a diagnostic-motivated mitigation.}\n    The diagnostic naturally motivates entity-level aggregation, adapting entity voting from ensemble NER \\cite{florian2003named} to stochastic sampling: LP-weighted construction yields $+1.40$\\,pp on Few-NERD and $+1.02$\\,pp on SciERC (multi-seed mean, $p{<}0.005$; \\S\\ref{sec:prescriptive}).\n    Construction and LP selection are complementary on two informative datasets, governed by LP-quality alignment; a simple alignment-based gating protocol correctly routes datasets.\n\\end{enumerate}\n\n",
      "numLines": 45,
      "startLine": 1,
      "totalLines": 45
    }
  }
}
```

</details>

---


### Tool call

_source line 28_

<details open><summary>🔧 Tool call — Read · `toolu_017S9qfFUGAeX1PpYT8Tig9D`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "9edefe3e-ff23-4a32-af73-124319bc0653",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Aqkjj9hxgV8pX4f8kaENzc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1290,
      "cache_read_input_tokens": 38900,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1290
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

_source line 29 · 2026-05-19T13:33:49.805Z_

<details><summary>↩ Tool result · `toolu_017S9qfFUGAeX1PpYT8Tig9D`</summary>

```text
1	\section{Method}\label{sec:method}
2	
3	\subsection{Problem Formulation}\label{sec:formulation}
4	
5	Given model $\mathcal{M}$ and input $x$, we sample $N$ outputs $\{y_1, \ldots, y_N\}$ at temperature $T > 0$ via constrained decoding \cite{willard2023guided}, where each $y_i$ is an entity set.
6	A \textbf{per-sample signal} $c_{\text{ps}}: (x, y_i) \to \mathbb{R}$ scores each output independently; an \textbf{instance-level signal} $c_{\text{il}}: (x, \{y_i\}_{i=1}^N) \to \mathbb{R}$ produces a single score per input (notation in Appendix~\ref{app:notation}).
7	This distinction is consequential for selection: in our study, 4 of 5 signals are instance-level aggregates that assign identical QE scores to all $N$ candidates. Consensus-proximity (MBR) converts these to per-sample rankings (\S\ref{sec:selection_gap}), but these rankings do not improve selection; only natively per-sample signals can, in principle, exploit oracle headroom.
8	
9	\subsection{Confidence Signals}\label{sec:signals}
10	
11	Throughout, entity matching uses exact span and type match (a predicted entity is correct iff its character offsets and type label both match a gold entity).
12	Four are \textit{consistency signals}: \textit{structural} (Soft Jaccard [SJ], entity voting confidence [VC]) and \textit{surface} (exact match [EM], Fleiss' $\kappa$ [FK]); log-probability [LP] is the sole \textit{model-internal}, per-sample signal.
13	
14	\paragraph{Log-probability (model-internal, per-sample).}
15	For sample $y_i$ with tokens $t_1, \ldots, t_{|y_i|}$:
16	\begin{equation}\label{eq:logprob}
17	c_{\text{lp}}(y_i) = \frac{1}{|y_i|} \sum_{j=1}^{|y_i|} \log p_{\mathcal{M}}(t_j \mid t_{&lt;j}, x)
18	\end{equation}
19	
20	\paragraph{Exact match voting (surface, instance-level).}
21	The proportion of samples producing the most common output:
22	\begin{equation}\label{eq:em}
23	c_{\text{em}}(x) = \frac{1}{N} \max_{y} \big|\{i : y_i = y\}\big|
24	\end{equation}
25	
26	\paragraph{Fleiss' $\kappa$ (surface, instance-level).}
27	We adapt \citet{fleiss1971agreement} to entity sets: items are unique (text, type) tuples across all $N$ samples; each sample assigns binary present/absent labels, yielding a $|E_\cup| \times 2$ rating matrix:
28	\begin{equation}\label{eq:fk}
29	\kappa = \frac{\bar{P} - \bar{P}_e}{1 - \bar{P}_e}
30	\end{equation}
31	where $\bar{P}$ is mean observed and $\bar{P}_e$ expected agreement.
32	Temperature-based sampling introduces mild negative dependence ($-$0.4\% to $-$4.0\%; Appendix~\ref{app:fk_independence}), which does not inflate FK.
33	Unlike structural signals, FK relies on exact string matching.
34	
35	\paragraph{Soft Jaccard (structural, instance-level).}
36	For samples $y_i, y_j$, we group extractions by type, compute max-weight bipartite matching (Hungarian algorithm, token-level IoU), and define:
37	\begin{equation}\label{eq:sj}
38	\text{SJ}(y_i, y_j) = \frac{\sum_{m \in M} \text{sim}(a_m, b_m)}{\sum_{g} \max(|g_i|, |g_j|)}
39	\end{equation}
40	where $M$ is the matched set, $\text{sim}(a_m, b_m)$ is the token-level IoU, and $\max(|g_i|, |g_j|)$ penalizes length asymmetry.\footnote{The two normalizer variants produce nearly identical rankings ($|\Delta\rho|{\leq}0.009$; Table~\ref{tab:sj_normalizer}).}
41	The instance-level QE signal averages over all pairs: $c_{\text{sj}}(x) = \binom{N}{2}^{-1} \sum_{i&lt;j} \text{SJ}(y_i, y_j)$.\footnote{When $E_\cup = \emptyset$, SJ is defined as 1 (perfect agreement on empty output).}
42	For selection, consensus-proximity converts this to per-sample utility $u_{\text{sj}}(y_i) = (N{-}1)^{-1} \sum_{j \neq i} \text{SJ}(y_i, y_j)$, equivalent to MBR decoding \cite{eikema2022sampling}. The same construction applies to FK, EM, and VC.
43	
44	\paragraph{Entity voting confidence (structural, instance-level).}
45	For each entity $e$ in the union $E_\cup$ of all samples, we compute frequency $\text{freq}(e) = |\{i : e \in y_i\}| / N$.
46	The instance-level confidence is the mean frequency:
47	\begin{equation}\label{eq:voting}
48	c_{\text{vote}}(x) = \frac{1}{|E_\cup|} \sum_{e \in E_\cup} \text{freq}(e)
49	\end{equation}
50	When $E_\cup = \emptyset$, $c_{\mathrm{vc}}(x) = 0$.\footnote{For voted-output \textit{selection}, we include only entities with frequency ${>}N/2$ (standard majority voting).}
51	
52	\subsection{Evaluation Framework}\label{sec:evaluation}
53	
54	\paragraph{Quality estimation.}
55	Spearman $\rho$ between the signal and instance-level F1 (per-instance entity-level F1 counting exact span-and-type matches), and AUROC classifying instances as above/below median F1.
56	Both quality estimation and selection exclude instances with no gold annotations: $n{=}529$ on SciERC (from 551), $n{=}2{,}756$ on CoNLL (from 3{,}453).\footnote{On CoNLL, full-set ($n{=}3{,}453$) Spearman $\rho$ values are higher than gold-filtered ($n{=}2{,}756$) by $+0.03$--$0.05$ due to the zero/non-zero boundary inflating correlations, paralleling the effect documented for WNUT-17 in Appendix~\ref{app:additional}.}
57	
58	\paragraph{Sample selection.}
59	Best-of-$N$ F1: per-sample signals (LP) directly rank candidates; instance-level signals rank via consensus-proximity (MBR utility; see SJ definition above).
60	Baselines: \textit{oracle} (highest-F1 sample) and \textit{greedy} ($T{=}0$ argmax decoding).
61	We define \textbf{instance degeneracy} as the fraction of instances where all $N$ samples yield identical F1;\footnote{``Identical F1'' means constant F1 across all $N$ samples for a given instance, not necessarily F1${=}1.0$. Samples may differ in surface form but produce the same entity set and thus the same score.} for these instances, no signal can improve selection.
62	We report F1 under the protocol matching each experiment's configuration (seed, epoch, $N$). SciERC greedy F1 appears as four values across tables (0.640, 0.644, 0.645, 0.650) due to protocol variants: primary seed vs.\ multi-seed mean, 5-epoch vs.\ 3-epoch checkpoint, and gold-filtered vs.\ full test set. Each table specifies its protocol.
63	
64	%% Prescriptive framework content is in Discussion §5 (sec:selection_method label there)
65	%% to stay within 8-page main body limit
66	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "4f3ae154-f17e-47c0-af0c-1255762f965d",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/method.tex",
      "content": "\\section{Method}\\label{sec:method}\n\n\\subsection{Problem Formulation}\\label{sec:formulation}\n\nGiven model $\\mathcal{M}$ and input $x$, we sample $N$ outputs $\\{y_1, \\ldots, y_N\\}$ at temperature $T > 0$ via constrained decoding \\cite{willard2023guided}, where each $y_i$ is an entity set.\nA \\textbf{per-sample signal} $c_{\\text{ps}}: (x, y_i) \\to \\mathbb{R}$ scores each output independently; an \\textbf{instance-level signal} $c_{\\text{il}}: (x, \\{y_i\\}_{i=1}^N) \\to \\mathbb{R}$ produces a single score per input (notation in Appendix~\\ref{app:notation}).\nThis distinction is consequential for selection: in our study, 4 of 5 signals are instance-level aggregates that assign identical QE scores to all $N$ candidates. Consensus-proximity (MBR) converts these to per-sample rankings (\\S\\ref{sec:selection_gap}), but these rankings do not improve selection; only natively per-sample signals can, in principle, exploit oracle headroom.\n\n\\subsection{Confidence Signals}\\label{sec:signals}\n\nThroughout, entity matching uses exact span and type match (a predicted entity is correct iff its character offsets and type label both match a gold entity).\nFour are \\textit{consistency signals}: \\textit{structural} (Soft Jaccard [SJ], entity voting confidence [VC]) and \\textit{surface} (exact match [EM], Fleiss' $\\kappa$ [FK]); log-probability [LP] is the sole \\textit{model-internal}, per-sample signal.\n\n\\paragraph{Log-probability (model-internal, per-sample).}\nFor sample $y_i$ with tokens $t_1, \\ldots, t_{|y_i|}$:\n\\begin{equation}\\label{eq:logprob}\nc_{\\text{lp}}(y_i) = \\frac{1}{|y_i|} \\sum_{j=1}^{|y_i|} \\log p_{\\mathcal{M}}(t_j \\mid t_{&lt;j}, x)\n\\end{equation}\n\n\\paragraph{Exact match voting (surface, instance-level).}\nThe proportion of samples producing the most common output:\n\\begin{equation}\\label{eq:em}\nc_{\\text{em}}(x) = \\frac{1}{N} \\max_{y} \\big|\\{i : y_i = y\\}\\big|\n\\end{equation}\n\n\\paragraph{Fleiss' $\\kappa$ (surface, instance-level).}\nWe adapt \\citet{fleiss1971agreement} to entity sets: items are unique (text, type) tuples across all $N$ samples; each sample assigns binary present/absent labels, yielding a $|E_\\cup| \\times 2$ rating matrix:\n\\begin{equation}\\label{eq:fk}\n\\kappa = \\frac{\\bar{P} - \\bar{P}_e}{1 - \\bar{P}_e}\n\\end{equation}\nwhere $\\bar{P}$ is mean observed and $\\bar{P}_e$ expected agreement.\nTemperature-based sampling introduces mild negative dependence ($-$0.4\\% to $-$4.0\\%; Appendix~\\ref{app:fk_independence}), which does not inflate FK.\nUnlike structural signals, FK relies on exact string matching.\n\n\\paragraph{Soft Jaccard (structural, instance-level).}\nFor samples $y_i, y_j$, we group extractions by type, compute max-weight bipartite matching (Hungarian algorithm, token-level IoU), and define:\n\\begin{equation}\\label{eq:sj}\n\\text{SJ}(y_i, y_j) = \\frac{\\sum_{m \\in M} \\text{sim}(a_m, b_m)}{\\sum_{g} \\max(|g_i|, |g_j|)}\n\\end{equation}\nwhere $M$ is the matched set, $\\text{sim}(a_m, b_m)$ is the token-level IoU, and $\\max(|g_i|, |g_j|)$ penalizes length asymmetry.\\footnote{The two normalizer variants produce nearly identical rankings ($|\\Delta\\rho|{\\leq}0.009$; Table~\\ref{tab:sj_normalizer}).}\nThe instance-level QE signal averages over all pairs: $c_{\\text{sj}}(x) = \\binom{N}{2}^{-1} \\sum_{i&lt;j} \\text{SJ}(y_i, y_j)$.\\footnote{When $E_\\cup = \\emptyset$, SJ is defined as 1 (perfect agreement on empty output).}\nFor selection, consensus-proximity converts this to per-sample utility $u_{\\text{sj}}(y_i) = (N{-}1)^{-1} \\sum_{j \\neq i} \\text{SJ}(y_i, y_j)$, equivalent to MBR decoding \\cite{eikema2022sampling}. The same construction applies to FK, EM, and VC.\n\n\\paragraph{Entity voting confidence (structural, instance-level).}\nFor each entity $e$ in the union $E_\\cup$ of all samples, we compute frequency $\\text{freq}(e) = |\\{i : e \\in y_i\\}| / N$.\nThe instance-level confidence is the mean frequency:\n\\begin{equation}\\label{eq:voting}\nc_{\\text{vote}}(x) = \\frac{1}{|E_\\cup|} \\sum_{e \\in E_\\cup} \\text{freq}(e)\n\\end{equation}\nWhen $E_\\cup = \\emptyset$, $c_{\\mathrm{vc}}(x) = 0$.\\footnote{For voted-output \\textit{selection}, we include only entities with frequency ${>}N/2$ (standard majority voting).}\n\n\\subsection{Evaluation Framework}\\label{sec:evaluation}\n\n\\paragraph{Quality estimation.}\nSpearman $\\rho$ between the signal and instance-level F1 (per-instance entity-level F1 counting exact span-and-type matches), and AUROC classifying instances as above/below median F1.\nBoth quality estimation and selection exclude instances with no gold annotations: $n{=}529$ on SciERC (from 551), $n{=}2{,}756$ on CoNLL (from 3{,}453).\\footnote{On CoNLL, full-set ($n{=}3{,}453$) Spearman $\\rho$ values are higher than gold-filtered ($n{=}2{,}756$) by $+0.03$--$0.05$ due to the zero/non-zero boundary inflating correlations, paralleling the effect documented for WNUT-17 in Appendix~\\ref{app:additional}.}\n\n\\paragraph{Sample selection.}\nBest-of-$N$ F1: per-sample signals (LP) directly rank candidates; instance-level signals rank via consensus-proximity (MBR utility; see SJ definition above).\nBaselines: \\textit{oracle} (highest-F1 sample) and \\textit{greedy} ($T{=}0$ argmax decoding).\nWe define \\textbf{instance degeneracy} as the fraction of instances where all $N$ samples yield identical F1;\\footnote{``Identical F1'' means constant F1 across all $N$ samples for a given instance, not necessarily F1${=}1.0$. Samples may differ in surface form but produce the same entity set and thus the same score.} for these instances, no signal can improve selection.\nWe report F1 under the protocol matching each experiment's configuration (seed, epoch, $N$). SciERC greedy F1 appears as four values across tables (0.640, 0.644, 0.645, 0.650) due to protocol variants: primary seed vs.\\ multi-seed mean, 5-epoch vs.\\ 3-epoch checkpoint, and gold-filtered vs.\\ full test set. Each table specifies its protocol.\n\n%% Prescriptive framework content is in Discussion §5 (sec:selection_method label there)\n%% to stay within 8-page main body limit\n",
      "numLines": 66,
      "startLine": 1,
      "totalLines": 66
    }
  }
}
```

</details>

---


### Tool call

_source line 30_

<details open><summary>🔧 Tool call — Read · `toolu_012tdT3PzozFA1FwL2N2G5Xr`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "c7eabdd1-ae84-4c12-8d21-55066f03d110",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Aqkjj9hxgV8pX4f8kaENzc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1290,
      "cache_read_input_tokens": 38900,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1290
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

_source line 31 · 2026-05-19T13:33:50.334Z_

<details><summary>↩ Tool result · `toolu_012tdT3PzozFA1FwL2N2G5Xr`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	\subsection{Experimental Setup}
5	\label{sec:setup}
6	
7	\paragraph{Datasets.}
8	We evaluate on four English NER benchmarks spanning a difficulty gradient, each serving a distinct role.
9	\textbf{SciERC} \cite{luan2018scierc} (551 test instances, 6 entity types) is the primary medium-difficulty test bed where models achieve ${\approx}$65\% F1.
10	\textbf{Few-NERD} \cite{ding2021fewnerd} (INTRA coarse; 37{,}648 instances, 8 entity types, ${\approx}$75\% F1) provides a low-degeneracy contrast where LP selection succeeds (\S\ref{sec:fewnerd}).
11	\textbf{CoNLL-2003} \cite{tjongkimsang2003conll} (3{,}453 test sentences, 4 entity types, ${\approx}$91\% F1) serves as a ceiling-effect control where limited oracle headroom constrains selection gains.
12	\textbf{WNUT-17} \cite{derczynski2017wnut} (1{,}287 social media instances, 52\% zero F1) probes the signal-collapse boundary where model capability is insufficient.
13	
14	\paragraph{Models and sampling.}
15	\textbf{Qwen3-8B} and \textbf{LLaMA-3.1-8B-Instruct} are LoRA fine-tuned using LLaMA Factory \cite{zheng2024llamafactory} (training details in Appendix~\ref{app:training}; Few-NERD uses 3 epochs vs.\ 5 for others due to earlier convergence; Appendix~\ref{app:epoch_confound}).
16	We draw $N{=}8$ samples at $T{=}1.0$ (primary) with vLLM constrained decoding \cite{willard2023guided}, with $N{=}16$ for scaling experiments (Appendix~\ref{app:n_scaling}).
17	
18	%% ============================================================
19	\subsection{Quality Estimation Results}
20	\label{sec:qe_results}
21	
22	\begin{table*}[t]
23	\centering
24	\small
25	\caption{NER quality estimation ($\rho$ and AUROC; $N{=}8$, primary seed${=}42$; 3-seed stability $\sigma{\leq}0.026$ in Table~\ref{tab:multiseed}). Best in \textbf{bold}. RE results in Appendix~\ref{app:re_extension}. $N{=}16$ in Table~\ref{tab:robustness}.}
26	\label{tab:quality_estimation}
27	\begin{tabular}{ll cc cc cc}
28	\toprule
29	& & \multicolumn{2}{c}{\textbf{SciERC}} & \multicolumn{2}{c}{\textbf{CoNLL (Qwen)}} & \multicolumn{2}{c}{\textbf{CoNLL (LLaMA)}} \\
30	\cmidrule(lr){3-4} \cmidrule(lr){5-6} \cmidrule(lr){7-8}
31	Signal & Family & $\rho$ & AUC & $\rho$ & AUC & $\rho$ & AUC \\
32	\midrule
33	VC & Structural & \textbf{.379} & \textbf{.663} & .424 & .789 & .426 & .709 \\
34	SJ  & Structural & .360 & .650 & .436 & .801 & \textbf{.431} & .704 \\
35	FK & Surface & .267 & .602 & .400 & .774 & .428 & .703 \\
36	EM  & Surface    & .295 & .614 & \textbf{.451} & \textbf{.816} & \textbf{.431} & .705 \\
37	\midrule
38	LP     & Model      & .205 & .578 & .316 & .753 & .307 & \textbf{.761} \\
39	\bottomrule
40	\end{tabular}
41	\end{table*}
42	
43	Table~\ref{tab:quality_estimation} presents $\rho$ and AUROC for five signals across tasks and models ($\varepsilon$-free; $\varepsilon{=}0.05$ applies to selection only, stable across $[0, 0.2]$, Appendix~\ref{app:epsilon_robustness}).
44	
45	\paragraph{Signal rankings are difficulty-dependent.}
46	On SciERC (medium difficulty), structural signals lead (VC $\rho{=}0.379$, SJ $0.360$) over LP ($0.205$); bootstrap CIs confirm the gap ($\Delta\rho{=}{+}0.155$; Appendix~\ref{app:bootstrap_signal}).
47	On CoNLL (single-sample F1${\approx}$0.91), EM leads both $\rho$ and AUROC ($0.816$).
48	At the signal-collapse boundary (WNUT-17, macro F1${\approx}$42\%), full-set correlations are dominated by the zero/non-zero boundary (VC $\rho{=}0.724$ but conditional $\rho{=}0.038$; Table~\ref{tab:wnut}); LP shows the reverse (conditional $\rho{=}0.350$; Figure~\ref{fig:signal_heatmap}).
49	This collapse illustrates a regime where model capability is insufficient to produce meaningful inter-sample variation: 52\% of instances yield zero F1 across all samples, and consistency signals merely detect this floor rather than discriminating quality among non-trivial outputs.
50	
51	%% ============================================================
52	\subsection{The Correlation-Selection Gap}
53	\label{sec:selection_gap}
54	
55	Four of five signals (SJ, FK, EM, VC) assign identical scores to all candidates from the same input by construction (\S\ref{sec:formulation}); they can estimate quality across instances but cannot rank candidates within an instance.
56	The empirical question is whether LP, the sole per-sample signal, can exploit its candidate-discriminative nature for selection.
57	LP selection effectiveness is primarily determined by LP-quality alignment rather than degeneracy level (\S\ref{sec:discussion}).
58	Cross-instance $\rho$ (Table~\ref{tab:quality_estimation}) is attenuated by varying instance difficulty; within-instance $\rho$ directly measures whether LP discriminates candidates for a fixed input, making it the relevant predictor of selection success.
59	
60	\begin{table}[t]
61	\centering
62	\small
63	\caption{Best-of-$N$ NER selection (macro F1) on SciERC ($N{=}8$, $T{=}1.0$, 2-seed mean${\pm}\sigma$). LP is per-sample; others use consensus-proximity. Best non-oracle in \textbf{bold}. Non-tied subset in \S\ref{sec:discussion}; RE in Appendix~\ref{app:re_extension}. $^\dagger$Instance-level signals assign one score per input; per-sample ranking $p$-values are undefined.}
64	\label{tab:selection}
65	\begin{tabular}{lcc}
66	\toprule
67	Method & NER F1 & $p$ \\
68	\midrule
69	Oracle & $0.775 \pm 0.001$ & --- \\
70	Greedy ($T{=}0$) & $0.645 \pm 0.001$ & --- \\
71	\midrule
72	\multicolumn{3}{l}{\textit{Per-sample signal}} \\
73	LP           & $\mathbf{0.647} \pm 0.005$ & .29 \\
74	\midrule
75	\multicolumn{3}{l}{\textit{Instance-level signals (consensus-proximity selection)}} \\
76	SJ           & $0.646 \pm 0.002$ & .67 \\
77	FK           & $0.646 \pm 0.001$ & .79 \\
78	EM           & $0.637 \pm 0.001$ & n/a$^\dagger$ \\
79	VC           & $0.623 \pm 0.004$ & n/a$^\dagger$ \\
80	\midrule
81	Random           & $0.610 \pm 0.003$ & --- \\
82	\bottomrule
83	\end{tabular}
84	\end{table}
85	
86	\begin{figure}[t]
87	\centering
88	\includegraphics[width=\columnwidth]{fig_selection_gap}
89	\caption{The correlation-selection gap on SciERC ($N{=}8$, $T{=}1.0$). Bars: quality estimation $\rho$ (seed 42); line with error bars: $\Delta$F1 vs.\ greedy (3-seed mean, seeds 42/123/456). Despite $\rho$ up to 0.38, no signal significantly outperforms greedy (all $p{>}0.05$; Table~\ref{tab:selection}). Dashed green: oracle upper bound ($+13.1$~pp); dotted gray: random baseline.}
90	\label{fig:selection_gap}
91	\end{figure}
92	
93	Instance-level signals assign identical QE scores to all candidates; MBR conversion does not improve over greedy on the primary test bed (Table~\ref{tab:selection}; Figure~\ref{fig:selection_gap}).
94	Instance-level signals predict \textit{which inputs} the model handles reliably, not \textit{which output} is best.
95	
96	\paragraph{LP: the sole per-sample signal also fails.}
97	On SciERC ($n{=}529$, 2-seed sign tests\footnote{MDE${\approx}$1.5~pp at 80\% power ($n{=}529$); Few-NERD ($n{=}32{,}565$; MDE${\approx}$0.22~pp) provides the definitive test.}), the oracle (0.775) reveals 13.0~pp of headroom, but LP achieves $+0.2$~pp ($p{=}0.29$), below the MDE (${\approx}$1.5~pp); selection effects below this threshold cannot be reliably detected.
98	The pattern holds across CoNLL and WNUT-17 (Table~\ref{tab:cross_selection}); under stringent TOST anchors, some configurations show significant \textit{degradation} (Appendix~\ref{app:tost}).
99	Few-NERD provides the definitive contrast: LP achieves $+1.39$~pp ($p{<}0.001$) at low degeneracy (\S\ref{sec:fewnerd}), while structural signals still degrade selection.
100	
101	\paragraph{Qualitative factors governing selection effectiveness.}
102	Three factors qualitatively shape LP selection gains: (1)~\textit{instance degeneracy} compresses the candidate space, leaving fewer instances where any signal can improve over greedy (SciERC 17.8\%, CoNLL 48.4\%; Table~\ref{tab:fewnerd}); (2)~\textit{oracle headroom} bounds the maximum achievable gain (CoNLL ${\approx}2$\,pp vs.\ SciERC 13.1\,pp); (3)~\textit{LP-quality alignment}, measured as within-instance $\rho(\text{LP}, \text{F1})$, determines whether LP can discriminate candidates in the remaining non-degenerate instances (Few-NERD $\rho{\approx}0.5$--$0.7$ vs.\ SciERC $\rho{\approx}0.26$).
103	These factors are consistent with the observed pattern (Table~\ref{tab:fewnerd}): Few-NERD (low degeneracy, strong alignment) shows the largest LP gain ($+1.39$\,pp), SciERC (weak alignment) shows unreliable gains ($+0.04{\pm}0.48$\,pp, 3-seed; Table~\ref{tab:multiseed}), CoNLL (high degeneracy, minimal headroom) shows no gain, and WNUT-17 represents the signal-collapse boundary: LP $\rho{=}{-}0.446$ (the model assigns higher log-probabilities to confidently wrong outputs), within-instance alignment absent ($\rho{=}0.043$, n.s.), and construction ineffective ($p{>}0.05$, mixed sign) because 51\% of instances yield F1${=}0$.
104	Yet QE remains effective on WNUT-17 (VC $\rho{=}0.730$; Table~\ref{tab:wnut}), confirming QE-selection decoupling at this boundary.
105	This characterization is qualitative: the three factors do not combine into a predictive model ($R^2{<}0$ across 23 configurations), but each factor's role is individually supported by controlled ablations (\S\ref{sec:fewnerd}, \S\ref{sec:discussion}).
106	
107	%% ============================================================
108	\subsection{Cross-Dataset Contrast: Few-NERD}
109	\label{sec:fewnerd}
110	
111	\begin{table}[t]
112	\centering
113	\small
114	\caption{LP selection across datasets (Qwen3-8B, $N{=}8$, $T{=}1.0$, gold-filtered). Few-NERD/CoNLL: 3-seed means; SciERC: single-seed (3-seed in Table~\ref{tab:multiseed}). $p$: paired bootstrap.}
115	\label{tab:fewnerd}
116	\resizebox{\columnwidth}{!}{%
117	\begin{tabular}{@{}lrccccr@{}}
118	\toprule
119	Dataset & $n$ & Greedy & Degen.\% & LP $\rho$ & LP $\Delta$ & $p$ \\
120	\midrule
121	WNUT-17 & 1{,}287 & .452 & 67.9\% & $-$.446 & $-$0.45\,pp & .72 \\
122	CoNLL & 2{,}756 & .908 & 48.4\% & .302 & $-$0.85\,pp & 1.0 \\
123	SciERC & 529 & .644 & 17.8\% & .205 & $+$0.61\,pp & .193 \\
124	Few-NERD & 32{,}565 & .748 & 13.8\% & .220 & $\mathbf{+1.39}$\,pp & ${<}.001$ \\
125	\bottomrule
126	\end{tabular}}
127	\end{table}
128	
129	Few-NERD (Table~\ref{tab:fewnerd}) confirms LP selection at low degeneracy: $+1.39$~pp ($p{<}0.001$), while structural signals degrade selection (VC $-1.79$, SJ $-2.14$~pp). LP is 50$\times$ more seed-stable ($\sigma{=}0.04$ vs.\ SJ $2.02$~pp) and generalizes to LLaMA-3.1-8B (Table~\ref{tab:cross_selection}).
130	Training convergence modulates degeneracy: 5-epoch Few-NERD raises degeneracy to 31\% and halves LP gains (Appendix~\ref{app:epoch_confound}).
131	
132	\paragraph{Degeneracy alone does not predict LP selection direction.}
133	Across 23 configurations, degeneracy does not predict LP gain ($\rho{=}0.052$, $p{=}0.81$; Figure~\ref{fig:degeneracy_scatter}), though within fixed settings it causally modulates LP ($\rho{=}{-}0.881$; Appendix~\ref{app:per_type_lp}).
134	Cross-dataset prediction requires LP signal quality: Few-NERD ($\rho{\approx}0.5$--$0.7$) shows consistent gains, SciERC ($\rho{\approx}0.26$) does not (Appendix~\ref{app:conditional_decomp}).
135	
136	\begin{figure}[t]
137	\centering
138	\includegraphics[width=\columnwidth]{figures/fig_degeneracy_lp_scatter.pdf}
139	\caption{Instance degeneracy vs.\ LP selection gain across 23 configurations ($N{=}8$; $\rho{=}0.052$, $p{=}0.81$). Within Few-NERD per-entity-type analysis ($\rho{=}{-}0.881$; Appendix~\ref{app:per_type_lp}), degeneracy predicts LP gain when alignment is held constant.}
140	\label{fig:degeneracy_scatter}
141	\end{figure}
142	
143	Structural signals remain negative regardless of sample budget; $N$-scaling analyses are in Appendix~\ref{app:n_scaling}.
144	
145	%% ============================================================
146	\subsection{Robustness}
147	\label{sec:robustness_main}
148	
149	Consistency signals are robust across $T{\in}\{0.7, 1.0\}$ with sublinear $N$-scaling gains (Table~\ref{tab:robustness}); signal rankings are stable across seeds ($W{=}1.0$; Table~\ref{tab:ranking-stability}). NER calibration is reasonable (ECE 0.069--0.096; Appendix~\ref{app:calibration}).
150	
151	\begin{table}[t]
152	\centering
153	\small
154	\caption{Scale ablation: 8B vs.\ 4B QE $\rho$ ($N{=}8$, $T{=}1.0$, seed 42). RE in Appendix~\ref{app:re_extension}.}
155	\label{tab:scale_ablation}
156	\begin{tabular}{@{}ll cc r@{}}
157	\toprule
158	& & \textbf{8B} & \textbf{4B} & $\Delta$ \\
159	\midrule
160	CoNLL & SJ & .436 & .422 & $-$.014 \\
161	      & FK & .400 & .418 & $+$.018 \\
162	SciERC & SJ & .360 & .422 & $+$.062 \\
163	       & FK & .267 & .326 & $+$.059 \\
164	\bottomrule
165	\end{tabular}
166	\end{table}
167	
168	\paragraph{Scale robustness.}
169	With Qwen3-4B (Table~\ref{tab:scale_ablation}), QE is comparable (mean $|\Delta\rho|{=}0.042$), yet selection remains below greedy despite 13.0~pp headroom. Task difficulty is a stronger predictor than model scale within the 3B--8B range (Appendix~\ref{app:llama3b}).
170	Degeneracy scales with capability: 8B shows 17.8\% vs.\ 4B's 10.4\% on SciERC (Table~\ref{tab:degeneracy}).
171	
172	\paragraph{LoRA-rank ablation.}
173	LoRA rank${=}8$ (vs.\ 32) lowers degeneracy to 7.2\% but LP remains below greedy ($\rho(\text{LP}, \text{F1}){\approx}0.24$); temperature manipulation ($T{=}1.2$; \S\ref{sec:discussion}) confirms that low degeneracy and adequate alignment are independently necessary.
174	
175	\paragraph{Supervised signal combination and hidden probes.}
176	Supervised classifiers (LR, MLP, RF; 5-fold CV, $N{=}16$) and a DeBERTa-v3-base verifier all fail to close the selection gap (Appendix~\ref{app:supervised_combination}).
177	Hidden state probes improve correlation ($+37$\% on SciERC) but not selection (gap closure $-5.1$\%; Appendix~\ref{app:hidden_probe}); the bottleneck extends to model-internal representations.
178	
179	%% ============================================================
180	\subsection{Scaling Behavior}
181	\label{sec:scaling}
182	
183	We evaluate Qwen2.5-72B-Instruct in a zero-shot setting to test whether the gap persists at larger scale without fine-tuning.
184	
185	\begin{table}[t]
186	\centering
187	\small
188	\caption{Fine-tuned 8B vs.\ zero-shot 72B ($N{=}8$, $T{=}1.0$). Hdr.\ = oracle $-$ greedy (pp).}
189	\label{tab:scale_comparison}
190	\begin{tabular}{@{}llcccccc@{}}
191	\toprule
192	Dataset & Regime & Greedy & Hdr. & VC & SJ & FK & LP \\
193	\midrule
194	SciERC & 8B FT  & .645 & 13.0 & .379 & .360 & .267 & .205 \\
195	       & 72B ZS & .399 & 15.0 & .277 & .217 & .227 & .081 \\
196	\midrule
197	CoNLL  & 8B FT  & .908 & ${\approx}$2 & .424 & .436 & .400 & .302 \\
198	       & 72B ZS & .712 & 5.3  & .297 & .304 & .302 & $-$.002 \\
199	\bottomrule
200	\end{tabular}
201	\end{table}
202	
203	Zero-shot 72B produces lower greedy F1 but larger oracle headroom (Table~\ref{tab:scale_comparison}). LP $\rho$ drops from $0.205$ to $0.081$ on SciERC and from $0.302$ to near zero on CoNLL; LP selection fails in both datasets (SciERC $-0.1$~pp, CoNLL $-0.4$~pp), confirming that the gap is a structural property of the task rather than a fine-tuning artifact.
204	Structural signals remain positive but reduced (VC $\rho{=}0.277$ on SciERC, SJ $\rho{=}0.304$ on CoNLL). LP-weighted construction partially compensates on SciERC ($+1.5$\,pp, 41.4\% vs.\ 39.9\% greedy) but not on CoNLL ($-0.37$\,pp), where limited headroom (5.3~pp) leaves little room for aggregation.
205	
206	\textcolor{red}{TODO: (1) Add 72B fine-tuned results to determine whether fine-tuning at larger scale recovers signal quality. (2) Report degeneracy percentages for 72B zero-shot.}
207	
208	\begin{figure}[t]
209	\centering
210	% \includegraphics[width=\columnwidth]{figures/fig_scaling_curve.pdf}
211	\textcolor{red}{TODO: Scaling curve. X-axis: model scale (4B, 8B, 72B). Panels: (a) greedy/oracle F1 and headroom, (b) signal $\rho$. Separate lines for fine-tuned vs.\ zero-shot.}
212	\caption{\textcolor{red}{TODO: Signal quality and oracle headroom across model scales.}}
213	\label{fig:scaling_curve}
214	\end{figure}
215	
216	%% ============================================================
217	\subsection{Prescriptive Results}
218	\label{sec:prescriptive}
219	
220	The preceding sections establish that instance-level selection fails for structured IE. We now present two approaches that extract value from multi-sample generation without relying on sample ranking.
221	
222	\paragraph{Entity-level construction.}
223	Rather than selecting one of $N$ complete outputs, we aggregate entities across all samples, retaining those exceeding a confirmation threshold $\theta{=}2/N$ (${\geq}2$ of $N$ samples), with LP-weighted or uniform frequency scoring. Under fine-tuning, this default achieves the best or near-best F1 across all datasets ($\theta$ stable within $[0.15, 0.35]$; Appendix~\ref{app:theta_sweep}). In the zero-shot regime, uniform voting degrades (SciERC $-0.52$\,pp, CoNLL $-0.92$\,pp) because greater output diversity admits noise entities; LP-weighting is necessary for construction to succeed without fine-tuning (SciERC $+1.5$\,pp; \S\ref{sec:scaling}).
224	
225	\begin{table}[t]
226	\centering
227	\small
228	\caption{Entity construction vs.\ greedy ($\Delta$ macro F1; $N{=}8$, $T{=}1.0$, Qwen3-8B, multi-seed mean${\pm}\sigma$). $\theta{=}2/N$. $p$: paired bootstrap vs.\ greedy. Best in \textbf{bold}.}
229	\label{tab:entity_construction}
230	\resizebox{\columnwidth}{!}{%
231	\begin{tabular}{@{}llcccc@{}}
232	\toprule
233	Dataset & Wt. & Greedy & Constr. & $\Delta$ & $p$ \\
234	\midrule
235	SciERC & LP & $.646{\pm}.002$ & $\mathbf{.656{\pm}.003}$ & $+1.02{\pm}0.49$\,pp & .004 \\
236	       & Unif. & $.646{\pm}.002$ & $.653{\pm}.006$ & $+0.74{\pm}0.71$\,pp & .023 \\
237	\addlinespace
238	Few-NERD & LP & $.748$ & $\mathbf{.762{\pm}.005}$ & $+1.40{\pm}0.51$\,pp & ${<}.001$ \\
239	         & Unif. & $.748$ & $.756{\pm}.006$ & $+0.74{\pm}0.58$\,pp & .003 \\
240	\addlinespace
241	CoNLL & Unif. & .908 & .904 & $-0.39$\,pp & n.s. \\
242	\bottomrule
243	\end{tabular}}
244	\end{table}
245	
246	LP-weighted construction improves over greedy on Few-NERD ($+1.40{\pm}0.51$\,pp, $p{<}0.001$) and SciERC ($+1.02{\pm}0.49$\,pp, $p{=}0.004$; Table~\ref{tab:entity_construction}), positive across all 7 seed-dataset combinations, recovering ${\approx}$8\% (SciERC) and 11\% (Few-NERD) of oracle headroom. CoNLL shows no gain ($-0.39$\,pp), consistent with ceiling-regime degeneracy. The mechanism is recall-driven: aggregating low-frequency correct entities recovers mentions that no single sample captures ($N$-scaling in Appendix~\ref{app:n_scaling}).
247	
248	\paragraph{LP-alignment gating (preliminary diagnostic).}
249	Construction and LP selection are complementary: construction dominates on SciERC ($+1.02$\,pp vs.\ LP $+0.04{\pm}0.48$\,pp, n.s.; $\rho{\approx}0.2$), while on Few-NERD both yield comparable gains ($+1.40$ vs.\ $+1.39$\,pp; $\rho{\approx}0.5$--$0.7$).
250	We estimate within-instance $\rho(\text{LP}, \text{F1})$ on 50 held-out instances with bootstrap CIs (1000 resamples). Degeneracy-adjusted $\rho_{\text{adj}}$: Few-NERD $0.516$ [0.459, 0.759], SciERC $0.167$ [0.146, 0.281], CoNLL $0.065$ [$-$0.061, 0.620], WNUT-17 ${\approx}0$ (n.s.).
251	The protocol performs three-way routing: (1)~$\rho_{\text{adj}} \geq \tau{=}0.3$: apply LP selection; (2)~$\rho_{\text{adj}} < \tau$ and construction shows positive dev-set gain: apply construction; (3)~otherwise: retain greedy decoding.
252	This routes Few-NERD to LP selection ($+1.39$\,pp); SciERC, CoNLL, and WNUT-17 fall below $\tau$ and route to greedy. The conservative protocol trades SciERC's missed construction gain ($+1.02$\,pp) for protection against negative outcomes (CoNLL $-0.39$\,pp, WNUT-17 n.s.).
253	Routing is stable across $\tau{\in}[0.2, 0.4]$ and matches test-set direction for all four datasets; narrower inter-dataset margins remain untested.
254	
255	\paragraph{Selective prediction.}
256	Orthogonal to construction, QE signals support selective prediction: at 80\% coverage, filtering low-confidence instances yields $+5$--$8$\,pp F1 (AUPRC 0.70--0.92; Table~\ref{tab:cross_selection}).
257	
258	\phantomsection\label{sec:selection_results}
259	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "7e904ab5-cbc9-41a6-8cb8-0b341fe0d10b",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/experiments.tex",
      "content": "\\section{Experiments}\n\\label{sec:experiments}\n\n\\subsection{Experimental Setup}\n\\label{sec:setup}\n\n\\paragraph{Datasets.}\nWe evaluate on four English NER benchmarks spanning a difficulty gradient, each serving a distinct role.\n\\textbf{SciERC} \\cite{luan2018scierc} (551 test instances, 6 entity types) is the primary medium-difficulty test bed where models achieve ${\\approx}$65\\% F1.\n\\textbf{Few-NERD} \\cite{ding2021fewnerd} (INTRA coarse; 37{,}648 instances, 8 entity types, ${\\approx}$75\\% F1) provides a low-degeneracy contrast where LP selection succeeds (\\S\\ref{sec:fewnerd}).\n\\textbf{CoNLL-2003} \\cite{tjongkimsang2003conll} (3{,}453 test sentences, 4 entity types, ${\\approx}$91\\% F1) serves as a ceiling-effect control where limited oracle headroom constrains selection gains.\n\\textbf{WNUT-17} \\cite{derczynski2017wnut} (1{,}287 social media instances, 52\\% zero F1) probes the signal-collapse boundary where model capability is insufficient.\n\n\\paragraph{Models and sampling.}\n\\textbf{Qwen3-8B} and \\textbf{LLaMA-3.1-8B-Instruct} are LoRA fine-tuned using LLaMA Factory \\cite{zheng2024llamafactory} (training details in Appendix~\\ref{app:training}; Few-NERD uses 3 epochs vs.\\ 5 for others due to earlier convergence; Appendix~\\ref{app:epoch_confound}).\nWe draw $N{=}8$ samples at $T{=}1.0$ (primary) with vLLM constrained decoding \\cite{willard2023guided}, with $N{=}16$ for scaling experiments (Appendix~\\ref{app:n_scaling}).\n\n%% ============================================================\n\\subsection{Quality Estimation Results}\n\\label{sec:qe_results}\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\caption{NER quality estimation ($\\rho$ and AUROC; $N{=}8$, primary seed${=}42$; 3-seed stability $\\sigma{\\leq}0.026$ in Table~\\ref{tab:multiseed}). Best in \\textbf{bold}. RE results in Appendix~\\ref{app:re_extension}. $N{=}16$ in Table~\\ref{tab:robustness}.}\n\\label{tab:quality_estimation}\n\\begin{tabular}{ll cc cc cc}\n\\toprule\n& & \\multicolumn{2}{c}{\\textbf{SciERC}} & \\multicolumn{2}{c}{\\textbf{CoNLL (Qwen)}} & \\multicolumn{2}{c}{\\textbf{CoNLL (LLaMA)}} \\\\\n\\cmidrule(lr){3-4} \\cmidrule(lr){5-6} \\cmidrule(lr){7-8}\nSignal & Family & $\\rho$ & AUC & $\\rho$ & AUC & $\\rho$ & AUC \\\\\n\\midrule\nVC & Structural & \\textbf{.379} & \\textbf{.663} & .424 & .789 & .426 & .709 \\\\\nSJ  & Structural & .360 & .650 & .436 & .801 & \\textbf{.431} & .704 \\\\\nFK & Surface & .267 & .602 & .400 & .774 & .428 & .703 \\\\\nEM  & Surface    & .295 & .614 & \\textbf{.451} & \\textbf{.816} & \\textbf{.431} & .705 \\\\\n\\midrule\nLP     & Model      & .205 & .578 & .316 & .753 & .307 & \\textbf{.761} \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\nTable~\\ref{tab:quality_estimation} presents $\\rho$ and AUROC for five signals across tasks and models ($\\varepsilon$-free; $\\varepsilon{=}0.05$ applies to selection only, stable across $[0, 0.2]$, Appendix~\\ref{app:epsilon_robustness}).\n\n\\paragraph{Signal rankings are difficulty-dependent.}\nOn SciERC (medium difficulty), structural signals lead (VC $\\rho{=}0.379$, SJ $0.360$) over LP ($0.205$); bootstrap CIs confirm the gap ($\\Delta\\rho{=}{+}0.155$; Appendix~\\ref{app:bootstrap_signal}).\nOn CoNLL (single-sample F1${\\approx}$0.91), EM leads both $\\rho$ and AUROC ($0.816$).\nAt the signal-collapse boundary (WNUT-17, macro F1${\\approx}$42\\%), full-set correlations are dominated by the zero/non-zero boundary (VC $\\rho{=}0.724$ but conditional $\\rho{=}0.038$; Table~\\ref{tab:wnut}); LP shows the reverse (conditional $\\rho{=}0.350$; Figure~\\ref{fig:signal_heatmap}).\nThis collapse illustrates a regime where model capability is insufficient to produce meaningful inter-sample variation: 52\\% of instances yield zero F1 across all samples, and consistency signals merely detect this floor rather than discriminating quality among non-trivial outputs.\n\n%% ============================================================\n\\subsection{The Correlation-Selection Gap}\n\\label{sec:selection_gap}\n\nFour of five signals (SJ, FK, EM, VC) assign identical scores to all candidates from the same input by construction (\\S\\ref{sec:formulation}); they can estimate quality across instances but cannot rank candidates within an instance.\nThe empirical question is whether LP, the sole per-sample signal, can exploit its candidate-discriminative nature for selection.\nLP selection effectiveness is primarily determined by LP-quality alignment rather than degeneracy level (\\S\\ref{sec:discussion}).\nCross-instance $\\rho$ (Table~\\ref{tab:quality_estimation}) is attenuated by varying instance difficulty; within-instance $\\rho$ directly measures whether LP discriminates candidates for a fixed input, making it the relevant predictor of selection success.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Best-of-$N$ NER selection (macro F1) on SciERC ($N{=}8$, $T{=}1.0$, 2-seed mean${\\pm}\\sigma$). LP is per-sample; others use consensus-proximity. Best non-oracle in \\textbf{bold}. Non-tied subset in \\S\\ref{sec:discussion}; RE in Appendix~\\ref{app:re_extension}. $^\\dagger$Instance-level signals assign one score per input; per-sample ranking $p$-values are undefined.}\n\\label{tab:selection}\n\\begin{tabular}{lcc}\n\\toprule\nMethod & NER F1 & $p$ \\\\\n\\midrule\nOracle & $0.775 \\pm 0.001$ & --- \\\\\nGreedy ($T{=}0$) & $0.645 \\pm 0.001$ & --- \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textit{Per-sample signal}} \\\\\nLP           & $\\mathbf{0.647} \\pm 0.005$ & .29 \\\\\n\\midrule\n\\multicolumn{3}{l}{\\textit{Instance-level signals (consensus-proximity selection)}} \\\\\nSJ           & $0.646 \\pm 0.002$ & .67 \\\\\nFK           & $0.646 \\pm 0.001$ & .79 \\\\\nEM           & $0.637 \\pm 0.001$ & n/a$^\\dagger$ \\\\\nVC           & $0.623 \\pm 0.004$ & n/a$^\\dagger$ \\\\\n\\midrule\nRandom           & $0.610 \\pm 0.003$ & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_selection_gap}\n\\caption{The correlation-selection gap on SciERC ($N{=}8$, $T{=}1.0$). Bars: quality estimation $\\rho$ (seed 42); line with error bars: $\\Delta$F1 vs.\\ greedy (3-seed mean, seeds 42/123/456). Despite $\\rho$ up to 0.38, no signal significantly outperforms greedy (all $p{>}0.05$; Table~\\ref{tab:selection}). Dashed green: oracle upper bound ($+13.1$~pp); dotted gray: random baseline.}\n\\label{fig:selection_gap}\n\\end{figure}\n\nInstance-level signals assign identical QE scores to all candidates; MBR conversion does not improve over greedy on the primary test bed (Table~\\ref{tab:selection}; Figure~\\ref{fig:selection_gap}).\nInstance-level signals predict \\textit{which inputs} the model handles reliably, not \\textit{which output} is best.\n\n\\paragraph{LP: the sole per-sample signal also fails.}\nOn SciERC ($n{=}529$, 2-seed sign tests\\footnote{MDE${\\approx}$1.5~pp at 80\\% power ($n{=}529$); Few-NERD ($n{=}32{,}565$; MDE${\\approx}$0.22~pp) provides the definitive test.}), the oracle (0.775) reveals 13.0~pp of headroom, but LP achieves $+0.2$~pp ($p{=}0.29$), below the MDE (${\\approx}$1.5~pp); selection effects below this threshold cannot be reliably detected.\nThe pattern holds across CoNLL and WNUT-17 (Table~\\ref{tab:cross_selection}); under stringent TOST anchors, some configurations show significant \\textit{degradation} (Appendix~\\ref{app:tost}).\nFew-NERD provides the definitive contrast: LP achieves $+1.39$~pp ($p{<}0.001$) at low degeneracy (\\S\\ref{sec:fewnerd}), while structural signals still degrade selection.\n\n\\paragraph{Qualitative factors governing selection effectiveness.}\nThree factors qualitatively shape LP selection gains: (1)~\\textit{instance degeneracy} compresses the candidate space, leaving fewer instances where any signal can improve over greedy (SciERC 17.8\\%, CoNLL 48.4\\%; Table~\\ref{tab:fewnerd}); (2)~\\textit{oracle headroom} bounds the maximum achievable gain (CoNLL ${\\approx}2$\\,pp vs.\\ SciERC 13.1\\,pp); (3)~\\textit{LP-quality alignment}, measured as within-instance $\\rho(\\text{LP}, \\text{F1})$, determines whether LP can discriminate candidates in the remaining non-degenerate instances (Few-NERD $\\rho{\\approx}0.5$--$0.7$ vs.\\ SciERC $\\rho{\\approx}0.26$).\nThese factors are consistent with the observed pattern (Table~\\ref{tab:fewnerd}): Few-NERD (low degeneracy, strong alignment) shows the largest LP gain ($+1.39$\\,pp), SciERC (weak alignment) shows unreliable gains ($+0.04{\\pm}0.48$\\,pp, 3-seed; Table~\\ref{tab:multiseed}), CoNLL (high degeneracy, minimal headroom) shows no gain, and WNUT-17 represents the signal-collapse boundary: LP $\\rho{=}{-}0.446$ (the model assigns higher log-probabilities to confidently wrong outputs), within-instance alignment absent ($\\rho{=}0.043$, n.s.), and construction ineffective ($p{>}0.05$, mixed sign) because 51\\% of instances yield F1${=}0$.\nYet QE remains effective on WNUT-17 (VC $\\rho{=}0.730$; Table~\\ref{tab:wnut}), confirming QE-selection decoupling at this boundary.\nThis characterization is qualitative: the three factors do not combine into a predictive model ($R^2{<}0$ across 23 configurations), but each factor's role is individually supported by controlled ablations (\\S\\ref{sec:fewnerd}, \\S\\ref{sec:discussion}).\n\n%% ============================================================\n\\subsection{Cross-Dataset Contrast: Few-NERD}\n\\label{sec:fewnerd}\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{LP selection across datasets (Qwen3-8B, $N{=}8$, $T{=}1.0$, gold-filtered). Few-NERD/CoNLL: 3-seed means; SciERC: single-seed (3-seed in Table~\\ref{tab:multiseed}). $p$: paired bootstrap.}\n\\label{tab:fewnerd}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}lrccccr@{}}\n\\toprule\nDataset & $n$ & Greedy & Degen.\\% & LP $\\rho$ & LP $\\Delta$ & $p$ \\\\\n\\midrule\nWNUT-17 & 1{,}287 & .452 & 67.9\\% & $-$.446 & $-$0.45\\,pp & .72 \\\\\nCoNLL & 2{,}756 & .908 & 48.4\\% & .302 & $-$0.85\\,pp & 1.0 \\\\\nSciERC & 529 & .644 & 17.8\\% & .205 & $+$0.61\\,pp & .193 \\\\\nFew-NERD & 32{,}565 & .748 & 13.8\\% & .220 & $\\mathbf{+1.39}$\\,pp & ${<}.001$ \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nFew-NERD (Table~\\ref{tab:fewnerd}) confirms LP selection at low degeneracy: $+1.39$~pp ($p{<}0.001$), while structural signals degrade selection (VC $-1.79$, SJ $-2.14$~pp). LP is 50$\\times$ more seed-stable ($\\sigma{=}0.04$ vs.\\ SJ $2.02$~pp) and generalizes to LLaMA-3.1-8B (Table~\\ref{tab:cross_selection}).\nTraining convergence modulates degeneracy: 5-epoch Few-NERD raises degeneracy to 31\\% and halves LP gains (Appendix~\\ref{app:epoch_confound}).\n\n\\paragraph{Degeneracy alone does not predict LP selection direction.}\nAcross 23 configurations, degeneracy does not predict LP gain ($\\rho{=}0.052$, $p{=}0.81$; Figure~\\ref{fig:degeneracy_scatter}), though within fixed settings it causally modulates LP ($\\rho{=}{-}0.881$; Appendix~\\ref{app:per_type_lp}).\nCross-dataset prediction requires LP signal quality: Few-NERD ($\\rho{\\approx}0.5$--$0.7$) shows consistent gains, SciERC ($\\rho{\\approx}0.26$) does not (Appendix~\\ref{app:conditional_decomp}).\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{figures/fig_degeneracy_lp_scatter.pdf}\n\\caption{Instance degeneracy vs.\\ LP selection gain across 23 configurations ($N{=}8$; $\\rho{=}0.052$, $p{=}0.81$). Within Few-NERD per-entity-type analysis ($\\rho{=}{-}0.881$; Appendix~\\ref{app:per_type_lp}), degeneracy predicts LP gain when alignment is held constant.}\n\\label{fig:degeneracy_scatter}\n\\end{figure}\n\nStructural signals remain negative regardless of sample budget; $N$-scaling analyses are in Appendix~\\ref{app:n_scaling}.\n\n%% ============================================================\n\\subsection{Robustness}\n\\label{sec:robustness_main}\n\nConsistency signals are robust across $T{\\in}\\{0.7, 1.0\\}$ with sublinear $N$-scaling gains (Table~\\ref{tab:robustness}); signal rankings are stable across seeds ($W{=}1.0$; Table~\\ref{tab:ranking-stability}). NER calibration is reasonable (ECE 0.069--0.096; Appendix~\\ref{app:calibration}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Scale ablation: 8B vs.\\ 4B QE $\\rho$ ($N{=}8$, $T{=}1.0$, seed 42). RE in Appendix~\\ref{app:re_extension}.}\n\\label{tab:scale_ablation}\n\\begin{tabular}{@{}ll cc r@{}}\n\\toprule\n& & \\textbf{8B} & \\textbf{4B} & $\\Delta$ \\\\\n\\midrule\nCoNLL & SJ & .436 & .422 & $-$.014 \\\\\n      & FK & .400 & .418 & $+$.018 \\\\\nSciERC & SJ & .360 & .422 & $+$.062 \\\\\n       & FK & .267 & .326 & $+$.059 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Scale robustness.}\nWith Qwen3-4B (Table~\\ref{tab:scale_ablation}), QE is comparable (mean $|\\Delta\\rho|{=}0.042$), yet selection remains below greedy despite 13.0~pp headroom. Task difficulty is a stronger predictor than model scale within the 3B--8B range (Appendix~\\ref{app:llama3b}).\nDegeneracy scales with capability: 8B shows 17.8\\% vs.\\ 4B's 10.4\\% on SciERC (Table~\\ref{tab:degeneracy}).\n\n\\paragraph{LoRA-rank ablation.}\nLoRA rank${=}8$ (vs.\\ 32) lowers degeneracy to 7.2\\% but LP remains below greedy ($\\rho(\\text{LP}, \\text{F1}){\\approx}0.24$); temperature manipulation ($T{=}1.2$; \\S\\ref{sec:discussion}) confirms that low degeneracy and adequate alignment are independently necessary.\n\n\\paragraph{Supervised signal combination and hidden probes.}\nSupervised classifiers (LR, MLP, RF; 5-fold CV, $N{=}16$) and a DeBERTa-v3-base verifier all fail to close the selection gap (Appendix~\\ref{app:supervised_combination}).\nHidden state probes improve correlation ($+37$\\% on SciERC) but not selection (gap closure $-5.1$\\%; Appendix~\\ref{app:hidden_probe}); the bottleneck extends to model-internal representations.\n\n%% ============================================================\n\\subsection{Scaling Behavior}\n\\label{sec:scaling}\n\nWe evaluate Qwen2.5-72B-Instruct in a zero-shot setting to test whether the gap persists at larger scale without fine-tuning.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Fine-tuned 8B vs.\\ zero-shot 72B ($N{=}8$, $T{=}1.0$). Hdr.\\ = oracle $-$ greedy (pp).}\n\\label{tab:scale_comparison}\n\\begin{tabular}{@{}llcccccc@{}}\n\\toprule\nDataset & Regime & Greedy & Hdr. & VC & SJ & FK & LP \\\\\n\\midrule\nSciERC & 8B FT  & .645 & 13.0 & .379 & .360 & .267 & .205 \\\\\n       & 72B ZS & .399 & 15.0 & .277 & .217 & .227 & .081 \\\\\n\\midrule\nCoNLL  & 8B FT  & .908 & ${\\approx}$2 & .424 & .436 & .400 & .302 \\\\\n       & 72B ZS & .712 & 5.3  & .297 & .304 & .302 & $-$.002 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nZero-shot 72B produces lower greedy F1 but larger oracle headroom (Table~\\ref{tab:scale_comparison}). LP $\\rho$ drops from $0.205$ to $0.081$ on SciERC and from $0.302$ to near zero on CoNLL; LP selection fails in both datasets (SciERC $-0.1$~pp, CoNLL $-0.4$~pp), confirming that the gap is a structural property of the task rather than a fine-tuning artifact.\nStructural signals remain positive but reduced (VC $\\rho{=}0.277$ on SciERC, SJ $\\rho{=}0.304$ on CoNLL). LP-weighted construction partially compensates on SciERC ($+1.5$\\,pp, 41.4\\% vs.\\ 39.9\\% greedy) but not on CoNLL ($-0.37$\\,pp), where limited headroom (5.3~pp) leaves little room for aggregation.\n\n\\textcolor{red}{TODO: (1) Add 72B fine-tuned results to determine whether fine-tuning at larger scale recovers signal quality. (2) Report degeneracy percentages for 72B zero-shot.}\n\n\\begin{figure}[t]\n\\centering\n% \\includegraphics[width=\\columnwidth]{figures/fig_scaling_curve.pdf}\n\\textcolor{red}{TODO: Scaling curve. X-axis: model scale (4B, 8B, 72B). Panels: (a) greedy/oracle F1 and headroom, (b) signal $\\rho$. Separate lines for fine-tuned vs.\\ zero-shot.}\n\\caption{\\textcolor{red}{TODO: Signal quality and oracle headroom across model scales.}}\n\\label{fig:scaling_curve}\n\\end{figure}\n\n%% ============================================================\n\\subsection{Prescriptive Results}\n\\label{sec:prescriptive}\n\nThe preceding sections establish that instance-level selection fails for structured IE. We now present two approaches that extract value from multi-sample generation without relying on sample ranking.\n\n\\paragraph{Entity-level construction.}\nRather than selecting one of $N$ complete outputs, we aggregate entities across all samples, retaining those exceeding a confirmation threshold $\\theta{=}2/N$ (${\\geq}2$ of $N$ samples), with LP-weighted or uniform frequency scoring. Under fine-tuning, this default achieves the best or near-best F1 across all datasets ($\\theta$ stable within $[0.15, 0.35]$; Appendix~\\ref{app:theta_sweep}). In the zero-shot regime, uniform voting degrades (SciERC $-0.52$\\,pp, CoNLL $-0.92$\\,pp) because greater output diversity admits noise entities; LP-weighting is necessary for construction to succeed without fine-tuning (SciERC $+1.5$\\,pp; \\S\\ref{sec:scaling}).\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Entity construction vs.\\ greedy ($\\Delta$ macro F1; $N{=}8$, $T{=}1.0$, Qwen3-8B, multi-seed mean${\\pm}\\sigma$). $\\theta{=}2/N$. $p$: paired bootstrap vs.\\ greedy. Best in \\textbf{bold}.}\n\\label{tab:entity_construction}\n\\resizebox{\\columnwidth}{!}{%\n\\begin{tabular}{@{}llcccc@{}}\n\\toprule\nDataset & Wt. & Greedy & Constr. & $\\Delta$ & $p$ \\\\\n\\midrule\nSciERC & LP & $.646{\\pm}.002$ & $\\mathbf{.656{\\pm}.003}$ & $+1.02{\\pm}0.49$\\,pp & .004 \\\\\n       & Unif. & $.646{\\pm}.002$ & $.653{\\pm}.006$ & $+0.74{\\pm}0.71$\\,pp & .023 \\\\\n\\addlinespace\nFew-NERD & LP & $.748$ & $\\mathbf{.762{\\pm}.005}$ & $+1.40{\\pm}0.51$\\,pp & ${<}.001$ \\\\\n         & Unif. & $.748$ & $.756{\\pm}.006$ & $+0.74{\\pm}0.58$\\,pp & .003 \\\\\n\\addlinespace\nCoNLL & Unif. & .908 & .904 & $-0.39$\\,pp & n.s. \\\\\n\\bottomrule\n\\end{tabular}}\n\\end{table}\n\nLP-weighted construction improves over greedy on Few-NERD ($+1.40{\\pm}0.51$\\,pp, $p{<}0.001$) and SciERC ($+1.02{\\pm}0.49$\\,pp, $p{=}0.004$; Table~\\ref{tab:entity_construction}), positive across all 7 seed-dataset combinations, recovering ${\\approx}$8\\% (SciERC) and 11\\% (Few-NERD) of oracle headroom. CoNLL shows no gain ($-0.39$\\,pp), consistent with ceiling-regime degeneracy. The mechanism is recall-driven: aggregating low-frequency correct entities recovers mentions that no single sample captures ($N$-scaling in Appendix~\\ref{app:n_scaling}).\n\n\\paragraph{LP-alignment gating (preliminary diagnostic).}\nConstruction and LP selection are complementary: construction dominates on SciERC ($+1.02$\\,pp vs.\\ LP $+0.04{\\pm}0.48$\\,pp, n.s.; $\\rho{\\approx}0.2$), while on Few-NERD both yield comparable gains ($+1.40$ vs.\\ $+1.39$\\,pp; $\\rho{\\approx}0.5$--$0.7$).\nWe estimate within-instance $\\rho(\\text{LP}, \\text{F1})$ on 50 held-out instances with bootstrap CIs (1000 resamples). Degeneracy-adjusted $\\rho_{\\text{adj}}$: Few-NERD $0.516$ [0.459, 0.759], SciERC $0.167$ [0.146, 0.281], CoNLL $0.065$ [$-$0.061, 0.620], WNUT-17 ${\\approx}0$ (n.s.).\nThe protocol performs three-way routing: (1)~$\\rho_{\\text{adj}} \\geq \\tau{=}0.3$: apply LP selection; (2)~$\\rho_{\\text{adj}} < \\tau$ and construction shows positive dev-set gain: apply construction; (3)~otherwise: retain greedy decoding.\nThis routes Few-NERD to LP selection ($+1.39$\\,pp); SciERC, CoNLL, and WNUT-17 fall below $\\tau$ and route to greedy. The conservative protocol trades SciERC's missed construction gain ($+1.02$\\,pp) for protection against negative outcomes (CoNLL $-0.39$\\,pp, WNUT-17 n.s.).\nRouting is stable across $\\tau{\\in}[0.2, 0.4]$ and matches test-set direction for all four datasets; narrower inter-dataset margins remain untested.\n\n\\paragraph{Selective prediction.}\nOrthogonal to construction, QE signals support selective prediction: at 80\\% coverage, filtering low-confidence instances yields $+5$--$8$\\,pp F1 (AUPRC 0.70--0.92; Table~\\ref{tab:cross_selection}).\n\n\\phantomsection\\label{sec:selection_results}\n",
      "numLines": 259,
      "startLine": 1,
      "totalLines": 259
    }
  }
}
```

</details>

---


### Tool call

_source line 32_

<details open><summary>🔧 Tool call — Read · `toolu_01RHFfpVJDhGFrpm7CdNoNB8`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "5d19a7f9-d8d5-4eab-8afb-3a0b58b3e01c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Aqkjj9hxgV8pX4f8kaENzc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1290,
      "cache_read_input_tokens": 38900,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1290
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

_source line 33 · 2026-05-19T13:33:51.431Z_

<details><summary>↩ Tool result · `toolu_01RHFfpVJDhGFrpm7CdNoNB8`</summary>

```text
1	\section{Discussion}\label{sec:discussion}
2	
3	The decoupling of $\rho$, AUROC, and selection F1 means single-metric evaluation risks selecting the wrong signal; effective selection likely requires content-aware verifiers \cite{cobbe2021verifiers, venktesh2025trust}.
4	Three factors qualitatively constrain selection: instance degeneracy (17.8--67.9\%) compresses the candidate space, limited oracle headroom bounds achievable gains, and LP compression (within-instance $\rho$ 0.043--0.667) prevents exploiting the remainder; within non-degenerate instances, MBR utility correlates positively with F1 (SJ median $\rho{=}0.524$) \cite{eikema2022sampling}.
5	Where compression is mitigated (LP range ${\geq}0.05$, $n{=}210$), LP selection yields $+2.9$~pp ($p{=}0.004$; Table~\ref{tab:nontied_main}), but $\varepsilon{=}0.05$ is post-hoc ($p_{\text{adj}}{=}0.14$ after joint correction; Appendix~\ref{app:epsilon_robustness}), so this is exploratory evidence.
6	Temperature disentangles degeneracy from alignment: at $T{=}1.2$, degeneracy drops to 14.9\% yet LP does not improve (median $\rho{=}0.225$; Table~\ref{tab:t_degeneracy}); the selection window narrows as models improve \cite{wang2023selfconsistency, snell2025scaling}.
7	
8	\paragraph{From diagnosis to practice.}\label{sec:selection_method}
9	Entity-level construction bypasses both failure mechanisms (Table~\ref{tab:entity_construction}), complementary with LP selection and governed by LP-quality alignment (\S\ref{sec:prescriptive}).
10	Alternative strategies (DALS, MBR, DGS) fail to reliably beat greedy (Appendix~\ref{app:dals}); our negative results are specific to fine-tuned models with constrained decoding (Appendix~\ref{app:when_selection_works}).
11	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "16ce3a1d-8ed9-4acb-a42a-5d7c962741bd",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex",
      "content": "\\section{Discussion}\\label{sec:discussion}\n\nThe decoupling of $\\rho$, AUROC, and selection F1 means single-metric evaluation risks selecting the wrong signal; effective selection likely requires content-aware verifiers \\cite{cobbe2021verifiers, venktesh2025trust}.\nThree factors qualitatively constrain selection: instance degeneracy (17.8--67.9\\%) compresses the candidate space, limited oracle headroom bounds achievable gains, and LP compression (within-instance $\\rho$ 0.043--0.667) prevents exploiting the remainder; within non-degenerate instances, MBR utility correlates positively with F1 (SJ median $\\rho{=}0.524$) \\cite{eikema2022sampling}.\nWhere compression is mitigated (LP range ${\\geq}0.05$, $n{=}210$), LP selection yields $+2.9$~pp ($p{=}0.004$; Table~\\ref{tab:nontied_main}), but $\\varepsilon{=}0.05$ is post-hoc ($p_{\\text{adj}}{=}0.14$ after joint correction; Appendix~\\ref{app:epsilon_robustness}), so this is exploratory evidence.\nTemperature disentangles degeneracy from alignment: at $T{=}1.2$, degeneracy drops to 14.9\\% yet LP does not improve (median $\\rho{=}0.225$; Table~\\ref{tab:t_degeneracy}); the selection window narrows as models improve \\cite{wang2023selfconsistency, snell2025scaling}.\n\n\\paragraph{From diagnosis to practice.}\\label{sec:selection_method}\nEntity-level construction bypasses both failure mechanisms (Table~\\ref{tab:entity_construction}), complementary with LP selection and governed by LP-quality alignment (\\S\\ref{sec:prescriptive}).\nAlternative strategies (DALS, MBR, DGS) fail to reliably beat greedy (Appendix~\\ref{app:dals}); our negative results are specific to fine-tuned models with constrained decoding (Appendix~\\ref{app:when_selection_works}).\n",
      "numLines": 11,
      "startLine": 1,
      "totalLines": 11
    }
  }
}
```

</details>

---


### Tool call

_source line 34_

<details open><summary>🔧 Tool call — Read · `toolu_01HduiovUXyhfuAt8SYam9ij`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "29105cb7-b3a7-41d2-8437-0a9c308404bb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Aqkjj9hxgV8pX4f8kaENzc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1290,
      "cache_read_input_tokens": 38900,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1290
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

_source line 35 · 2026-05-19T13:33:51.903Z_

<details><summary>↩ Tool result · `toolu_01HduiovUXyhfuAt8SYam9ij`</summary>

```text
1	Our evaluation covers four NER datasets; an exploratory RE extension on SciERC is reported in Appendix~\ref{app:re_extension} but generalization to other RE benchmarks remains unvalidated.
2	All experiments use English-language datasets; cross-lingual generalization remains untested.
3	Entity-level construction assumes the model produces useful partial outputs across samples; when model capability is insufficient (WNUT-17, 51\% F1${=}0$), this precondition fails and construction cannot improve over greedy.
4	We cover 4B\textendash 8B scale; whether the gap holds for 70B+ models or closed-source APIs is untested. Larger models may produce more diverse samples (potentially reducing degeneracy), but their LP-quality alignment behavior is unknown, and these two factors may shift in opposite directions.
5	Our supervised approaches (DeBERTa verifier, hidden state probes, MLP/RF on signal combinations) all fail to close the oracle gap; whether content-aware verifiers with access to task-specific structure could succeed remains open.
6	
7	We evaluate at $N{=}8$ (primary) and $N{=}16$; behavior at larger sample sizes is unknown (Appendix~\ref{app:n_scaling}).
8	The free-form ablation covers SciERC NER and CoNLL NER with one model; RE free-form results are in Appendix~\ref{app:re_extension}.
9	Qwen3-8B's SciERC checkpoint used empty \texttt{&lt;think>&lt;/think>} blocks; a three-part analysis rules out this confound (Appendix~\ref{app:thinking_token}).
10	LP compression worsens on easy datasets at lower temperature (CoNLL tied fractions reach 95.8\% at $T{=}0.7$); whether reduced temperature translates to selection gains remains untested.
11	We tested verbalized confidence \cite{lin2022teaching, tian2023calibration} as a second per-sample signal; it exhibits severe overconfidence (mean 8.58/10 on SciERC, 9.24/10 on CoNLL) and yields the weakest QE and selection among all signals (Appendix~\ref{app:verbalized_confidence}).
12	Ad-hoc LP${\times}$VC combinations yield at most $+0.2$~pp over greedy (not significant; \S\ref{sec:discussion}); whether \textit{learned} combinations could close the gap remains open.
13	The $\varepsilon{=}0.05$ threshold used for tied/non-tied LP stratification is a post-hoc exploratory choice; while selection F1 is stable across $\varepsilon \in [0, 0.2]$ (Appendix~\ref{app:epsilon_robustness}), the specific subset gains should be interpreted as characterizing the compression phenomenon rather than as a tuned selection strategy.
14	We tested one remedy for LP compression (entity-token-only LP, excluding format/schema tokens) which fails to improve selection despite increasing within-instance variance on SciERC ($4{\times}$); LP${\times}$VC combinations also fail to recover selection (\S\ref{sec:discussion}). Our supervised signal combination baseline uses only the five unsupervised signals studied; a DeBERTa verifier encoding input-output pairs also fails to close the gap (preliminary, SciERC $n{=}106$), hidden state probes on the generating model's representations improve correlation ($+37$\% on SciERC) but do not improve selection (gap closure $-5.1$\%; Appendix~\ref{app:hidden_probe}), ; the bottleneck extends to model-internal access. Entity embeddings and calibration-based approaches remain untested.
15	Other per-sample scoring methods exist but were not evaluated: Self-Certainty \cite{kang2025selfcertainty} (consistency of token-level self-evaluation) and P(True) \cite{kadavath2022language} (model's own probability estimate of correctness) both produce per-sample scores and could in principle address the alignment bottleneck; whether they suffer from similar compression under fine-tuning is unknown.
16	Our selection experiments use 3 training seeds for Few-NERD and CoNLL (stability $\sigma{\leq}0.04$~pp for LP selection); these confirm robustness on the key positive and negative datasets. SciERC uses 1 primary seed with high seed sensitivity ($\sigma{=}0.48$~pp, $n{=}529$), which reflects limited within-seed statistical power.
17	Few-NERD models are trained for 3 epochs (vs.\ 5 for other datasets) due to earlier convergence; epoch confound analyses on both Few-NERD (2-point) and SciERC (3-point, including 10-epoch overfitting) are provided in Appendix~\ref{app:epoch_confound}.
18	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "fdb5040f-fc51-4ba9-b0a8-2fcbf1d60b3a",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex",
      "content": "Our evaluation covers four NER datasets; an exploratory RE extension on SciERC is reported in Appendix~\\ref{app:re_extension} but generalization to other RE benchmarks remains unvalidated.\nAll experiments use English-language datasets; cross-lingual generalization remains untested.\nEntity-level construction assumes the model produces useful partial outputs across samples; when model capability is insufficient (WNUT-17, 51\\% F1${=}0$), this precondition fails and construction cannot improve over greedy.\nWe cover 4B\\textendash 8B scale; whether the gap holds for 70B+ models or closed-source APIs is untested. Larger models may produce more diverse samples (potentially reducing degeneracy), but their LP-quality alignment behavior is unknown, and these two factors may shift in opposite directions.\nOur supervised approaches (DeBERTa verifier, hidden state probes, MLP/RF on signal combinations) all fail to close the oracle gap; whether content-aware verifiers with access to task-specific structure could succeed remains open.\n\nWe evaluate at $N{=}8$ (primary) and $N{=}16$; behavior at larger sample sizes is unknown (Appendix~\\ref{app:n_scaling}).\nThe free-form ablation covers SciERC NER and CoNLL NER with one model; RE free-form results are in Appendix~\\ref{app:re_extension}.\nQwen3-8B's SciERC checkpoint used empty \\texttt{&lt;think>&lt;/think>} blocks; a three-part analysis rules out this confound (Appendix~\\ref{app:thinking_token}).\nLP compression worsens on easy datasets at lower temperature (CoNLL tied fractions reach 95.8\\% at $T{=}0.7$); whether reduced temperature translates to selection gains remains untested.\nWe tested verbalized confidence \\cite{lin2022teaching, tian2023calibration} as a second per-sample signal; it exhibits severe overconfidence (mean 8.58/10 on SciERC, 9.24/10 on CoNLL) and yields the weakest QE and selection among all signals (Appendix~\\ref{app:verbalized_confidence}).\nAd-hoc LP${\\times}$VC combinations yield at most $+0.2$~pp over greedy (not significant; \\S\\ref{sec:discussion}); whether \\textit{learned} combinations could close the gap remains open.\nThe $\\varepsilon{=}0.05$ threshold used for tied/non-tied LP stratification is a post-hoc exploratory choice; while selection F1 is stable across $\\varepsilon \\in [0, 0.2]$ (Appendix~\\ref{app:epsilon_robustness}), the specific subset gains should be interpreted as characterizing the compression phenomenon rather than as a tuned selection strategy.\nWe tested one remedy for LP compression (entity-token-only LP, excluding format/schema tokens) which fails to improve selection despite increasing within-instance variance on SciERC ($4{\\times}$); LP${\\times}$VC combinations also fail to recover selection (\\S\\ref{sec:discussion}). Our supervised signal combination baseline uses only the five unsupervised signals studied; a DeBERTa verifier encoding input-output pairs also fails to close the gap (preliminary, SciERC $n{=}106$), hidden state probes on the generating model's representations improve correlation ($+37$\\% on SciERC) but do not improve selection (gap closure $-5.1$\\%; Appendix~\\ref{app:hidden_probe}), ; the bottleneck extends to model-internal access. Entity embeddings and calibration-based approaches remain untested.\nOther per-sample scoring methods exist but were not evaluated: Self-Certainty \\cite{kang2025selfcertainty} (consistency of token-level self-evaluation) and P(True) \\cite{kadavath2022language} (model's own probability estimate of correctness) both produce per-sample scores and could in principle address the alignment bottleneck; whether they suffer from similar compression under fine-tuning is unknown.\nOur selection experiments use 3 training seeds for Few-NERD and CoNLL (stability $\\sigma{\\leq}0.04$~pp for LP selection); these confirm robustness on the key positive and negative datasets. SciERC uses 1 primary seed with high seed sensitivity ($\\sigma{=}0.48$~pp, $n{=}529$), which reflects limited within-seed statistical power.\nFew-NERD models are trained for 3 epochs (vs.\\ 5 for other datasets) due to earlier convergence; epoch confound analyses on both Few-NERD (2-point) and SciERC (3-point, including 10-epoch overfitting) are provided in Appendix~\\ref{app:epoch_confound}.\n",
      "numLines": 18,
      "startLine": 1,
      "totalLines": 18
    }
  }
}
```

</details>

---


### Tool call

_source line 36_

<details open><summary>🔧 Tool call — Read · `toolu_013ZQtGaXxc52uxfN5f72Czr`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "b16f43e7-330c-4775-a7e0-b4cfa1a2bfbb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Aqkjj9hxgV8pX4f8kaENzc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1290,
      "cache_read_input_tokens": 38900,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1290
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

_source line 37 · 2026-05-19T13:33:52.224Z_

<details><summary>↩ Tool result · `toolu_013ZQtGaXxc52uxfN5f72Czr`</summary>

```text
1	\section{Conclusion}\label{sec:conclusion}
2	
3	Five confidence signals achieve reliable NER quality estimation ($\rho$ up to 0.45, AUROC up to 0.82), enabling selective prediction ($+5$--$8$\,pp F1 at 80\% coverage). Instance-level selection fails due to degeneracy and LP compression; entity-level construction yields $+1.40$\,pp on Few-NERD and $+1.02$\,pp on SciERC ($p{<}0.005$), complementary with LP selection and governed by LP-quality alignment. For practitioners: use QE for selective prediction; apply construction when multi-sample generation is feasible; assess LP-alignment to route between strategies. As models improve, degeneracy rises and the selection window narrows; content-aware verifiers \cite{cobbe2021verifiers} may be needed to close the remaining gap.
4	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "58c2aed0-9137-44cc-b6ec-c4d586798144",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/conclusion.tex",
      "content": "\\section{Conclusion}\\label{sec:conclusion}\n\nFive confidence signals achieve reliable NER quality estimation ($\\rho$ up to 0.45, AUROC up to 0.82), enabling selective prediction ($+5$--$8$\\,pp F1 at 80\\% coverage). Instance-level selection fails due to degeneracy and LP compression; entity-level construction yields $+1.40$\\,pp on Few-NERD and $+1.02$\\,pp on SciERC ($p{<}0.005$), complementary with LP selection and governed by LP-quality alignment. For practitioners: use QE for selective prediction; apply construction when multi-sample generation is feasible; assess LP-alignment to route between strategies. As models improve, degeneracy rises and the selection window narrows; content-aware verifiers \\cite{cobbe2021verifiers} may be needed to close the remaining gap.\n",
      "numLines": 4,
      "startLine": 1,
      "totalLines": 4
    }
  }
}
```

</details>

---


### Tool call

_source line 38_

<details open><summary>🔧 Tool call — Read · `toolu_01Jcrpd3cBDokYw3GVf66Co9`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/related_work.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "c3e88487-3d4a-4a2c-aa4b-8f1964742c83",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Aqkjj9hxgV8pX4f8kaENzc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1290,
      "cache_read_input_tokens": 38900,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1290
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

_source line 39 · 2026-05-19T13:33:52.696Z_

<details><summary>↩ Tool result · `toolu_01Jcrpd3cBDokYw3GVf66Co9`</summary>

```text
1	\section{Related Work}\label{sec:related}
2	
3	\paragraph{Self-consistency and test-time scaling.}
4	Self-consistency \cite{wang2023selfconsistency} improves reasoning via majority voting; extensions handle free-form text \cite{chen2024usc, thirukovalluru2024atomic, manakul2023selfcheckgpt}.
5	Test-time scaling studies \cite{snell2025scaling, brown2024monkeys} and reward-free selectors \cite{taubenfeld2025cisc, kang2025selfcertainty, wang2025rankedvoting, oh2026latentsc} rely on answer-level agreement.
6	Adaptive variants gate on answer agreement \cite{aggarwal2023adaptive}, input difficulty \cite{wang2025make, feng2025optimal}, or response confidence \cite{kim2026reasc}; \citet{chen2025twofailures} diagnose SC failure modes without proposing gating.
7	All target discrete-answer reasoning; structured prediction requires different gating signals because degeneracy operates at the entity-set level.
8	
9	\paragraph{Consistency for structured IE.}
10	\citet{yao2026consistency} show consistency correlates with accuracy for LLM-based NER/RE; we show correlation alone does not ensure selection gains, diagnosing degeneracy and compression as blocking mechanisms.
11	CoCoA \cite{vashurin2025cocoa} fuses confidence with consistency; our supervised baseline confirms combination is not the bottleneck (\S\ref{sec:robustness_main}).
12	Earlier work on confidence for structured prediction \cite{culotta2004confidence, mejer2010confidence, fomicheva2020unsupervised} establishes the paradigm we extend to set-valued outputs.
13	Ensemble approaches aggregate predictions from multiple models or prompts \cite{florian2003named, xiao2025el4ner}; \citet{xie2023zeroshot} propose two-stage entity voting for zero-shot NER, the closest prior work to our entity-level construction.
14	LLM-Blender \cite{jiang2023llmblender} fuses outputs from multiple LLMs via pairwise ranking, whereas our single-model stochastic sampling derives diversity from temperature rather than model heterogeneity.
15	Our entity-level construction aggregates across samples from a single fine-tuned model, without requiring model diversity or prompt engineering.
16	Our evaluation builds on generative IE \cite{zhou2024uniner, sainz2024gollie, li2023codeie, wadhwa2023revisiting, xie2024selfimproving} and constrained decoding \cite{willard2023guided, dong2024xgrammar, park2024grammar, schall2025hidden}.
17	\citet{yun2025price} show structured formats induce diversity collapse; our LP compression (median range 0.041 nats; \S\ref{sec:discussion}) corroborates this for NER.
18	
19	\paragraph{Uncertainty estimation and MBR decoding.}
20	Surveys cover confidence estimation \cite{geng2024confidence}, uncertainty quantification \cite{xia2025survey}, and calibration \cite{hobelsberger2025systematic}; semantic uncertainty \cite{kuhn2023semantic, farquhar2024detecting} and P(True) \cite{kadavath2022language} provide model-internal alternatives.
21	Our selection strategies instantiate MBR decoding \cite{eikema2022sampling, deguchi2024centroid}; unlike MT where MBR yields consistent gains \cite{freitag2022high} and code generation where execution-based MBR improves selection \cite{shi2022mbr}, instance degeneracy eliminates the headroom MBR needs even when utility is well-aligned ($\rho{=}0.52$; \S\ref{sec:discussion}).
22	\citet{eikema2025structured} find MBR utilities degrade on structured outputs; our diagnosis is complementary: degeneracy, not utility misalignment, is the primary bottleneck.
23	Our QE results connect to selective prediction \cite{geifman2017selective, kuleshov2015calibrated, varshney2022investigating}: signals with AUROC up to 0.82 support abstention policies independent of sample selection.
24	
25	\paragraph{Best-of-$N$ with learned verifiers.}
26	\citet{gao2023scaling} establish BoN scaling laws and \citet{chen2021evaluating} define the pass@$k$ metric for code generation; our unsupervised signals face a more fundamental limitation than reward overoptimization.
27	Trained verifiers \cite{cobbe2021verifiers, lightman2024verify, fernandes2022quality} and self-evaluation guided search \cite{xie2023selfevaluation} learn per-sample scoring.
28	CISC \cite{taubenfeld2025cisc} and Self-Certainty \cite{kang2025selfcertainty} derive per-sample confidence from hidden states rather than output statistics, but require architecture-specific access to intermediate representations; these hidden-state signals remain untested for structured prediction (\S Limitations).
29	Fine-tuning \cite{kirk2024understanding} and constrained decoding \cite{holtzman2020curious, vijayakumar2018diverse} both limit the diversity recoverable for selection.
30	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "02874389-9e50-414e-9123-f4a5280e57b3",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/related_work.tex",
      "content": "\\section{Related Work}\\label{sec:related}\n\n\\paragraph{Self-consistency and test-time scaling.}\nSelf-consistency \\cite{wang2023selfconsistency} improves reasoning via majority voting; extensions handle free-form text \\cite{chen2024usc, thirukovalluru2024atomic, manakul2023selfcheckgpt}.\nTest-time scaling studies \\cite{snell2025scaling, brown2024monkeys} and reward-free selectors \\cite{taubenfeld2025cisc, kang2025selfcertainty, wang2025rankedvoting, oh2026latentsc} rely on answer-level agreement.\nAdaptive variants gate on answer agreement \\cite{aggarwal2023adaptive}, input difficulty \\cite{wang2025make, feng2025optimal}, or response confidence \\cite{kim2026reasc}; \\citet{chen2025twofailures} diagnose SC failure modes without proposing gating.\nAll target discrete-answer reasoning; structured prediction requires different gating signals because degeneracy operates at the entity-set level.\n\n\\paragraph{Consistency for structured IE.}\n\\citet{yao2026consistency} show consistency correlates with accuracy for LLM-based NER/RE; we show correlation alone does not ensure selection gains, diagnosing degeneracy and compression as blocking mechanisms.\nCoCoA \\cite{vashurin2025cocoa} fuses confidence with consistency; our supervised baseline confirms combination is not the bottleneck (\\S\\ref{sec:robustness_main}).\nEarlier work on confidence for structured prediction \\cite{culotta2004confidence, mejer2010confidence, fomicheva2020unsupervised} establishes the paradigm we extend to set-valued outputs.\nEnsemble approaches aggregate predictions from multiple models or prompts \\cite{florian2003named, xiao2025el4ner}; \\citet{xie2023zeroshot} propose two-stage entity voting for zero-shot NER, the closest prior work to our entity-level construction.\nLLM-Blender \\cite{jiang2023llmblender} fuses outputs from multiple LLMs via pairwise ranking, whereas our single-model stochastic sampling derives diversity from temperature rather than model heterogeneity.\nOur entity-level construction aggregates across samples from a single fine-tuned model, without requiring model diversity or prompt engineering.\nOur evaluation builds on generative IE \\cite{zhou2024uniner, sainz2024gollie, li2023codeie, wadhwa2023revisiting, xie2024selfimproving} and constrained decoding \\cite{willard2023guided, dong2024xgrammar, park2024grammar, schall2025hidden}.\n\\citet{yun2025price} show structured formats induce diversity collapse; our LP compression (median range 0.041 nats; \\S\\ref{sec:discussion}) corroborates this for NER.\n\n\\paragraph{Uncertainty estimation and MBR decoding.}\nSurveys cover confidence estimation \\cite{geng2024confidence}, uncertainty quantification \\cite{xia2025survey}, and calibration \\cite{hobelsberger2025systematic}; semantic uncertainty \\cite{kuhn2023semantic, farquhar2024detecting} and P(True) \\cite{kadavath2022language} provide model-internal alternatives.\nOur selection strategies instantiate MBR decoding \\cite{eikema2022sampling, deguchi2024centroid}; unlike MT where MBR yields consistent gains \\cite{freitag2022high} and code generation where execution-based MBR improves selection \\cite{shi2022mbr}, instance degeneracy eliminates the headroom MBR needs even when utility is well-aligned ($\\rho{=}0.52$; \\S\\ref{sec:discussion}).\n\\citet{eikema2025structured} find MBR utilities degrade on structured outputs; our diagnosis is complementary: degeneracy, not utility misalignment, is the primary bottleneck.\nOur QE results connect to selective prediction \\cite{geifman2017selective, kuleshov2015calibrated, varshney2022investigating}: signals with AUROC up to 0.82 support abstention policies independent of sample selection.\n\n\\paragraph{Best-of-$N$ with learned verifiers.}\n\\citet{gao2023scaling} establish BoN scaling laws and \\citet{chen2021evaluating} define the pass@$k$ metric for code generation; our unsupervised signals face a more fundamental limitation than reward overoptimization.\nTrained verifiers \\cite{cobbe2021verifiers, lightman2024verify, fernandes2022quality} and self-evaluation guided search \\cite{xie2023selfevaluation} learn per-sample scoring.\nCISC \\cite{taubenfeld2025cisc} and Self-Certainty \\cite{kang2025selfcertainty} derive per-sample confidence from hidden states rather than output statistics, but require architecture-specific access to intermediate representations; these hidden-state signals remain untested for structured prediction (\\S Limitations).\nFine-tuning \\cite{kirk2024understanding} and constrained decoding \\cite{holtzman2020curious, vijayakumar2018diverse} both limit the diversity recoverable for selection.\n",
      "numLines": 30,
      "startLine": 1,
      "totalLines": 30
    }
  }
}
```

</details>

---


### Tool call

_source line 40_

<details open><summary>🔧 Tool call — Read · `toolu_01VfpEVWtpou7YpW2kiPBBoz`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "b9ce8b16-cc47-4119-8b87-cc827b593d82",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Aqkjj9hxgV8pX4f8kaENzc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1290,
      "cache_read_input_tokens": 38900,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1290
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

_source line 41 · 2026-05-19T13:33:53.515Z_

<details><summary>↩ Tool result · reported error · `toolu_01VfpEVWtpou7YpW2kiPBBoz`</summary>

```text
File content (41705 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "66313c27-320b-4ae6-a4ba-ed2ce3dc8d5d",
  "tool_use_result": "Error: File content (41705 tokens) exceeds maximum allowed tokens (25000). Use offset and limit parameters to read specific portions of the file, or search for specific content instead of reading the whole file."
}
```

</details>

---


### Assistant

_source line 42_

<details><summary>Logged reasoning block</summary>

```text
The appendix is too large to read at once. Let me now read the registry data for the specific experiments mentioned in the task. I also need to read portions of the appendix that contain specific data tables. Let me first extract data from the registry for key experiments.

Let me read the registry data from the saved file, focusing on the specific experiments mentioned in the task.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "82e947b8-0353-442e-9bd0-b3e6f2207ff6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VPL292VYvX2e44f8PPuEg4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 16774,
      "cache_read_input_tokens": 40190,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 16774
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

_source line 43_

论文各章节已读取。现在从 registry 提取关键实验数据进行交叉验证。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "3ca625a8-cc48-4efa-8bca-1b13097287a8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VPL292VYvX2e44f8PPuEg4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 16774,
      "cache_read_input_tokens": 40190,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 16774
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

_source line 44_

<details open><summary>🔧 Tool call — Bash · `toolu_01JfzvT7VqH1vTkmj6w7L6dT`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result.get('data', result.get('experiments', []))\ntarget_ids = [\n    'exp_012_logprob_baseline', 'exp_001_ner_n16_scierc', 'exp_006_v2',\n    'exp_016_signal_ensemble', 'exp_023_lora_rank8', 'exp_entity_construction',\n    'exp_llama_fewnerd_inference', 'exp_qwen25_72b_zeroshot',\n    'exp_016_rerun_1024', 'exp_021_fewnerd_full', 'exp_freeform_ablation',\n    'exp_012_rerun_1024', 'exp_016_rerun_1024_bootstrap',\n    'exp_scale_4b', 'exp_scale_ablation', 'exp_018'\n]\nfor exp in exps:\n    eid = exp.get('exp_id', '')\n    if any(t in eid for t in target_ids):\n        print(f'=== {eid} ===')\n        print(f'status: {exp.get(\\\"status\\\", \\\"?\\\")}')\n        print(f'conclusion: {exp.get(\\\"conclusion\\\", \\\"?\\\")}')\n        metrics = exp.get('metrics', {})\n        if metrics:\n            print(f'metrics: {json.dumps(metrics, indent=2)[:3000]}')\n        print()\n\" 2>&1 | head -500\n",
  "description": "Extract key experiment data from registry",
  "timeout": 30000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "42ee99aa-d8f4-479f-9121-6256200a44c9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VPL292VYvX2e44f8PPuEg4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 16774,
      "cache_read_input_tokens": 40190,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 16774
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

_source line 45 · 2026-05-19T13:34:09.470Z_

<details><summary>↩ Tool result · `toolu_01JfzvT7VqH1vTkmj6w7L6dT`</summary>

```text
Traceback (most recent call last):
  File "&lt;string>", line 15, in &lt;module>
    eid = exp.get('exp_id', '')
          ^^^^^^^
AttributeError: 'str' object has no attribute 'get'
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "358c137a-2eaf-4636-a7bc-1352f2db8673",
  "tool_use_result": {
    "stdout": "Traceback (most recent call last):\n  File \"&lt;string>\", line 15, in &lt;module>\n    eid = exp.get('exp_id', '')\n          ^^^^^^^\nAttributeError: 'str' object has no attribute 'get'",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---


### Tool call

_source line 46_

<details open><summary>🔧 Tool call — Bash · `toolu_01DGi45FSvYTZMEC9PTVgi6Y`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\n# Check structure\nif isinstance(result, dict):\n    for k in result.keys():\n        v = result[k]\n        if isinstance(v, list):\n            print(f'key={k}, type=list, len={len(v)}, first_type={type(v[0]).__name__ if v else \\\"empty\\\"}')\n            if v and isinstance(v[0], dict):\n                print(f'  first keys: {list(v[0].keys())[:10]}')\n        elif isinstance(v, dict):\n            print(f'key={k}, type=dict, keys={list(v.keys())[:5]}')\n            for sk, sv in list(v.items())[:2]:\n                print(f'  {sk}: type={type(sv).__name__}')\n                if isinstance(sv, dict):\n                    print(f'    keys: {list(sv.keys())[:10]}')\n        else:\n            print(f'key={k}, type={type(v).__name__}, val={str(v)[:100]}')\n\" 2>&1\n",
  "description": "Check registry data structure"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "bb2dfe31-83d3-4cf1-ad4e-a51d7dca4ba1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ScZEumC2Xit6GxRscbJkQm",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 778,
      "cache_read_input_tokens": 56964,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 778
      },
      "output_tokens": 69,
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

_source line 47 · 2026-05-19T13:34:22.939Z_

<details><summary>↩ Tool result · `toolu_01DGi45FSvYTZMEC9PTVgi6Y`</summary>

```text
key=success, type=bool, val=True
key=data, type=dict, keys=['experiments', 'count', 'total', 'baseline']
  experiments: type=dict
    keys: ['exp_qwen25_72b_zeroshot', 'exp_qwen25_14b_fewnerd', 'exp_qwen25_32b_fewnerd', 'exp_qwen25_7b_fewnerd', 'exp_wnut17_qwen25_7b', 'exp_llama_fewnerd_inference', 'exp_entity_construction', 'exp_lp_alignment_gating', 'exp_selective_prediction', 'exp_llama_fewnerd_lora']
  count: type=int
key=error, type=NoneType, val=None
key=metadata, type=dict, keys=['elapsed_seconds']
  elapsed_seconds: type=float
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "1c3253e3-a3bf-4820-b255-df71167aa8ab",
  "tool_use_result": {
    "stdout": "key=success, type=bool, val=True\nkey=data, type=dict, keys=['experiments', 'count', 'total', 'baseline']\n  experiments: type=dict\n    keys: ['exp_qwen25_72b_zeroshot', 'exp_qwen25_14b_fewnerd', 'exp_qwen25_32b_fewnerd', 'exp_qwen25_7b_fewnerd', 'exp_wnut17_qwen25_7b', 'exp_llama_fewnerd_inference', 'exp_entity_construction', 'exp_lp_alignment_gating', 'exp_selective_prediction', 'exp_llama_fewnerd_lora']\n  count: type=int\nkey=error, type=NoneType, val=None\nkey=metadata, type=dict, keys=['elapsed_seconds']\n  elapsed_seconds: type=float",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---


### Tool call

_source line 48_

<details open><summary>🔧 Tool call — Bash · `toolu_01JCLo6jixUo7zBLcnU8qX4i`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\nprint('All experiment IDs:')\nfor eid in exps.keys():\n    print(f'  {eid}')\nprint(f'\\nTotal: {len(exps)}')\n\" 2>&1\n",
  "description": "List all experiment IDs"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "c4eb51b3-2aa1-41f7-99d1-dac1a1446bb3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014PL5bVbzs41QzfNeKkjHac",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 688,
      "cache_read_input_tokens": 57742,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 688
      },
      "output_tokens": 69,
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

_source line 49 · 2026-05-19T13:34:27.419Z_

<details><summary>↩ Tool result · `toolu_01JCLo6jixUo7zBLcnU8qX4i`</summary>

```text
All experiment IDs:
  exp_qwen25_72b_zeroshot
  exp_qwen25_14b_fewnerd
  exp_qwen25_32b_fewnerd
  exp_qwen25_7b_fewnerd
  exp_wnut17_qwen25_7b
  exp_llama_fewnerd_inference
  exp_entity_construction
  exp_lp_alignment_gating
  exp_selective_prediction
  exp_llama_fewnerd_lora
  hidden_state_probe_conll_full
  hidden_state_probe_conll_v2
  exp_031_fewnerd_t12
  exp_030_conll_t12
  mbr_pilot
  dgs_pilot
  exp_fewnerd_s789_n8
  exp_026_t12_seed456
  exp_026_t12_seed123
  exp_026_t10_seed456
  exp_026_t10_seed123
  exp_026_t10_seed42
  exp_026_t08_seed456
  exp_026_t08_seed123
  exp_026_t05_seed456
  exp_026_t05_seed123
  exp_029b
  exp_029a
  exp_021_fewnerd_n8_seed456
  exp_021_fewnerd_n8_seed123
  exp_002_conll_n16_seed456
  exp_002_conll_n16_seed123
  exp_017_llama_conll_n16_s456_r1024
  exp_017_llama_conll_n16_r1024
  exp_018_llama_scierc_seed456_r1024
  exp_018_llama_scierc_seed42_r1024
  exp_002_conll_n16
  exp_012_rerun_1024
  exp_llama_scierc_seed456
  exp_007_llama_scierc_seed123
  exp_qwen3_4b_conll_scs_inference
  exp_qwen3_4b_conll_scs_inference_v2
  exp_qwen3_4b_scierc_scs_inference
  exp_027_fewnerd_n16
  exp_026_t12
  exp_026_t08
  exp_026_t05
  exp_026_T12
  exp_026_T08
  exp_026_T05
  exp_017_llama_conll_n16_s123_r1024
  exp_018_llama_scierc_seed123
  exp_018_qwen_scierc_seed456
  exp_018_qwen_scierc_seed123
  exp_epoch_dgs_analysis
  exp_diagnostic_calibration
  exp_adaptive_temperature
  exp_entity_consensus
  exp_ccs_selection
  exp_017_llama_conll
  exp_017_llama_conll_finetune
  exp_028_entity_token_lp
  exp_026_t12_scierc
  exp_026_t08_scierc
  exp_026_t05_scierc
  exp_027_mlp_verifier
  exp_028_fewnerd_5epoch
  exp_028
  exp_024_claim_audit
  exp_016_rerun_1024_bootstrap
  exp_verbalized_confidence
  exp_entity_token_lp
  exp_freeform_ablation
  exp_008_re_n16
  exp_001_ner_n16_seed123
  exp_007_ner_multi_model
  exp_003_ner_wnut17
  exp_001_seed456_t10_full
  exp_001_seed123_t10_full
  exp_008_re_n16_t10_full
  exp_007_llama_inference
  exp_003_wnut17_eval
  exp_010_selection_curves
  exp_007_llama_seed456
  exp_007_llama_seed123
  exp_008_re_seed123
  exp_001_seed42_v2
  exp_001_seed123_v2
  exp_008_re_n16_v2
  exp_005_v2
  exp_006_v2
  exp_004_v2
  exp_009_v2
  exp_016_v2
  exp_001_seed456_v2
  exp_017_llama_conll_infer
  exp_003_wnut17_v2
  exp_001_seed456_v2_ner
  exp_009_v2_re_rerun
  exp_007_llama_n16
  exp_017_llama_conll_n16
  exp_015_v2
  exp_001_n16_seed456
  exp_011_ood_scierc_to_conll
  exp_qwen3_4b_scierc_finetune_v4
  exp_011_ood_conll_to_scierc
  exp_freeform_seed789_v3
  exp_freeform_seed789
  exp_freeform_seed456
  exp_freeform_seed123
  exp_009_capability_stratification
  exp_023_lora_rank8
  exp_022_seed789
  exp_025_n32
  exp_021_fewnerd_full
  exp_015_metrics_expansion
  exp_020_fewnerd_smoke
  exp_vc_lp_cascade_selection
  exp_tacred_re_benchmark
  exp_vc_quartile_analysis
  exp_llama3b_scierc_ablation
  exp_freeform_conll_4seed
  exp_qwen3_4b_conll_merge_inference_v2
  exp_qwen3_4b_scierc_merge_inference
  exp_qwen3_4b_scierc_finetune_v3
  exp_qwen3_4b_conll_finetune_resume
  exp_qwen3_4b_scierc_finetune_v2
  exp_qwen3_4b_conll_finetune
  exp_freeform_seed789_v2
  exp_qwen3_4b_scierc_finetune
  exp_lp_t07_scierc
  exp_lp_scierc_t07
  exp_re_scierc_seed456
  exp_re_scierc_seed123
  exp_017_llama_conll_n8_t07
  exp008_re_n16
  exp001_seed456
  exp001_seed123
  exp_001_n16_seed456_full
  exp_001_n16_seed123_full
  exp_007_ner_llama
  exp_002_merge_conll2003
  exp_019_supervised_verifier
  exp_018_llama_scierc_seed456
  exp_002_conll_n16_r1024
  exp_007_llama_n16_r1024
  exp_001_seed123_v2_r1024
  exp_001_seed456_v2_ner_r1024
  exp_001_seed42_v2_r1024
  exp_017_llama_conll_n16_s456
  exp_017_llama_conll_n16_s123
  exp_008_re_n16_full
  exp_001_n16_seed123
  exp_016_signal_ensemble
  exp_001_ner_n16_scierc
  exp_002
  exp_002_ner_conll2003
  exp_004_re_diagnostic
  exp_005
  exp_014_entity_majority_voting
  exp_013_exact_match_voting
  exp_012_logprob_baseline
  mvp_pilot_005
  e1_component_wise_re_sj
  mvp_pilot_004
  ft_002_v2
  mvp_pilot_002
  ft_002
  ft_001
  mvp_pilot_003
  mvp_pilot_001

Total: 171
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "8d3d1b92-cac7-4ab5-935d-907d2da065ad",
  "tool_use_result": {
    "stdout": "All experiment IDs:\n  exp_qwen25_72b_zeroshot\n  exp_qwen25_14b_fewnerd\n  exp_qwen25_32b_fewnerd\n  exp_qwen25_7b_fewnerd\n  exp_wnut17_qwen25_7b\n  exp_llama_fewnerd_inference\n  exp_entity_construction\n  exp_lp_alignment_gating\n  exp_selective_prediction\n  exp_llama_fewnerd_lora\n  hidden_state_probe_conll_full\n  hidden_state_probe_conll_v2\n  exp_031_fewnerd_t12\n  exp_030_conll_t12\n  mbr_pilot\n  dgs_pilot\n  exp_fewnerd_s789_n8\n  exp_026_t12_seed456\n  exp_026_t12_seed123\n  exp_026_t10_seed456\n  exp_026_t10_seed123\n  exp_026_t10_seed42\n  exp_026_t08_seed456\n  exp_026_t08_seed123\n  exp_026_t05_seed456\n  exp_026_t05_seed123\n  exp_029b\n  exp_029a\n  exp_021_fewnerd_n8_seed456\n  exp_021_fewnerd_n8_seed123\n  exp_002_conll_n16_seed456\n  exp_002_conll_n16_seed123\n  exp_017_llama_conll_n16_s456_r1024\n  exp_017_llama_conll_n16_r1024\n  exp_018_llama_scierc_seed456_r1024\n  exp_018_llama_scierc_seed42_r1024\n  exp_002_conll_n16\n  exp_012_rerun_1024\n  exp_llama_scierc_seed456\n  exp_007_llama_scierc_seed123\n  exp_qwen3_4b_conll_scs_inference\n  exp_qwen3_4b_conll_scs_inference_v2\n  exp_qwen3_4b_scierc_scs_inference\n  exp_027_fewnerd_n16\n  exp_026_t12\n  exp_026_t08\n  exp_026_t05\n  exp_026_T12\n  exp_026_T08\n  exp_026_T05\n  exp_017_llama_conll_n16_s123_r1024\n  exp_018_llama_scierc_seed123\n  exp_018_qwen_scierc_seed456\n  exp_018_qwen_scierc_seed123\n  exp_epoch_dgs_analysis\n  exp_diagnostic_calibration\n  exp_adaptive_temperature\n  exp_entity_consensus\n  exp_ccs_selection\n  exp_017_llama_conll\n  exp_017_llama_conll_finetune\n  exp_028_entity_token_lp\n  exp_026_t12_scierc\n  exp_026_t08_scierc\n  exp_026_t05_scierc\n  exp_027_mlp_verifier\n  exp_028_fewnerd_5epoch\n  exp_028\n  exp_024_claim_audit\n  exp_016_rerun_1024_bootstrap\n  exp_verbalized_confidence\n  exp_entity_token_lp\n  exp_freeform_ablation\n  exp_008_re_n16\n  exp_001_ner_n16_seed123\n  exp_007_ner_multi_model\n  exp_003_ner_wnut17\n  exp_001_seed456_t10_full\n  exp_001_seed123_t10_full\n  exp_008_re_n16_t10_full\n  exp_007_llama_inference\n  exp_003_wnut17_eval\n  exp_010_selection_curves\n  exp_007_llama_seed456\n  exp_007_llama_seed123\n  exp_008_re_seed123\n  exp_001_seed42_v2\n  exp_001_seed123_v2\n  exp_008_re_n16_v2\n  exp_005_v2\n  exp_006_v2\n  exp_004_v2\n  exp_009_v2\n  exp_016_v2\n  exp_001_seed456_v2\n  exp_017_llama_conll_infer\n  exp_003_wnut17_v2\n  exp_001_seed456_v2_ner\n  exp_009_v2_re_rerun\n  exp_007_llama_n16\n  exp_017_llama_conll_n16\n  exp_015_v2\n  exp_001_n16_seed456\n  exp_011_ood_scierc_to_conll\n  exp_qwen3_4b_scierc_finetune_v4\n  exp_011_ood_conll_to_scierc\n  exp_freeform_seed789_v3\n  exp_freeform_seed789\n  exp_freeform_seed456\n  exp_freeform_seed123\n  exp_009_capability_stratification\n  exp_023_lora_rank8\n  exp_022_seed789\n  exp_025_n32\n  exp_021_fewnerd_full\n  exp_015_metrics_expansion\n  exp_020_fewnerd_smoke\n  exp_vc_lp_cascade_selection\n  exp_tacred_re_benchmark\n  exp_vc_quartile_analysis\n  exp_llama3b_scierc_ablation\n  exp_freeform_conll_4seed\n  exp_qwen3_4b_conll_merge_inference_v2\n  exp_qwen3_4b_scierc_merge_inference\n  exp_qwen3_4b_scierc_finetune_v3\n  exp_qwen3_4b_conll_finetune_resume\n  exp_qwen3_4b_scierc_finetune_v2\n  exp_qwen3_4b_conll_finetune\n  exp_freeform_seed789_v2\n  exp_qwen3_4b_scierc_finetune\n  exp_lp_t07_scierc\n  exp_lp_scierc_t07\n  exp_re_scierc_seed456\n  exp_re_scierc_seed123\n  exp_017_llama_conll_n8_t07\n  exp008_re_n16\n  exp001_seed456\n  exp001_seed123\n  exp_001_n16_seed456_full\n  exp_001_n16_seed123_full\n  exp_007_ner_llama\n  exp_002_merge_conll2003\n  exp_019_supervised_verifier\n  exp_018_llama_scierc_seed456\n  exp_002_conll_n16_r1024\n  exp_007_llama_n16_r1024\n  exp_001_seed123_v2_r1024\n  exp_001_seed456_v2_ner_r1024\n  exp_001_seed42_v2_r1024\n  exp_017_llama_conll_n16_s456\n  exp_017_llama_conll_n16_s123\n  exp_008_re_n16_full\n  exp_001_n16_seed123\n  exp_016_signal_ensemble\n  exp_001_ner_n16_scierc\n  exp_002\n  exp_002_ner_conll2003\n  exp_004_re_diagnostic\n  exp_005\n  exp_014_entity_majority_voting\n  exp_013_exact_match_voting\n  exp_012_logprob_baseline\n  mvp_pilot_005\n  e1_component_wise_re_sj\n  mvp_pilot_004\n  ft_002_v2\n  mvp_pilot_002\n  ft_002\n  ft_001\n  mvp_pilot_003\n  mvp_pilot_001\n\nTotal: 171",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---


### Assistant

_source line 50_

<details><summary>Logged reasoning block</summary>

```text
Now I need to extract data from the key experiments. Let me query specific experiments that are referenced in the paper's quantitative claims. Let me batch extract the key ones.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "56e96934-2e6d-41a3-bfba-eeb4ecbe252c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MsRob3z4KisH1yGF1vayWh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2317,
      "cache_read_input_tokens": 58430,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2317
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

_source line 51_

<details open><summary>🔧 Tool call — Bash · `toolu_01QBJynRX6KaKLJVYH4prtKa`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\ntargets = [\n    'exp_012_rerun_1024', 'exp_016_rerun_1024_bootstrap', 'exp_016_signal_ensemble',\n    'exp_021_fewnerd_full', 'exp_023_lora_rank8', 'exp_entity_construction',\n    'exp_qwen25_72b_zeroshot', 'exp_freeform_ablation',\n    'exp_001_ner_n16_scierc', 'exp_012_logprob_baseline',\n    'exp_qwen3_4b_scierc_scs_inference', 'exp_qwen3_4b_conll_scs_inference_v2',\n    'exp_llama_fewnerd_inference', 'exp_selective_prediction',\n    'exp_lp_alignment_gating'\n]\nfor t in targets:\n    if t in exps:\n        e = exps[t]\n        print(f'=== {t} ===')\n        print(f'status: {e.get(\\\"status\\\",\\\"?\\\")}')\n        conc = e.get('conclusion','')\n        if conc:\n            print(f'conclusion: {conc[:500]}')\n        m = e.get('metrics', {})\n        if m:\n            ms = json.dumps(m, indent=2)\n            print(f'metrics: {ms[:2000]}')\n        print()\n\" 2>&1 | head -800\n",
  "description": "Extract metrics from key experiments",
  "timeout": 30000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "3815d689-4caf-4041-9b84-34c2c2c16ee6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01MsRob3z4KisH1yGF1vayWh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2317,
      "cache_read_input_tokens": 58430,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2317
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

_source line 52 · 2026-05-19T13:34:36.312Z_

<details><summary>↩ Tool result · `toolu_01QBJynRX6KaKLJVYH4prtKa`</summary>

```text
=== exp_012_rerun_1024 ===
status: DONE
conclusion: success
metrics: {
  "degen_rate": 0.1777,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered",
  "ner_full": {
    "n": 529,
    "SJ": {
      "rho": 0.3599,
      "tau": 0.2646,
      "AUROC": 0.6917,
      "ECE": 0.4531,
      "rho_ci95": [
        0.2732,
        0.4389
      ],
      "AUROC_ci95": [
        0.6304,
        0.7406
      ]
    },
    "FK": {
      "rho": 0.2665,
      "tau": 0.1974,
      "AUROC": 0.629,
      "ECE": 0.4512,
      "rho_ci95": [
        0.1743,
        0.3486
      ],
      "AUROC_ci95": [
        0.5612,
        0.6882
      ]
    },
    "logprob": {
      "rho": 0.2052,
      "tau": 0.1478,
      "AUROC": 0.5783,
      "ECE": 0.7064,
      "rho_ci95": [
        0.1171,
        0.2904
      ],
      "AUROC_ci95": [
        0.5179,
        0.6387
      ]
    },
    "EM": {
      "rho": 0.2945,
      "tau": 0.2208,
      "AUROC": 0.7493,
      "ECE": 0.3526,
      "rho_ci95": [
        0.2094,
        0.37
      ],
      "AUROC_ci95": [
        0.7002,
        0.7928
      ]
    },
    "voting_conf": {
      "rho": 0.3792,
      "tau": 0.2805,
      "AUROC": 0.6841,
      "ECE": 0.3807,
      "rho_ci95": [
        0.2972,
        0.4486
      ],
      "AUROC_ci95": [
        0.6249,
        0.7366
      ]
    }
  },
  "ner_cond": {
    "n": 477,
    "SJ": {
      "rho": 0.3113,
      "tau": 0.2257,
      "AUROC": 0.6772,
      "ECE": 0.4416,
      "rho_ci95": [
        0.2353,
        0.3959
      ],
      "AUROC_ci95": [
        0.621,
        0.7337
      ]
    },
    "FK": {
      "rho": 0.1761,
      "tau": 0.1284,
      "AUROC": 0.6078,
      "ECE": 0.4389,
      "rho_ci95": [
        0.0839,
        0.2665
      ],
      "AUROC_ci95": [
        0.5442,
        0.6709
      ]
    },
    "logprob": {
      "rho": 0.1538,
      "tau": 0.1111,
      "AUROC": 0.5633,
      "ECE": 0.6803,
      "rho_ci95": [
        0.0637,
        0.2424
      ],
      "AUROC_ci95": [
        0.5032,
        0.6232
      ]
    },
    "EM": {
      "

=== exp_016_rerun_1024_bootstrap ===
status: DONE
conclusion: negative
metrics: {
  "bootstrap_ci_95": [
    -0.03,
    0.042
  ],
  "permutation_p": 0.39,
  "cohen_d": 0.038,
  "sign_test_win_rate": 0.466,
  "ner_logprob_vs_greedy_delta": 0.006,
  "conclusion_summary": "NER selection: no signal significantly outperforms greedy; RE: same conclusion"
}

=== exp_016_signal_ensemble ===
status: DONE
conclusion: success
metrics: {
  "sj_logprob_pearson_ner": 0.57,
  "sj_logprob_pearson_re": 0.42,
  "best_linear_ner": {
    "combo": "SJ+voting_conf",
    "alpha": 0.3,
    "rho": 0.489
  },
  "best_linear_re": {
    "combo": "voting_conf+logprob",
    "alpha": 0.6,
    "rho": 0.429
  },
  "ensemble_ner_auroc": 0.735,
  "ensemble_re_auroc": 0.719,
  "best_single_ner_auroc": 0.7,
  "best_single_re_auroc": 0.721,
  "ensemble_ner_delta": 0.035,
  "selection_f1_ner": {
    "greedy": 0.609,
    "logprob": 0.609,
    "sj": 0.604,
    "ensemble": 0.604,
    "voting": 0.596,
    "random": 0.58,
    "oracle": 0.769
  },
  "selection_f1_re": {
    "logprob": 0.397,
    "greedy": 0.374,
    "sj": 0.368,
    "ensemble": 0.367,
    "voting": 0.338,
    "random": 0.338,
    "oracle": 0.561
  },
  "diagnosis": "SJ+voting_conf linear combo boosts NER \u03c1 to 0.489 (+23%). RE: logprob-best is ONLY method beating greedy (0.397 vs 0.374). Ensemble AUROC +0.035 on NER. Oracle gap still huge."
}

=== exp_021_fewnerd_full ===
status: DONE
conclusion: success
metrics: {
  "total_steps": 6177,
  "train_loss": 0.048,
  "eval_loss": 0.0275,
  "train_runtime": "3h57m",
  "epochs": 3,
  "final_checkpoint": "output/exp_021_fewnerd_full/checkpoint-6177",
  "adapter_path": "output/exp_021_fewnerd_full/adapter_model.safetensors",
  "inference_instances": 37648,
  "inference_filtered": 32565,
  "inference_n_samples": 8,
  "greedy_macro_f1": 0.7478,
  "oracle_macro_f1": 0.8719,
  "headroom": 0.124,
  "zero_f1_rate": 0.119,
  "degeneracy_rate": 0.101,
  "lp_within_range_mean": 0.0879,
  "lp_within_range_median": 0.0662,
  "lp_global_rho": 0.4215,
  "lp_cond_rho": 0.4225,
  "sj_global_rho": 0.3002,
  "sj_cond_rho": 0.2937,
  "fk_global_rho": 0.3132,
  "fk_cond_rho": 0.3093,
  "em_global_rho": 0.2871,
  "em_cond_rho": 0.271,
  "vc_global_rho": 0.3858,
  "vc_cond_rho": 0.3234,
  "lp_selection_delta_pp": 1.36,
  "vc_selection_delta_pp": -1.79,
  "sj_selection_delta_pp": -2.14,
  "fk_selection_delta_pp": -2.26,
  "em_selection_delta_pp": -3.85,
  "lp_bootstrap_ci_95_pp": [
    1.18,
    1.53
  ],
  "lp_sample_auroc": 0.5782,
  "vc_sample_auroc": 0.5354,
  "fk_sample_auroc": 0.521,
  "sj_sample_auroc": 0.5197,
  "em_sample_auroc": 0.5137,
  "scenario": "A_partial",
  "note": "Full analysis (gold-filtered n=32565). Prior simplified analysis used unfiltered data with different metrics."
}

=== exp_023_lora_rank8 ===
status: DONE
conclusion: success
metrics: {
  "train_loss": 0.1018,
  "eval_loss": 0.0776,
  "train_runtime": "28m45s",
  "ner_full": {
    "n": 529,
    "greedy_f1": 0.6397,
    "oracle_f1": 0.7998,
    "oracle_headroom": 0.1601,
    "degeneracy_rate": 0.072,
    "SJ_rho": 0.3649,
    "FK_rho": 0.2838,
    "VC_rho": 0.394,
    "EM_rho": 0.2562,
    "LP_rho": 0.2105,
    "SJ_auroc": 0.689,
    "FK_auroc": 0.6002,
    "VC_auroc": 0.6886,
    "EM_auroc": 0.7265,
    "LP_auroc": 0.6054,
    "sel_SJ": 0.6306,
    "sel_FK": 0.6265,
    "sel_VC": 0.5919,
    "sel_EM": 0.6073,
    "sel_LP": 0.635
  },
  "ner_cond": {
    "n": 477,
    "SJ_rho": 0.3056,
    "FK_rho": 0.1452,
    "VC_rho": 0.3191,
    "EM_rho": 0.3558,
    "LP_rho": 0.169
  },
  "re_full": {
    "n": 397,
    "greedy_f1": 0.3712,
    "oracle_f1": 0.609,
    "oracle_headroom": 0.2378,
    "degeneracy_rate": 0.217,
    "SJ_rho": 0.2244,
    "FK_rho": 0.3448,
    "VC_rho": 0.3617,
    "EM_rho": 0.068,
    "LP_rho": 0.2737,
    "SJ_auroc": 0.7092,
    "FK_auroc": 0.6469,
    "VC_auroc": 0.7533,
    "EM_auroc": 0.7306,
    "LP_auroc": 0.6325,
    "sel_SJ": 0.3584,
    "sel_FK": 0.3498,
    "sel_VC": 0.3715,
    "sel_EM": 0.3291,
    "sel_LP": 0.3606
  },
  "re_cond": {
    "n": 242,
    "SJ_rho": 0.3601,
    "FK_rho": 0.2343,
    "VC_rho": 0.3703,
    "EM_rho": 0.4613,
    "LP_rho": 0.1809
  }
}

=== exp_entity_construction ===
status: DONE
conclusion: success
metrics: {
  "n16_fair_cv": {
    "scierc_ner": {
      "cv_uniform_delta": "+1.35pp",
      "p_value": 0.018,
      "significant": true
    },
    "conll_ner": {
      "cv_uniform_delta": "+0.10pp",
      "p_value": 0.303,
      "significant": false
    },
    "fewnerd_ner": {
      "cv_uniform_delta": "+1.32pp",
      "p_value": 0,
      "significant": true
    },
    "scierc_re": {
      "cv_uniform_delta": "+1.69pp",
      "p_value": 0.049,
      "significant": true
    }
  },
  "n8_fair_cv": {
    "scierc_ner": {
      "uniform_confirm": "+1.54pp (p=0.023, sig)",
      "lp_weighted_confirm": "+1.67pp (p=0.004, sig)",
      "cv_uniform": "+1.12pp (p=0.057, borderline)"
    },
    "conll_ner": {
      "cv_uniform": "-0.39pp (p=0.963, not sig)"
    },
    "fewnerd_ner": {
      "lp_weighted_cv": "+0.88pp (p=0.000, sig)",
      "uniform_cv": "+0.32pp (p=0.003, sig)"
    }
  },
  "adaptive_combination": "INVALIDATED - gold label leakage confirmed",
  "note": "5-fold CV, bootstrap B=10000, paired one-sided"
}

=== exp_qwen25_72b_zeroshot ===
status: RUNNING

=== exp_freeform_ablation ===
status: DONE
conclusion: negative
metrics: {
  "lp_std_ratio_free_vs_constrained": 0.97,
  "lp_range_ratio": 0.96,
  "tied_fraction_constrained": 0.597,
  "tied_fraction_freeform": 0.577,
  "ner_selection_gap_constrained": 0.0059,
  "ner_selection_gap_freeform": 0.0018,
  "re_selection_gap_constrained": -0.0068,
  "re_selection_gap_freeform": 0.0169,
  "parse_rate": 0.9995,
  "ner_vc_rho_constrained": 0.3792,
  "ner_vc_rho_freeform": 0.4089
}

=== exp_001_ner_n16_scierc ===
status: DONE
conclusion: success
metrics: {
  "n_instances": 551,
  "ner_n": 529,
  "re_n": 397,
  "N": 16,
  "T": 1,
  "seed": 42,
  "full_test_set": true,
  "ner_voting_conf_rho": 0.399,
  "ner_sj_rho": 0.398,
  "ner_em_rho": 0.339,
  "ner_fk_rho": 0.288,
  "ner_logprob_rho": 0.237,
  "ner_voting_conf_auroc": 0.704,
  "ner_sj_auroc": 0.697,
  "ner_cond_em_rho": 0.414,
  "ner_cond_sj_rho": 0.349,
  "ner_cond_vc_rho": 0.34,
  "re_voting_conf_rho": 0.38,
  "re_logprob_rho": 0.293,
  "re_fk_rho": 0.281,
  "re_sj_rho": 0.277,
  "re_em_rho": 0.148,
  "re_voting_conf_auroc": 0.699,
  "re_cond_em_rho": 0.475,
  "re_cond_sj_rho": 0.318,
  "re_cond_vc_rho": 0.35,
  "re_cond_em_auroc": 0.742,
  "diagnosis": "551 instances T=1.0: voting_conf best on full set (NER 0.399, RE 0.380). EM SURPRISE best on conditional set (NER cond 0.414, RE cond 0.475). RE full FAIL (SJ 0.277 < 0.40). Previous N-scaling 'breakthrough' was artifact of 200 instances + T=0.7."
}

=== exp_012_logprob_baseline ===
status: DONE
conclusion: success
metrics: {
  "ner_full_rho_sj": 0.3565,
  "ner_full_rho_fk": 0.2651,
  "ner_full_rho_logprob": 0.1396,
  "ner_full_rho_greedy_logprob": 0.1615,
  "ner_full_tau_sj": 0.2658,
  "ner_full_tau_logprob": 0.1006,
  "ner_full_auroc_sj": 0.6892,
  "ner_full_auroc_fk": 0.6292,
  "ner_full_auroc_logprob": 0.5907,
  "ner_full_n": 529,
  "ner_sj_vs_logprob_delta": 0.2169,
  "re_full_rho_sj": 0.2112,
  "re_full_rho_fk": 0.2528,
  "re_full_rho_logprob": 0.2467,
  "re_full_auroc_sj": 0.5916,
  "re_full_auroc_fk": 0.6262,
  "re_full_auroc_logprob": 0.6186,
  "re_full_n": 397,
  "re_cond_rho_sj": 0.3683,
  "re_cond_rho_fk": 0.3168,
  "re_cond_rho_logprob": 0.1457,
  "re_cond_auroc_sj": 0.6839,
  "re_cond_auroc_logprob": 0.5487,
  "re_cond_n": 296,
  "diagnosis": "NER: SJ crushes logprob (rho +0.217). RE full: logprob slightly ahead. RE cond: SJ crushes logprob (rho +0.223). SJ unique value CONFIRMED."
}

=== exp_qwen3_4b_scierc_scs_inference ===
status: DONE
conclusion: success
metrics: {
  "ner_greedy_f1": 0.6612,
  "ner_oracle_f1": 0.7839,
  "ner_headroom_pp": 12.28,
  "ner_SJ_rho": 0.4221,
  "ner_FK_rho": 0.3258,
  "ner_LP_rho": 0.28,
  "re_greedy_f1": 0.4136,
  "re_oracle_f1": 0.5846,
  "re_headroom_pp": 17.1,
  "re_SJ_rho": 0.2673,
  "re_FK_rho": 0.3593,
  "re_LP_rho": 0.3512,
  "re_sample_f1_pct_zero": 0.476,
  "re_LP_rho_cond": 0.1135,
  "re_LP_rho_cond_p": 0.074,
  "degen_rate": 0.104,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered"
}

=== exp_qwen3_4b_conll_scs_inference_v2 ===
status: DONE
conclusion: success
metrics: {
  "greedy_f1": 0.9234,
  "oracle_f1": 0.9404,
  "oracle_headroom_pp": 1.7,
  "SJ_rho_full": 0.4217,
  "SJ_rho_cond": 0.459,
  "FK_rho_full": 0.4181,
  "FK_rho_cond": 0.4538,
  "LP_rho_full": 0.3313,
  "LP_rho_cond": 0.3487,
  "LP_auroc_full": 0.7761,
  "LP_auroc_cond": 0.8209,
  "n_instances": 3453,
  "verdict": "MARGINAL",
  "degen_rate": 0.9057,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered"
}

=== exp_llama_fewnerd_inference ===
status: DONE
conclusion: success
metrics: {
  "3seed_mean": {
    "greedy_f1": 0.7842,
    "oracle_f1": 0.8843,
    "headroom_pp": 10.01,
    "degeneracy_pct": 23.36,
    "lp_delta_pp": 0.36,
    "dgs_delta_pp": -0.35
  },
  "seed_42": {
    "greedy_f1": 0.7841,
    "oracle_f1": 0.8854,
    "degen": 27.32
  },
  "seed_123": {
    "greedy_f1": 0.784,
    "oracle_f1": 0.8839,
    "degen": 24.63
  },
  "seed_456": {
    "greedy_f1": 0.7844,
    "oracle_f1": 0.8835,
    "degen": 18.13
  },
  "signal_ranking": "LP (+0.36pp) > SJ (-0.52) > FK (-0.53) > EM (-1.02) > VC (-2.39)",
  "lp_only_positive": true,
  "n_instances_gold_filtered": 32565
}

=== exp_selective_prediction ===
status: DONE
conclusion: success
metrics: {
  "vc_best_signal": true,
  "f1_at_80pct_coverage": {
    "scierc": "+5.0pp",
    "conll": "+8.4pp",
    "fewnerd": "+6.2pp"
  },
  "precision_coverage_curves": "output/prescriptive_analysis/fig_selective_prediction.pdf"
}

=== exp_lp_alignment_gating ===
status: DONE
conclusion: success
metrics: {
  "adjusted_score": "mean_rho * valid_ratio",
  "threshold": 0.3,
  "accuracy": "3/3 datasets correct",
  "robust_range": "0.2-0.4"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "ba886997-d6fe-4e19-9032-79f6625b619c",
  "tool_use_result": {
    "stdout": "=== exp_012_rerun_1024 ===\nstatus: DONE\nconclusion: success\nmetrics: {\n  \"degen_rate\": 0.1777,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\",\n  \"ner_full\": {\n    \"n\": 529,\n    \"SJ\": {\n      \"rho\": 0.3599,\n      \"tau\": 0.2646,\n      \"AUROC\": 0.6917,\n      \"ECE\": 0.4531,\n      \"rho_ci95\": [\n        0.2732,\n        0.4389\n      ],\n      \"AUROC_ci95\": [\n        0.6304,\n        0.7406\n      ]\n    },\n    \"FK\": {\n      \"rho\": 0.2665,\n      \"tau\": 0.1974,\n      \"AUROC\": 0.629,\n      \"ECE\": 0.4512,\n      \"rho_ci95\": [\n        0.1743,\n        0.3486\n      ],\n      \"AUROC_ci95\": [\n        0.5612,\n        0.6882\n      ]\n    },\n    \"logprob\": {\n      \"rho\": 0.2052,\n      \"tau\": 0.1478,\n      \"AUROC\": 0.5783,\n      \"ECE\": 0.7064,\n      \"rho_ci95\": [\n        0.1171,\n        0.2904\n      ],\n      \"AUROC_ci95\": [\n        0.5179,\n        0.6387\n      ]\n    },\n    \"EM\": {\n      \"rho\": 0.2945,\n      \"tau\": 0.2208,\n      \"AUROC\": 0.7493,\n      \"ECE\": 0.3526,\n      \"rho_ci95\": [\n        0.2094,\n        0.37\n      ],\n      \"AUROC_ci95\": [\n        0.7002,\n        0.7928\n      ]\n    },\n    \"voting_conf\": {\n      \"rho\": 0.3792,\n      \"tau\": 0.2805,\n      \"AUROC\": 0.6841,\n      \"ECE\": 0.3807,\n      \"rho_ci95\": [\n        0.2972,\n        0.4486\n      ],\n      \"AUROC_ci95\": [\n        0.6249,\n        0.7366\n      ]\n    }\n  },\n  \"ner_cond\": {\n    \"n\": 477,\n    \"SJ\": {\n      \"rho\": 0.3113,\n      \"tau\": 0.2257,\n      \"AUROC\": 0.6772,\n      \"ECE\": 0.4416,\n      \"rho_ci95\": [\n        0.2353,\n        0.3959\n      ],\n      \"AUROC_ci95\": [\n        0.621,\n        0.7337\n      ]\n    },\n    \"FK\": {\n      \"rho\": 0.1761,\n      \"tau\": 0.1284,\n      \"AUROC\": 0.6078,\n      \"ECE\": 0.4389,\n      \"rho_ci95\": [\n        0.0839,\n        0.2665\n      ],\n      \"AUROC_ci95\": [\n        0.5442,\n        0.6709\n      ]\n    },\n    \"logprob\": {\n      \"rho\": 0.1538,\n      \"tau\": 0.1111,\n      \"AUROC\": 0.5633,\n      \"ECE\": 0.6803,\n      \"rho_ci95\": [\n        0.0637,\n        0.2424\n      ],\n      \"AUROC_ci95\": [\n        0.5032,\n        0.6232\n      ]\n    },\n    \"EM\": {\n      \"\n\n=== exp_016_rerun_1024_bootstrap ===\nstatus: DONE\nconclusion: negative\nmetrics: {\n  \"bootstrap_ci_95\": [\n    -0.03,\n    0.042\n  ],\n  \"permutation_p\": 0.39,\n  \"cohen_d\": 0.038,\n  \"sign_test_win_rate\": 0.466,\n  \"ner_logprob_vs_greedy_delta\": 0.006,\n  \"conclusion_summary\": \"NER selection: no signal significantly outperforms greedy; RE: same conclusion\"\n}\n\n=== exp_016_signal_ensemble ===\nstatus: DONE\nconclusion: success\nmetrics: {\n  \"sj_logprob_pearson_ner\": 0.57,\n  \"sj_logprob_pearson_re\": 0.42,\n  \"best_linear_ner\": {\n    \"combo\": \"SJ+voting_conf\",\n    \"alpha\": 0.3,\n    \"rho\": 0.489\n  },\n  \"best_linear_re\": {\n    \"combo\": \"voting_conf+logprob\",\n    \"alpha\": 0.6,\n    \"rho\": 0.429\n  },\n  \"ensemble_ner_auroc\": 0.735,\n  \"ensemble_re_auroc\": 0.719,\n  \"best_single_ner_auroc\": 0.7,\n  \"best_single_re_auroc\": 0.721,\n  \"ensemble_ner_delta\": 0.035,\n  \"selection_f1_ner\": {\n    \"greedy\": 0.609,\n    \"logprob\": 0.609,\n    \"sj\": 0.604,\n    \"ensemble\": 0.604,\n    \"voting\": 0.596,\n    \"random\": 0.58,\n    \"oracle\": 0.769\n  },\n  \"selection_f1_re\": {\n    \"logprob\": 0.397,\n    \"greedy\": 0.374,\n    \"sj\": 0.368,\n    \"ensemble\": 0.367,\n    \"voting\": 0.338,\n    \"random\": 0.338,\n    \"oracle\": 0.561\n  },\n  \"diagnosis\": \"SJ+voting_conf linear combo boosts NER \\u03c1 to 0.489 (+23%). RE: logprob-best is ONLY method beating greedy (0.397 vs 0.374). Ensemble AUROC +0.035 on NER. Oracle gap still huge.\"\n}\n\n=== exp_021_fewnerd_full ===\nstatus: DONE\nconclusion: success\nmetrics: {\n  \"total_steps\": 6177,\n  \"train_loss\": 0.048,\n  \"eval_loss\": 0.0275,\n  \"train_runtime\": \"3h57m\",\n  \"epochs\": 3,\n  \"final_checkpoint\": \"output/exp_021_fewnerd_full/checkpoint-6177\",\n  \"adapter_path\": \"output/exp_021_fewnerd_full/adapter_model.safetensors\",\n  \"inference_instances\": 37648,\n  \"inference_filtered\": 32565,\n  \"inference_n_samples\": 8,\n  \"greedy_macro_f1\": 0.7478,\n  \"oracle_macro_f1\": 0.8719,\n  \"headroom\": 0.124,\n  \"zero_f1_rate\": 0.119,\n  \"degeneracy_rate\": 0.101,\n  \"lp_within_range_mean\": 0.0879,\n  \"lp_within_range_median\": 0.0662,\n  \"lp_global_rho\": 0.4215,\n  \"lp_cond_rho\": 0.4225,\n  \"sj_global_rho\": 0.3002,\n  \"sj_cond_rho\": 0.2937,\n  \"fk_global_rho\": 0.3132,\n  \"fk_cond_rho\": 0.3093,\n  \"em_global_rho\": 0.2871,\n  \"em_cond_rho\": 0.271,\n  \"vc_global_rho\": 0.3858,\n  \"vc_cond_rho\": 0.3234,\n  \"lp_selection_delta_pp\": 1.36,\n  \"vc_selection_delta_pp\": -1.79,\n  \"sj_selection_delta_pp\": -2.14,\n  \"fk_selection_delta_pp\": -2.26,\n  \"em_selection_delta_pp\": -3.85,\n  \"lp_bootstrap_ci_95_pp\": [\n    1.18,\n    1.53\n  ],\n  \"lp_sample_auroc\": 0.5782,\n  \"vc_sample_auroc\": 0.5354,\n  \"fk_sample_auroc\": 0.521,\n  \"sj_sample_auroc\": 0.5197,\n  \"em_sample_auroc\": 0.5137,\n  \"scenario\": \"A_partial\",\n  \"note\": \"Full analysis (gold-filtered n=32565). Prior simplified analysis used unfiltered data with different metrics.\"\n}\n\n=== exp_023_lora_rank8 ===\nstatus: DONE\nconclusion: success\nmetrics: {\n  \"train_loss\": 0.1018,\n  \"eval_loss\": 0.0776,\n  \"train_runtime\": \"28m45s\",\n  \"ner_full\": {\n    \"n\": 529,\n    \"greedy_f1\": 0.6397,\n    \"oracle_f1\": 0.7998,\n    \"oracle_headroom\": 0.1601,\n    \"degeneracy_rate\": 0.072,\n    \"SJ_rho\": 0.3649,\n    \"FK_rho\": 0.2838,\n    \"VC_rho\": 0.394,\n    \"EM_rho\": 0.2562,\n    \"LP_rho\": 0.2105,\n    \"SJ_auroc\": 0.689,\n    \"FK_auroc\": 0.6002,\n    \"VC_auroc\": 0.6886,\n    \"EM_auroc\": 0.7265,\n    \"LP_auroc\": 0.6054,\n    \"sel_SJ\": 0.6306,\n    \"sel_FK\": 0.6265,\n    \"sel_VC\": 0.5919,\n    \"sel_EM\": 0.6073,\n    \"sel_LP\": 0.635\n  },\n  \"ner_cond\": {\n    \"n\": 477,\n    \"SJ_rho\": 0.3056,\n    \"FK_rho\": 0.1452,\n    \"VC_rho\": 0.3191,\n    \"EM_rho\": 0.3558,\n    \"LP_rho\": 0.169\n  },\n  \"re_full\": {\n    \"n\": 397,\n    \"greedy_f1\": 0.3712,\n    \"oracle_f1\": 0.609,\n    \"oracle_headroom\": 0.2378,\n    \"degeneracy_rate\": 0.217,\n    \"SJ_rho\": 0.2244,\n    \"FK_rho\": 0.3448,\n    \"VC_rho\": 0.3617,\n    \"EM_rho\": 0.068,\n    \"LP_rho\": 0.2737,\n    \"SJ_auroc\": 0.7092,\n    \"FK_auroc\": 0.6469,\n    \"VC_auroc\": 0.7533,\n    \"EM_auroc\": 0.7306,\n    \"LP_auroc\": 0.6325,\n    \"sel_SJ\": 0.3584,\n    \"sel_FK\": 0.3498,\n    \"sel_VC\": 0.3715,\n    \"sel_EM\": 0.3291,\n    \"sel_LP\": 0.3606\n  },\n  \"re_cond\": {\n    \"n\": 242,\n    \"SJ_rho\": 0.3601,\n    \"FK_rho\": 0.2343,\n    \"VC_rho\": 0.3703,\n    \"EM_rho\": 0.4613,\n    \"LP_rho\": 0.1809\n  }\n}\n\n=== exp_entity_construction ===\nstatus: DONE\nconclusion: success\nmetrics: {\n  \"n16_fair_cv\": {\n    \"scierc_ner\": {\n      \"cv_uniform_delta\": \"+1.35pp\",\n      \"p_value\": 0.018,\n      \"significant\": true\n    },\n    \"conll_ner\": {\n      \"cv_uniform_delta\": \"+0.10pp\",\n      \"p_value\": 0.303,\n      \"significant\": false\n    },\n    \"fewnerd_ner\": {\n      \"cv_uniform_delta\": \"+1.32pp\",\n      \"p_value\": 0,\n      \"significant\": true\n    },\n    \"scierc_re\": {\n      \"cv_uniform_delta\": \"+1.69pp\",\n      \"p_value\": 0.049,\n      \"significant\": true\n    }\n  },\n  \"n8_fair_cv\": {\n    \"scierc_ner\": {\n      \"uniform_confirm\": \"+1.54pp (p=0.023, sig)\",\n      \"lp_weighted_confirm\": \"+1.67pp (p=0.004, sig)\",\n      \"cv_uniform\": \"+1.12pp (p=0.057, borderline)\"\n    },\n    \"conll_ner\": {\n      \"cv_uniform\": \"-0.39pp (p=0.963, not sig)\"\n    },\n    \"fewnerd_ner\": {\n      \"lp_weighted_cv\": \"+0.88pp (p=0.000, sig)\",\n      \"uniform_cv\": \"+0.32pp (p=0.003, sig)\"\n    }\n  },\n  \"adaptive_combination\": \"INVALIDATED - gold label leakage confirmed\",\n  \"note\": \"5-fold CV, bootstrap B=10000, paired one-sided\"\n}\n\n=== exp_qwen25_72b_zeroshot ===\nstatus: RUNNING\n\n=== exp_freeform_ablation ===\nstatus: DONE\nconclusion: negative\nmetrics: {\n  \"lp_std_ratio_free_vs_constrained\": 0.97,\n  \"lp_range_ratio\": 0.96,\n  \"tied_fraction_constrained\": 0.597,\n  \"tied_fraction_freeform\": 0.577,\n  \"ner_selection_gap_constrained\": 0.0059,\n  \"ner_selection_gap_freeform\": 0.0018,\n  \"re_selection_gap_constrained\": -0.0068,\n  \"re_selection_gap_freeform\": 0.0169,\n  \"parse_rate\": 0.9995,\n  \"ner_vc_rho_constrained\": 0.3792,\n  \"ner_vc_rho_freeform\": 0.4089\n}\n\n=== exp_001_ner_n16_scierc ===\nstatus: DONE\nconclusion: success\nmetrics: {\n  \"n_instances\": 551,\n  \"ner_n\": 529,\n  \"re_n\": 397,\n  \"N\": 16,\n  \"T\": 1,\n  \"seed\": 42,\n  \"full_test_set\": true,\n  \"ner_voting_conf_rho\": 0.399,\n  \"ner_sj_rho\": 0.398,\n  \"ner_em_rho\": 0.339,\n  \"ner_fk_rho\": 0.288,\n  \"ner_logprob_rho\": 0.237,\n  \"ner_voting_conf_auroc\": 0.704,\n  \"ner_sj_auroc\": 0.697,\n  \"ner_cond_em_rho\": 0.414,\n  \"ner_cond_sj_rho\": 0.349,\n  \"ner_cond_vc_rho\": 0.34,\n  \"re_voting_conf_rho\": 0.38,\n  \"re_logprob_rho\": 0.293,\n  \"re_fk_rho\": 0.281,\n  \"re_sj_rho\": 0.277,\n  \"re_em_rho\": 0.148,\n  \"re_voting_conf_auroc\": 0.699,\n  \"re_cond_em_rho\": 0.475,\n  \"re_cond_sj_rho\": 0.318,\n  \"re_cond_vc_rho\": 0.35,\n  \"re_cond_em_auroc\": 0.742,\n  \"diagnosis\": \"551 instances T=1.0: voting_conf best on full set (NER 0.399, RE 0.380). EM SURPRISE best on conditional set (NER cond 0.414, RE cond 0.475). RE full FAIL (SJ 0.277 < 0.40). Previous N-scaling 'breakthrough' was artifact of 200 instances + T=0.7.\"\n}\n\n=== exp_012_logprob_baseline ===\nstatus: DONE\nconclusion: success\nmetrics: {\n  \"ner_full_rho_sj\": 0.3565,\n  \"ner_full_rho_fk\": 0.2651,\n  \"ner_full_rho_logprob\": 0.1396,\n  \"ner_full_rho_greedy_logprob\": 0.1615,\n  \"ner_full_tau_sj\": 0.2658,\n  \"ner_full_tau_logprob\": 0.1006,\n  \"ner_full_auroc_sj\": 0.6892,\n  \"ner_full_auroc_fk\": 0.6292,\n  \"ner_full_auroc_logprob\": 0.5907,\n  \"ner_full_n\": 529,\n  \"ner_sj_vs_logprob_delta\": 0.2169,\n  \"re_full_rho_sj\": 0.2112,\n  \"re_full_rho_fk\": 0.2528,\n  \"re_full_rho_logprob\": 0.2467,\n  \"re_full_auroc_sj\": 0.5916,\n  \"re_full_auroc_fk\": 0.6262,\n  \"re_full_auroc_logprob\": 0.6186,\n  \"re_full_n\": 397,\n  \"re_cond_rho_sj\": 0.3683,\n  \"re_cond_rho_fk\": 0.3168,\n  \"re_cond_rho_logprob\": 0.1457,\n  \"re_cond_auroc_sj\": 0.6839,\n  \"re_cond_auroc_logprob\": 0.5487,\n  \"re_cond_n\": 296,\n  \"diagnosis\": \"NER: SJ crushes logprob (rho +0.217). RE full: logprob slightly ahead. RE cond: SJ crushes logprob (rho +0.223). SJ unique value CONFIRMED.\"\n}\n\n=== exp_qwen3_4b_scierc_scs_inference ===\nstatus: DONE\nconclusion: success\nmetrics: {\n  \"ner_greedy_f1\": 0.6612,\n  \"ner_oracle_f1\": 0.7839,\n  \"ner_headroom_pp\": 12.28,\n  \"ner_SJ_rho\": 0.4221,\n  \"ner_FK_rho\": 0.3258,\n  \"ner_LP_rho\": 0.28,\n  \"re_greedy_f1\": 0.4136,\n  \"re_oracle_f1\": 0.5846,\n  \"re_headroom_pp\": 17.1,\n  \"re_SJ_rho\": 0.2673,\n  \"re_FK_rho\": 0.3593,\n  \"re_LP_rho\": 0.3512,\n  \"re_sample_f1_pct_zero\": 0.476,\n  \"re_LP_rho_cond\": 0.1135,\n  \"re_LP_rho_cond_p\": 0.074,\n  \"degen_rate\": 0.104,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"\n}\n\n=== exp_qwen3_4b_conll_scs_inference_v2 ===\nstatus: DONE\nconclusion: success\nmetrics: {\n  \"greedy_f1\": 0.9234,\n  \"oracle_f1\": 0.9404,\n  \"oracle_headroom_pp\": 1.7,\n  \"SJ_rho_full\": 0.4217,\n  \"SJ_rho_cond\": 0.459,\n  \"FK_rho_full\": 0.4181,\n  \"FK_rho_cond\": 0.4538,\n  \"LP_rho_full\": 0.3313,\n  \"LP_rho_cond\": 0.3487,\n  \"LP_auroc_full\": 0.7761,\n  \"LP_auroc_cond\": 0.8209,\n  \"n_instances\": 3453,\n  \"verdict\": \"MARGINAL\",\n  \"degen_rate\": 0.9057,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"\n}\n\n=== exp_llama_fewnerd_inference ===\nstatus: DONE\nconclusion: success\nmetrics: {\n  \"3seed_mean\": {\n    \"greedy_f1\": 0.7842,\n    \"oracle_f1\": 0.8843,\n    \"headroom_pp\": 10.01,\n    \"degeneracy_pct\": 23.36,\n    \"lp_delta_pp\": 0.36,\n    \"dgs_delta_pp\": -0.35\n  },\n  \"seed_42\": {\n    \"greedy_f1\": 0.7841,\n    \"oracle_f1\": 0.8854,\n    \"degen\": 27.32\n  },\n  \"seed_123\": {\n    \"greedy_f1\": 0.784,\n    \"oracle_f1\": 0.8839,\n    \"degen\": 24.63\n  },\n  \"seed_456\": {\n    \"greedy_f1\": 0.7844,\n    \"oracle_f1\": 0.8835,\n    \"degen\": 18.13\n  },\n  \"signal_ranking\": \"LP (+0.36pp) > SJ (-0.52) > FK (-0.53) > EM (-1.02) > VC (-2.39)\",\n  \"lp_only_positive\": true,\n  \"n_instances_gold_filtered\": 32565\n}\n\n=== exp_selective_prediction ===\nstatus: DONE\nconclusion: success\nmetrics: {\n  \"vc_best_signal\": true,\n  \"f1_at_80pct_coverage\": {\n    \"scierc\": \"+5.0pp\",\n    \"conll\": \"+8.4pp\",\n    \"fewnerd\": \"+6.2pp\"\n  },\n  \"precision_coverage_curves\": \"output/prescriptive_analysis/fig_selective_prediction.pdf\"\n}\n\n=== exp_lp_alignment_gating ===\nstatus: DONE\nconclusion: success\nmetrics: {\n  \"adjusted_score\": \"mean_rho * valid_ratio\",\n  \"threshold\": 0.3,\n  \"accuracy\": \"3/3 datasets correct\",\n  \"robust_range\": \"0.2-0.4\"\n}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---


### Assistant

_source line 53_

<details><summary>Logged reasoning block</summary>

```text
Now let me get some more experiment data, particularly the multi-seed entity construction results, the 72B data, the CoNLL selection data, and some additional cross-reference data.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "c3f13f9a-9883-4632-897e-74c96cc5e33b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018LiSbu2wsQpkFddF6d9dzL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6775,
      "cache_read_input_tokens": 60747,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6775
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

_source line 54_

<details open><summary>🔧 Tool call — Bash · `toolu_01T1Q4ygLrTdZwgKhcFxRjWb`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\ntargets = [\n    'exp_qwen25_72b_zeroshot', 'exp_018_llama_scierc_seed42_r1024',\n    'exp_018_llama_scierc_seed456_r1024', 'exp_018_llama_scierc_seed123',\n    'exp_017_llama_conll_n16_r1024', 'exp_017_llama_conll_n16_s456_r1024',\n    'exp_002_conll_n16_r1024', 'exp_002_conll_n16',\n    'exp_006_v2', 'exp_001_seed42_v2_r1024',\n    'exp_021_fewnerd_n8_seed456', 'exp_021_fewnerd_n8_seed123',\n    'exp_fewnerd_s789_n8', 'exp_003_wnut17_v2',\n    'exp_wnut17_qwen25_7b'\n]\nfor t in targets:\n    if t in exps:\n        e = exps[t]\n        print(f'=== {t} ===')\n        print(f'status: {e.get(\\\"status\\\",\\\"?\\\")}')\n        m = e.get('metrics', {})\n        if m:\n            ms = json.dumps(m, indent=2)\n            print(f'metrics: {ms[:2000]}')\n        print()\n    else:\n        print(f'=== {t} === NOT FOUND')\n        print()\n\" 2>&1 | head -600\n",
  "description": "Extract more experiment data",
  "timeout": 30000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "5e6ce5c7-90de-4776-9930-16d9194d1fad",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018LiSbu2wsQpkFddF6d9dzL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6775,
      "cache_read_input_tokens": 60747,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6775
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

_source line 55 · 2026-05-19T13:34:50.285Z_

<details><summary>↩ Tool result · `toolu_01T1Q4ygLrTdZwgKhcFxRjWb`</summary>

```text
=== exp_qwen25_72b_zeroshot ===
status: RUNNING

=== exp_018_llama_scierc_seed42_r1024 ===
status: DONE
metrics: {
  "degen_rate": 0.2495,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered",
  "ner": {
    "full": {
      "SJ": {
        "rho": 0.3096,
        "tau": 0.2288,
        "auroc": 0.6683
      },
      "FK": {
        "rho": 0.2352,
        "tau": 0.1759,
        "auroc": 0.6069
      },
      "logprob": {
        "rho": 0.1503,
        "tau": 0.1087,
        "auroc": 0.5318
      },
      "EM": {
        "rho": 0.2587,
        "tau": 0.1966,
        "auroc": 0.7174
      },
      "voting_conf": {
        "rho": 0.4053,
        "tau": 0.3042,
        "auroc": 0.6967
      }
    },
    "conditional": {
      "SJ": {
        "rho": 0.2718,
        "tau": null,
        "auroc": 0.6565
      },
      "FK": {
        "rho": 0.1472,
        "tau": null,
        "auroc": 0.5866
      },
      "logprob": {
        "rho": 0.081,
        "tau": null,
        "auroc": 0.5129
      },
      "EM": {
        "rho": 0.3165,
        "tau": null,
        "auroc": 0.7244
      },
      "voting_conf": {
        "rho": 0.3078,
        "tau": null,
        "auroc": 0.6714
      }
    },
    "greedy_f1": 0.6607,
    "oracle_f1": 0.7781,
    "n_full": 529,
    "n_cond": 478
  },
  "re": {
    "full": {
      "SJ": {
        "rho": 0.2748,
        "tau": 0.2102,
        "auroc": 0.7244
      },
      "FK": {
        "rho": 0.3027,
        "tau": 0.2337,
        "auroc": 0.691
      },
      "logprob": {
        "rho": 0.3163,
        "tau": 0.233,
        "auroc": 0.6313
      },
      "EM": {
        "rho": 0.1681,
        "tau": 0.1275,
        "auroc": 0.7697
      },
      "voting_conf": {
        "rho": 0.384,
        "tau": 0.2965,
        "auroc": 0.7337
      }
    },
    "conditional": {
      "SJ": {
        "rho": 0.3461,
        "tau": null,
        "auroc": 0.7233
      },
      "FK": {
        "rho": 0.1969,
        "tau": null,
        "auroc": 0.6684
      },
      "logprob": {
        "rho": 0.0888,
        "tau": null,
        "auroc": 0.5556
      },
    

=== exp_018_llama_scierc_seed456_r1024 ===
status: DONE
metrics: {
  "degen_rate": 0.2741,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered",
  "ner_greedy_f1": 0.6597,
  "ner_oracle_f1": 0.7683,
  "ner_oracle_headroom": 0.1086,
  "ner_cond_rho_fk": 0.1472,
  "ner_cond_rho_sj": 0.2718,
  "ner_cond_rho_logprob": 0.083,
  "ner_logprob_auroc_cond": 0.5485,
  "re_greedy_f1": 0.4338,
  "re_oracle_f1": 0.5834,
  "re_oracle_headroom": 0.1496,
  "re_cond_rho_fk": 0.2107,
  "re_cond_rho_sj": 0.3898,
  "re_cond_rho_logprob": 0.1252,
  "re_logprob_auroc_cond": 0.6119,
  "ner_structural_beats_logprob": true,
  "re_structural_beats_logprob": true
}

=== exp_018_llama_scierc_seed123 ===
status: DONE
metrics: {
  "degen_rate": 0.2665,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered"
}

=== exp_017_llama_conll_n16_r1024 ===
status: DONE
metrics: {
  "degen_rate": 0.8647,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered",
  "instance_count": 3453,
  "n_valid": 2756,
  "n_gold_empty": 697,
  "parse_rate": 1,
  "ner_greedy_f1": 0.9265,
  "ner_oracle_f1": 0.9499,
  "rho_fk_ner": 0.4752,
  "rho_sj_ner": 0.4836,
  "rho_vc_ner": 0.4746,
  "rho_em_ner": 0.4818,
  "rho_lp_ner": 0.3136,
  "auroc_fk_ner": 0.7467,
  "auroc_sj_ner": 0.7496,
  "auroc_vc_ner": 0.7529,
  "auroc_em_ner": 0.7508,
  "auroc_lp_ner": 0.7661,
  "auroc_note": "median F1=1.0, AUROC uses >=median threshold",
  "rho_note": "CORRECTED 2026-05-15: old values (rho_fk=0.8095,rho_sj=0.1815) were inflated/deflated by 697 gold-empty instances. Now uses gold-filtered pipeline (n=2756)."
}

=== exp_017_llama_conll_n16_s456_r1024 ===
status: DONE
metrics: {
  "degen_rate": 0.8672,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered",
  "instance_count": 3453,
  "n_valid": 2756,
  "n_gold_empty": 697,
  "parse_rate": 1,
  "ner_greedy_f1": 0.9265,
  "ner_oracle_f1": 0.9499,
  "rho_fk_ner": 0.469,
  "rho_sj_ner": 0.4734,
  "rho_vc_ner": 0.4722,
  "rho_em_ner": 0.4752,
  "rho_lp_ner": 0.3099,
  "auroc_fk_ner": 0.7408,
  "auroc_sj_ner": 0.7428,
  "auroc_vc_ner": 0.7495,
  "auroc_em_ner": 0.7444,
  "auroc_lp_ner": 0.7628,
  "auroc_note": "median F1=1.0, AUROC uses >=median threshold",
  "rho_note": "CORRECTED 2026-05-15: old values (rho_fk=0.8085,rho_sj=0.1895) were inflated/deflated by 697 gold-empty instances. Now uses gold-filtered pipeline (n=2756)."
}

=== exp_002_conll_n16_r1024 ===
status: DONE

=== exp_002_conll_n16 ===
status: DONE
metrics: {
  "degen_rate": 0.4844,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered",
  "N": 16,
  "dataset": "conll2003",
  "subtask": "ner",
  "n_instances": 3453,
  "n_valid": 2756,
  "n_conditional": 2614,
  "greedy_f1": 0.907,
  "full": {
    "SJ_rho": 0.4496,
    "FK_rho": 0.3928,
    "logprob_rho": 0.3146,
    "EM_rho": 0.4627,
    "voting_conf_rho": 0.4286,
    "SJ_AUROC": 0.8264,
    "FK_AUROC": 0.7821,
    "logprob_AUROC": 0.7531,
    "EM_AUROC": 0.8409,
    "voting_conf_AUROC": 0.8071,
    "SJ_ECE": 0.0747,
    "FK_ECE": 0.1786,
    "logprob_ECE": 0.2031,
    "EM_ECE": 0.0786,
    "voting_conf_ECE": 0.529
  },
  "conditional": {
    "SJ_rho": 0.4208,
    "FK_rho": 0.3494,
    "logprob_rho": 0.3756,
    "EM_rho": 0.4658,
    "voting_conf_rho": 0.3654,
    "SJ_AUROC": 0.8405,
    "FK_AUROC": 0.7819,
    "logprob_AUROC": 0.8259,
    "EM_AUROC": 0.8781,
    "voting_conf_AUROC": 0.7951,
    "SJ_ECE": 0.0982,
    "FK_ECE": 0.1899,
    "logprob_ECE": 0.2504,
    "EM_ECE": 0.0997,
    "voting_conf_ECE": 0.6096
  },
  "n8_vs_n16_delta_rho_full": {
    "SJ": 0.0139,
    "FK": -0.007,
    "logprob": -0.0011,
    "EM": 0.012,
    "voting_conf": 0.0049
  }
}

=== exp_006_v2 ===
status: DONE
metrics: {
  "NER_SciERC_s42": {
    "greedy": 0.618,
    "oracle": 0.787,
    "SJ": 0.62,
    "logprob": 0.621,
    "FK": 0.621,
    "EM": 0.606,
    "voting_conf": 0.585,
    "random": 0.586
  },
  "NER_SciERC_s123": {
    "greedy": 0.618,
    "oracle": 0.785,
    "SJ": 0.617,
    "logprob": 0.618,
    "FK": 0.621,
    "EM": 0.613,
    "voting_conf": 0.584,
    "random": 0.583
  },
  "NER_CoNLL": {
    "greedy": 0.725,
    "oracle": 0.757,
    "SJ": 0.718,
    "logprob": 0.716,
    "FK": 0.717,
    "EM": 0.716,
    "voting_conf": 0.714,
    "random": 0.692
  },
  "RE_SciERC": {
    "greedy": 0.403,
    "oracle": 0.631,
    "SJ": 0.397,
    "logprob": 0.41,
    "FK": 0.396,
    "EM": 0.381,
    "voting_conf": 0.408,
    "random": 0.364
  }
}

=== exp_001_seed42_v2_r1024 ===
status: DONE
metrics: {
  "greedy_f1": 0.6647,
  "oracle_f1": 0.8106,
  "softjaccard_rho_full": 0.3928,
  "fleiss_rho_full": 0.2489,
  "logprob_rho_full": 0.2136,
  "softjaccard_rho_cond": 0.3455,
  "fleiss_rho_cond": 0.163,
  "logprob_rho_cond": 0.1624,
  "verdict": "MARGINAL"
}

=== exp_021_fewnerd_n8_seed456 ===
status: DONE
metrics: {
  "degen_rate": 0.1212,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered",
  "instance_count": 37648,
  "n_valid": 32565,
  "n_gold_empty": 5083,
  "ner_greedy_f1": 0.7888,
  "ner_oracle_f1": 0.881,
  "rho_fk_ner": 0.1632,
  "rho_sj_ner": 0.313,
  "sample_f1_pct_zero": 19.32
}

=== exp_021_fewnerd_n8_seed123 ===
status: DONE
metrics: {
  "degen_rate": 0.1312,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered",
  "instance_count": 37648,
  "n_valid": 32565,
  "n_gold_empty": 5083,
  "ner_greedy_f1": 0.7885,
  "ner_oracle_f1": 0.8892,
  "rho_fk_ner": 0.1602,
  "rho_sj_ner": 0.3083,
  "sample_f1_pct_zero": 20.39
}

=== exp_fewnerd_s789_n8 ===
status: DONE
metrics: {
  "greedy_f1": 0.7478,
  "oracle_f1": 0.8714,
  "headroom_pp": 12.37,
  "degen_rate": 0.1177,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered",
  "instance_count": 37648,
  "n_valid": 32565,
  "lp_sel_f1": 0.7614,
  "lp_delta_pp": 1.36,
  "lp_rho_global": 0.1788,
  "lp_rho_cond": 0.176,
  "dgs_f1": 0.7621,
  "dgs_delta_pp": 1.43,
  "dgs_vs_lp_pp": 0.07,
  "best_signal": "LP",
  "four_seed_mean_greedy": 0.7481,
  "four_seed_mean_lp_delta_pp": 1.38,
  "four_seed_lp_delta_ci95": [
    1.32,
    1.44
  ]
}

=== exp_003_wnut17_v2 ===
status: DONE

=== exp_wnut17_qwen25_7b ===
status: DONE
metrics: {
  "seed42": {
    "greedy_f1": 0.4524,
    "construction_f1": 0.4439,
    "construction_delta_pp": -0.84,
    "construction_p": 0.95
  },
  "seed123": {
    "greedy_f1": 0.4518,
    "construction_f1": 0.4579,
    "construction_delta_pp": 0.61,
    "construction_p": 0.08
  },
  "seed456": {
    "greedy_f1": 0.4526,
    "construction_f1": 0.4583,
    "construction_delta_pp": 0.57,
    "construction_p": 0.12
  },
  "oracle_headroom_pp": "6.3-9.2"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "aaa68810-e019-4087-85f0-eec7037a84d1",
  "tool_use_result": {
    "stdout": "=== exp_qwen25_72b_zeroshot ===\nstatus: RUNNING\n\n=== exp_018_llama_scierc_seed42_r1024 ===\nstatus: DONE\nmetrics: {\n  \"degen_rate\": 0.2495,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\",\n  \"ner\": {\n    \"full\": {\n      \"SJ\": {\n        \"rho\": 0.3096,\n        \"tau\": 0.2288,\n        \"auroc\": 0.6683\n      },\n      \"FK\": {\n        \"rho\": 0.2352,\n        \"tau\": 0.1759,\n        \"auroc\": 0.6069\n      },\n      \"logprob\": {\n        \"rho\": 0.1503,\n        \"tau\": 0.1087,\n        \"auroc\": 0.5318\n      },\n      \"EM\": {\n        \"rho\": 0.2587,\n        \"tau\": 0.1966,\n        \"auroc\": 0.7174\n      },\n      \"voting_conf\": {\n        \"rho\": 0.4053,\n        \"tau\": 0.3042,\n        \"auroc\": 0.6967\n      }\n    },\n    \"conditional\": {\n      \"SJ\": {\n        \"rho\": 0.2718,\n        \"tau\": null,\n        \"auroc\": 0.6565\n      },\n      \"FK\": {\n        \"rho\": 0.1472,\n        \"tau\": null,\n        \"auroc\": 0.5866\n      },\n      \"logprob\": {\n        \"rho\": 0.081,\n        \"tau\": null,\n        \"auroc\": 0.5129\n      },\n      \"EM\": {\n        \"rho\": 0.3165,\n        \"tau\": null,\n        \"auroc\": 0.7244\n      },\n      \"voting_conf\": {\n        \"rho\": 0.3078,\n        \"tau\": null,\n        \"auroc\": 0.6714\n      }\n    },\n    \"greedy_f1\": 0.6607,\n    \"oracle_f1\": 0.7781,\n    \"n_full\": 529,\n    \"n_cond\": 478\n  },\n  \"re\": {\n    \"full\": {\n      \"SJ\": {\n        \"rho\": 0.2748,\n        \"tau\": 0.2102,\n        \"auroc\": 0.7244\n      },\n      \"FK\": {\n        \"rho\": 0.3027,\n        \"tau\": 0.2337,\n        \"auroc\": 0.691\n      },\n      \"logprob\": {\n        \"rho\": 0.3163,\n        \"tau\": 0.233,\n        \"auroc\": 0.6313\n      },\n      \"EM\": {\n        \"rho\": 0.1681,\n        \"tau\": 0.1275,\n        \"auroc\": 0.7697\n      },\n      \"voting_conf\": {\n        \"rho\": 0.384,\n        \"tau\": 0.2965,\n        \"auroc\": 0.7337\n      }\n    },\n    \"conditional\": {\n      \"SJ\": {\n        \"rho\": 0.3461,\n        \"tau\": null,\n        \"auroc\": 0.7233\n      },\n      \"FK\": {\n        \"rho\": 0.1969,\n        \"tau\": null,\n        \"auroc\": 0.6684\n      },\n      \"logprob\": {\n        \"rho\": 0.0888,\n        \"tau\": null,\n        \"auroc\": 0.5556\n      },\n    \n\n=== exp_018_llama_scierc_seed456_r1024 ===\nstatus: DONE\nmetrics: {\n  \"degen_rate\": 0.2741,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\",\n  \"ner_greedy_f1\": 0.6597,\n  \"ner_oracle_f1\": 0.7683,\n  \"ner_oracle_headroom\": 0.1086,\n  \"ner_cond_rho_fk\": 0.1472,\n  \"ner_cond_rho_sj\": 0.2718,\n  \"ner_cond_rho_logprob\": 0.083,\n  \"ner_logprob_auroc_cond\": 0.5485,\n  \"re_greedy_f1\": 0.4338,\n  \"re_oracle_f1\": 0.5834,\n  \"re_oracle_headroom\": 0.1496,\n  \"re_cond_rho_fk\": 0.2107,\n  \"re_cond_rho_sj\": 0.3898,\n  \"re_cond_rho_logprob\": 0.1252,\n  \"re_logprob_auroc_cond\": 0.6119,\n  \"ner_structural_beats_logprob\": true,\n  \"re_structural_beats_logprob\": true\n}\n\n=== exp_018_llama_scierc_seed123 ===\nstatus: DONE\nmetrics: {\n  \"degen_rate\": 0.2665,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"\n}\n\n=== exp_017_llama_conll_n16_r1024 ===\nstatus: DONE\nmetrics: {\n  \"degen_rate\": 0.8647,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\",\n  \"instance_count\": 3453,\n  \"n_valid\": 2756,\n  \"n_gold_empty\": 697,\n  \"parse_rate\": 1,\n  \"ner_greedy_f1\": 0.9265,\n  \"ner_oracle_f1\": 0.9499,\n  \"rho_fk_ner\": 0.4752,\n  \"rho_sj_ner\": 0.4836,\n  \"rho_vc_ner\": 0.4746,\n  \"rho_em_ner\": 0.4818,\n  \"rho_lp_ner\": 0.3136,\n  \"auroc_fk_ner\": 0.7467,\n  \"auroc_sj_ner\": 0.7496,\n  \"auroc_vc_ner\": 0.7529,\n  \"auroc_em_ner\": 0.7508,\n  \"auroc_lp_ner\": 0.7661,\n  \"auroc_note\": \"median F1=1.0, AUROC uses >=median threshold\",\n  \"rho_note\": \"CORRECTED 2026-05-15: old values (rho_fk=0.8095,rho_sj=0.1815) were inflated/deflated by 697 gold-empty instances. Now uses gold-filtered pipeline (n=2756).\"\n}\n\n=== exp_017_llama_conll_n16_s456_r1024 ===\nstatus: DONE\nmetrics: {\n  \"degen_rate\": 0.8672,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\",\n  \"instance_count\": 3453,\n  \"n_valid\": 2756,\n  \"n_gold_empty\": 697,\n  \"parse_rate\": 1,\n  \"ner_greedy_f1\": 0.9265,\n  \"ner_oracle_f1\": 0.9499,\n  \"rho_fk_ner\": 0.469,\n  \"rho_sj_ner\": 0.4734,\n  \"rho_vc_ner\": 0.4722,\n  \"rho_em_ner\": 0.4752,\n  \"rho_lp_ner\": 0.3099,\n  \"auroc_fk_ner\": 0.7408,\n  \"auroc_sj_ner\": 0.7428,\n  \"auroc_vc_ner\": 0.7495,\n  \"auroc_em_ner\": 0.7444,\n  \"auroc_lp_ner\": 0.7628,\n  \"auroc_note\": \"median F1=1.0, AUROC uses >=median threshold\",\n  \"rho_note\": \"CORRECTED 2026-05-15: old values (rho_fk=0.8085,rho_sj=0.1895) were inflated/deflated by 697 gold-empty instances. Now uses gold-filtered pipeline (n=2756).\"\n}\n\n=== exp_002_conll_n16_r1024 ===\nstatus: DONE\n\n=== exp_002_conll_n16 ===\nstatus: DONE\nmetrics: {\n  \"degen_rate\": 0.4844,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\",\n  \"N\": 16,\n  \"dataset\": \"conll2003\",\n  \"subtask\": \"ner\",\n  \"n_instances\": 3453,\n  \"n_valid\": 2756,\n  \"n_conditional\": 2614,\n  \"greedy_f1\": 0.907,\n  \"full\": {\n    \"SJ_rho\": 0.4496,\n    \"FK_rho\": 0.3928,\n    \"logprob_rho\": 0.3146,\n    \"EM_rho\": 0.4627,\n    \"voting_conf_rho\": 0.4286,\n    \"SJ_AUROC\": 0.8264,\n    \"FK_AUROC\": 0.7821,\n    \"logprob_AUROC\": 0.7531,\n    \"EM_AUROC\": 0.8409,\n    \"voting_conf_AUROC\": 0.8071,\n    \"SJ_ECE\": 0.0747,\n    \"FK_ECE\": 0.1786,\n    \"logprob_ECE\": 0.2031,\n    \"EM_ECE\": 0.0786,\n    \"voting_conf_ECE\": 0.529\n  },\n  \"conditional\": {\n    \"SJ_rho\": 0.4208,\n    \"FK_rho\": 0.3494,\n    \"logprob_rho\": 0.3756,\n    \"EM_rho\": 0.4658,\n    \"voting_conf_rho\": 0.3654,\n    \"SJ_AUROC\": 0.8405,\n    \"FK_AUROC\": 0.7819,\n    \"logprob_AUROC\": 0.8259,\n    \"EM_AUROC\": 0.8781,\n    \"voting_conf_AUROC\": 0.7951,\n    \"SJ_ECE\": 0.0982,\n    \"FK_ECE\": 0.1899,\n    \"logprob_ECE\": 0.2504,\n    \"EM_ECE\": 0.0997,\n    \"voting_conf_ECE\": 0.6096\n  },\n  \"n8_vs_n16_delta_rho_full\": {\n    \"SJ\": 0.0139,\n    \"FK\": -0.007,\n    \"logprob\": -0.0011,\n    \"EM\": 0.012,\n    \"voting_conf\": 0.0049\n  }\n}\n\n=== exp_006_v2 ===\nstatus: DONE\nmetrics: {\n  \"NER_SciERC_s42\": {\n    \"greedy\": 0.618,\n    \"oracle\": 0.787,\n    \"SJ\": 0.62,\n    \"logprob\": 0.621,\n    \"FK\": 0.621,\n    \"EM\": 0.606,\n    \"voting_conf\": 0.585,\n    \"random\": 0.586\n  },\n  \"NER_SciERC_s123\": {\n    \"greedy\": 0.618,\n    \"oracle\": 0.785,\n    \"SJ\": 0.617,\n    \"logprob\": 0.618,\n    \"FK\": 0.621,\n    \"EM\": 0.613,\n    \"voting_conf\": 0.584,\n    \"random\": 0.583\n  },\n  \"NER_CoNLL\": {\n    \"greedy\": 0.725,\n    \"oracle\": 0.757,\n    \"SJ\": 0.718,\n    \"logprob\": 0.716,\n    \"FK\": 0.717,\n    \"EM\": 0.716,\n    \"voting_conf\": 0.714,\n    \"random\": 0.692\n  },\n  \"RE_SciERC\": {\n    \"greedy\": 0.403,\n    \"oracle\": 0.631,\n    \"SJ\": 0.397,\n    \"logprob\": 0.41,\n    \"FK\": 0.396,\n    \"EM\": 0.381,\n    \"voting_conf\": 0.408,\n    \"random\": 0.364\n  }\n}\n\n=== exp_001_seed42_v2_r1024 ===\nstatus: DONE\nmetrics: {\n  \"greedy_f1\": 0.6647,\n  \"oracle_f1\": 0.8106,\n  \"softjaccard_rho_full\": 0.3928,\n  \"fleiss_rho_full\": 0.2489,\n  \"logprob_rho_full\": 0.2136,\n  \"softjaccard_rho_cond\": 0.3455,\n  \"fleiss_rho_cond\": 0.163,\n  \"logprob_rho_cond\": 0.1624,\n  \"verdict\": \"MARGINAL\"\n}\n\n=== exp_021_fewnerd_n8_seed456 ===\nstatus: DONE\nmetrics: {\n  \"degen_rate\": 0.1212,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\",\n  \"instance_count\": 37648,\n  \"n_valid\": 32565,\n  \"n_gold_empty\": 5083,\n  \"ner_greedy_f1\": 0.7888,\n  \"ner_oracle_f1\": 0.881,\n  \"rho_fk_ner\": 0.1632,\n  \"rho_sj_ner\": 0.313,\n  \"sample_f1_pct_zero\": 19.32\n}\n\n=== exp_021_fewnerd_n8_seed123 ===\nstatus: DONE\nmetrics: {\n  \"degen_rate\": 0.1312,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\",\n  \"instance_count\": 37648,\n  \"n_valid\": 32565,\n  \"n_gold_empty\": 5083,\n  \"ner_greedy_f1\": 0.7885,\n  \"ner_oracle_f1\": 0.8892,\n  \"rho_fk_ner\": 0.1602,\n  \"rho_sj_ner\": 0.3083,\n  \"sample_f1_pct_zero\": 20.39\n}\n\n=== exp_fewnerd_s789_n8 ===\nstatus: DONE\nmetrics: {\n  \"greedy_f1\": 0.7478,\n  \"oracle_f1\": 0.8714,\n  \"headroom_pp\": 12.37,\n  \"degen_rate\": 0.1177,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\",\n  \"instance_count\": 37648,\n  \"n_valid\": 32565,\n  \"lp_sel_f1\": 0.7614,\n  \"lp_delta_pp\": 1.36,\n  \"lp_rho_global\": 0.1788,\n  \"lp_rho_cond\": 0.176,\n  \"dgs_f1\": 0.7621,\n  \"dgs_delta_pp\": 1.43,\n  \"dgs_vs_lp_pp\": 0.07,\n  \"best_signal\": \"LP\",\n  \"four_seed_mean_greedy\": 0.7481,\n  \"four_seed_mean_lp_delta_pp\": 1.38,\n  \"four_seed_lp_delta_ci95\": [\n    1.32,\n    1.44\n  ]\n}\n\n=== exp_003_wnut17_v2 ===\nstatus: DONE\n\n=== exp_wnut17_qwen25_7b ===\nstatus: DONE\nmetrics: {\n  \"seed42\": {\n    \"greedy_f1\": 0.4524,\n    \"construction_f1\": 0.4439,\n    \"construction_delta_pp\": -0.84,\n    \"construction_p\": 0.95\n  },\n  \"seed123\": {\n    \"greedy_f1\": 0.4518,\n    \"construction_f1\": 0.4579,\n    \"construction_delta_pp\": 0.61,\n    \"construction_p\": 0.08\n  },\n  \"seed456\": {\n    \"greedy_f1\": 0.4526,\n    \"construction_f1\": 0.4583,\n    \"construction_delta_pp\": 0.57,\n    \"construction_p\": 0.12\n  },\n  \"oracle_headroom_pp\": \"6.3-9.2\"\n}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---


### Assistant

_source line 56_

<details><summary>Logged reasoning block</summary>

```text
Now let me also get the multi-seed entity construction data and the CoNLL/SciERC QE data from the actual paper tables. Let me also check the 72B zeroshot data more carefully and the multi-seed construction data.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "0416a5d8-c91f-419a-8772-10de664e6a97",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014LSD5eNEW7Sqekh4CjkaTi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5230,
      "cache_read_input_tokens": 67522,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5230
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

_source line 57_

Now let me extract the multi-seed entity construction data and some additional experiments.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "74dc055b-8563-4bea-9cae-4c7df962881d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014LSD5eNEW7Sqekh4CjkaTi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5230,
      "cache_read_input_tokens": 67522,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5230
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

_source line 58_

<details open><summary>🔧 Tool call — Bash · `toolu_01AD3jW8iECV3zuKgCa1CVyP`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n# Get the full 72B data\ne72b = exps.get('exp_qwen25_72b_zeroshot', {})\nprint('=== 72B zeroshot ===')\nprint(json.dumps(e72b, indent=2)[:4000])\n\" 2>&1\n",
  "description": "Extract 72B zeroshot experiment data"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "1ce25d7b-4e39-4c67-987f-c2c1fa677368",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014LSD5eNEW7Sqekh4CjkaTi",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5230,
      "cache_read_input_tokens": 67522,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5230
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

_source line 59 · 2026-05-19T13:35:00.043Z_

<details><summary>↩ Tool result · `toolu_01AD3jW8iECV3zuKgCa1CVyP`</summary>

```text
=== 72B zeroshot ===
{
  "status": "RUNNING",
  "retry_count": 1,
  "created_at": "2026-05-19T06:19:28.597Z",
  "updated_at": "2026-05-19T12:48:36.347Z",
  "hypothesis": "A larger zero-shot model (72B) will show higher greedy F1 and wider oracle-greedy gap than fine-tuned smaller models, because increased capacity enables more diverse valid extractions per stochastic sample, making self-consistency signals (SJ, FK, VC, EM) more informative for quality estimation.",
  "server": "autodl-5090-b",
  "gpu": "cuda:0,cuda:1,cuda:2,cuda:3",
  "account": "root",
  "reproduce": {
    "server": "autodl-5090-b",
    "gpu": "cuda:0,cuda:1,cuda:2,cuda:3",
    "started_at": "2026-05-19T06:47:42.658Z"
  },
  "notes": "2026-05-19 12:47 UTC: RECOVERED from false-positive startup recovery failure. 289848/301184 prompts (96.2%). SciERC \u2705 (551) CoNLL \u2705 (3453) FewNERD ~96%. ETA ~10-15min. PID 59040, 4\u00d75090 100% util. Cron registered.",
  "failure_reason": "startup recovery: RUNNING with no cron and no server/pid info",
  "completed_at": "2026-05-19T12:44:26.198Z",
  "extra": {
    "previous_failure": {
      "conclusion": "failed",
      "notes": "2026-05-19 11:36 UTC: 69.8% complete (210352/301184 prompts). SciERC \u2705 CoNLL \u2705 FewNERD ~66%. ETA ~1h15m. vLLM PID 59040, 4\u00d75090 100% util."
    }
  },
  "spec": {
    "command": "CUDA_VISIBLE_DEVICES=0,1,2,3 python code/zeroshot_inference_72b.py --datasets scierc conll2003 fewnerd --output-dir output/72b_zeroshot --seed 42",
    "server": "autodl-5090-b",
    "data_path": "data/{scierc,conll2003,fewnerd}",
    "data_count": 41630,
    "model_name": "Qwen2.5-72B-Instruct-AWQ",
    "seed": 42,
    "gpu_ids": [
      "cuda:0",
      "cuda:1",
      "cuda:2",
      "cuda:3"
    ],
    "pid": 59040
  }
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "c4b286ba-4f77-4390-93fb-a38813f1988c",
  "tool_use_result": {
    "stdout": "=== 72B zeroshot ===\n{\n  \"status\": \"RUNNING\",\n  \"retry_count\": 1,\n  \"created_at\": \"2026-05-19T06:19:28.597Z\",\n  \"updated_at\": \"2026-05-19T12:48:36.347Z\",\n  \"hypothesis\": \"A larger zero-shot model (72B) will show higher greedy F1 and wider oracle-greedy gap than fine-tuned smaller models, because increased capacity enables more diverse valid extractions per stochastic sample, making self-consistency signals (SJ, FK, VC, EM) more informative for quality estimation.\",\n  \"server\": \"autodl-5090-b\",\n  \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\",\n  \"account\": \"root\",\n  \"reproduce\": {\n    \"server\": \"autodl-5090-b\",\n    \"gpu\": \"cuda:0,cuda:1,cuda:2,cuda:3\",\n    \"started_at\": \"2026-05-19T06:47:42.658Z\"\n  },\n  \"notes\": \"2026-05-19 12:47 UTC: RECOVERED from false-positive startup recovery failure. 289848/301184 prompts (96.2%). SciERC \\u2705 (551) CoNLL \\u2705 (3453) FewNERD ~96%. ETA ~10-15min. PID 59040, 4\\u00d75090 100% util. Cron registered.\",\n  \"failure_reason\": \"startup recovery: RUNNING with no cron and no server/pid info\",\n  \"completed_at\": \"2026-05-19T12:44:26.198Z\",\n  \"extra\": {\n    \"previous_failure\": {\n      \"conclusion\": \"failed\",\n      \"notes\": \"2026-05-19 11:36 UTC: 69.8% complete (210352/301184 prompts). SciERC \\u2705 CoNLL \\u2705 FewNERD ~66%. ETA ~1h15m. vLLM PID 59040, 4\\u00d75090 100% util.\"\n    }\n  },\n  \"spec\": {\n    \"command\": \"CUDA_VISIBLE_DEVICES=0,1,2,3 python code/zeroshot_inference_72b.py --datasets scierc conll2003 fewnerd --output-dir output/72b_zeroshot --seed 42\",\n    \"server\": \"autodl-5090-b\",\n    \"data_path\": \"data/{scierc,conll2003,fewnerd}\",\n    \"data_count\": 41630,\n    \"model_name\": \"Qwen2.5-72B-Instruct-AWQ\",\n    \"seed\": 42,\n    \"gpu_ids\": [\n      \"cuda:0\",\n      \"cuda:1\",\n      \"cuda:2\",\n      \"cuda:3\"\n    ],\n    \"pid\": 59040\n  }\n}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---


### Assistant

_source line 60_

<details><summary>Logged reasoning block</summary>

```text
The 72B experiment is still running and doesn't have final metrics yet. But the paper already has data about 72B zero-shot results. The data in the paper might be from a previous run or from other sources. Let me check the artifacts directory for actual experimental data files.

Let me also look for the multi-seed entity construction data and verify the specific numbers used in the paper.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "8e1b39d0-81fa-4426-a834-1f69f5f33bd4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qmtq7ZiSMzNzJTcsd7E3qJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1132,
      "cache_read_input_tokens": 72752,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1132
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

_source line 61_

72B experiment is still RUNNING with no final metrics in the registry. Let me check if there are intermediate results or previous 72B data.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "641c8c46-846f-4ab1-a0b4-7820ea74a66c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qmtq7ZiSMzNzJTcsd7E3qJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1132,
      "cache_read_input_tokens": 72752,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1132
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

_source line 62_

<details open><summary>🔧 Tool call — Glob · `toolu_0113Z7yFNcddsEiSpcFpwBEq`</summary>

```json
{
  "pattern": "**/72b*/**",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/artifacts"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "c549eeb8-eccf-4e26-8f33-3da52e06a9a4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qmtq7ZiSMzNzJTcsd7E3qJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1132,
      "cache_read_input_tokens": 72752,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1132
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

_source line 63 · 2026-05-19T13:35:07.251Z_

<details><summary>↩ Tool result · `toolu_0113Z7yFNcddsEiSpcFpwBEq`</summary>

```text
No files found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "342aa21d-6170-41b1-808c-504b453ad1fe",
  "tool_use_result": {
    "filenames": [],
    "durationMs": 8,
    "numFiles": 0,
    "truncated": false
  }
}
```

</details>

---


### Tool call

_source line 64_

<details open><summary>🔧 Tool call — Bash · `toolu_01D9fUoZEdndCwSQF6eLvKeS`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Look for multi-seed entity construction and selection data\ntargets = ['exp_entity_construction', 'exp_026_t12', 'exp_026_t12_scierc',\n           'exp_016_rerun_1024', 'exp_002_conll_n16_r1024',\n           'exp_003_wnut17_v2', 'exp_003_ner_wnut17']\nfor t in targets:\n    if t in exps:\n        e = exps[t]\n        print(f'=== {t} ===')\n        ms = json.dumps(e.get('metrics', {}), indent=2)\n        print(ms[:3000])\n        print()\n\" 2>&1 | head -400\n",
  "description": "Extract entity construction and WNUT metrics"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "0098799e-5df2-4377-a4d8-ea1d8b9ac397",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Qmtq7ZiSMzNzJTcsd7E3qJ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1132,
      "cache_read_input_tokens": 72752,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1132
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

_source line 65 · 2026-05-19T13:35:12.955Z_

<details><summary>↩ Tool result · `toolu_01D9fUoZEdndCwSQF6eLvKeS`</summary>

```text
=== exp_entity_construction ===
{
  "n16_fair_cv": {
    "scierc_ner": {
      "cv_uniform_delta": "+1.35pp",
      "p_value": 0.018,
      "significant": true
    },
    "conll_ner": {
      "cv_uniform_delta": "+0.10pp",
      "p_value": 0.303,
      "significant": false
    },
    "fewnerd_ner": {
      "cv_uniform_delta": "+1.32pp",
      "p_value": 0,
      "significant": true
    },
    "scierc_re": {
      "cv_uniform_delta": "+1.69pp",
      "p_value": 0.049,
      "significant": true
    }
  },
  "n8_fair_cv": {
    "scierc_ner": {
      "uniform_confirm": "+1.54pp (p=0.023, sig)",
      "lp_weighted_confirm": "+1.67pp (p=0.004, sig)",
      "cv_uniform": "+1.12pp (p=0.057, borderline)"
    },
    "conll_ner": {
      "cv_uniform": "-0.39pp (p=0.963, not sig)"
    },
    "fewnerd_ner": {
      "lp_weighted_cv": "+0.88pp (p=0.000, sig)",
      "uniform_cv": "+0.32pp (p=0.003, sig)"
    }
  },
  "adaptive_combination": "INVALIDATED - gold label leakage confirmed",
  "note": "5-fold CV, bootstrap B=10000, paired one-sided"
}

=== exp_026_t12 ===
{
  "temperature": 1.2,
  "task": "T-ablation",
  "degen_rate": 0.1493,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered"
}

=== exp_026_t12_scierc ===
{}

=== exp_002_conll_n16_r1024 ===
{}

=== exp_003_wnut17_v2 ===
{}

=== exp_003_ner_wnut17 ===
{
  "ner": {
    "greedy_f1": 0.525,
    "oracle_f1": 0.664,
    "headroom": 0.139,
    "rho_sj_full": 0.082,
    "rho_fk_full": 0.124,
    "rho_logprob_full": -0.414,
    "rho_sj_cond": 0.275,
    "rho_fk_cond": 0.164,
    "rho_logprob_cond": 0.352,
    "sj_beats_logprob_cond": false
  },
  "n_instances": 1287,
  "n_gold_empty": 598,
  "sample_f1_mean": 0.401,
  "sample_f1_pct_zero": 53.7,
  "N": 16,
  "T": 1,
  "seed": 42,
  "verdict": "FAIL",
  "verdict_note": ">30% samples F1=0; structural rho weak; logprob baseline stronger"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "e044a644-7bfa-4eb6-868c-1a2e71854fa4",
  "tool_use_result": {
    "stdout": "=== exp_entity_construction ===\n{\n  \"n16_fair_cv\": {\n    \"scierc_ner\": {\n      \"cv_uniform_delta\": \"+1.35pp\",\n      \"p_value\": 0.018,\n      \"significant\": true\n    },\n    \"conll_ner\": {\n      \"cv_uniform_delta\": \"+0.10pp\",\n      \"p_value\": 0.303,\n      \"significant\": false\n    },\n    \"fewnerd_ner\": {\n      \"cv_uniform_delta\": \"+1.32pp\",\n      \"p_value\": 0,\n      \"significant\": true\n    },\n    \"scierc_re\": {\n      \"cv_uniform_delta\": \"+1.69pp\",\n      \"p_value\": 0.049,\n      \"significant\": true\n    }\n  },\n  \"n8_fair_cv\": {\n    \"scierc_ner\": {\n      \"uniform_confirm\": \"+1.54pp (p=0.023, sig)\",\n      \"lp_weighted_confirm\": \"+1.67pp (p=0.004, sig)\",\n      \"cv_uniform\": \"+1.12pp (p=0.057, borderline)\"\n    },\n    \"conll_ner\": {\n      \"cv_uniform\": \"-0.39pp (p=0.963, not sig)\"\n    },\n    \"fewnerd_ner\": {\n      \"lp_weighted_cv\": \"+0.88pp (p=0.000, sig)\",\n      \"uniform_cv\": \"+0.32pp (p=0.003, sig)\"\n    }\n  },\n  \"adaptive_combination\": \"INVALIDATED - gold label leakage confirmed\",\n  \"note\": \"5-fold CV, bootstrap B=10000, paired one-sided\"\n}\n\n=== exp_026_t12 ===\n{\n  \"temperature\": 1.2,\n  \"task\": \"T-ablation\",\n  \"degen_rate\": 0.1493,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"\n}\n\n=== exp_026_t12_scierc ===\n{}\n\n=== exp_002_conll_n16_r1024 ===\n{}\n\n=== exp_003_wnut17_v2 ===\n{}\n\n=== exp_003_ner_wnut17 ===\n{\n  \"ner\": {\n    \"greedy_f1\": 0.525,\n    \"oracle_f1\": 0.664,\n    \"headroom\": 0.139,\n    \"rho_sj_full\": 0.082,\n    \"rho_fk_full\": 0.124,\n    \"rho_logprob_full\": -0.414,\n    \"rho_sj_cond\": 0.275,\n    \"rho_fk_cond\": 0.164,\n    \"rho_logprob_cond\": 0.352,\n    \"sj_beats_logprob_cond\": false\n  },\n  \"n_instances\": 1287,\n  \"n_gold_empty\": 598,\n  \"sample_f1_mean\": 0.401,\n  \"sample_f1_pct_zero\": 53.7,\n  \"N\": 16,\n  \"T\": 1,\n  \"seed\": 42,\n  \"verdict\": \"FAIL\",\n  \"verdict_note\": \">30% samples F1=0; structural rho weak; logprob baseline stronger\"\n}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---


### Assistant

_source line 66_

<details><summary>Logged reasoning block</summary>

```text
Now let me also check the multi-seed selection and QE data for SciERC and CoNLL, and the WNUT selection data. I also need to find the actual entity construction results that include the multi-seed means for the paper's Table 5.

Let me also look at the paper's multi-seed data. The paper reports:
- SciERC entity construction: LP +1.02±0.49pp, Unif +0.74±0.71pp
- Few-NERD entity construction: LP +1.40±0.51pp, Unif +0.74±0.58pp


- CoNLL: -0.39pp

But when I check the registry for the entity construction experiments, I'm seeing different numbers than what's reported in the paper. The registry shows higher values for SciERC and Few-NERD, which suggests these might be individual runs rather than the multi-seed means the paper is reporting. I need to figure out how the paper's reported numbers were calculated from these individual results.

Looking at the Few-NERD data across different seeds, I'm noticing some inconsistency in the greedy baseline scores that doesn't quite add up.

The four-seed mean LP delta from the registry shows 1.38pp, but the paper reports 1.39pp in the main text and 1.40pp in Table 5—those don't match even with rounding, so there might be a discrepancy between what's recorded and what was published.

I should verify whether the paper's "multi-seed mean" refers to 3 or 4 seeds, and then spot-check a few other key numbers like the CoNLL QE results, WNUT-17 performance, and the LLaMA cross-model comparisons to see if there are other inconsistencies before I start compiling the audit report.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "7e4b42b8-5df6-4299-87ba-31d9c51d5f99",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EC25DqAScvyGqVL1qk9TZ4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1649,
      "cache_read_input_tokens": 73884,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1649
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

_source line 67_

Let me get multi-seed Few-NERD construction data and cross-selection table data.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "b6b99de4-d55c-4aab-84ad-633525d43ce7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EC25DqAScvyGqVL1qk9TZ4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1649,
      "cache_read_input_tokens": 73884,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1649
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

_source line 68_

<details open><summary>🔧 Tool call — Bash · `toolu_013GcZeq2jPTkSqNZ7Dgh7jp`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Get full exp_016_rerun_1024 with all selection data\ne = exps.get('exp_016_rerun_1024', {})\nprint('=== exp_016_rerun_1024 FULL ===')\nprint(json.dumps(e, indent=2)[:5000])\n\" 2>&1\n",
  "description": "Get full selection data from exp_016"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "9df3f0f2-1ab6-47ec-9fa9-7242ff34e784",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EC25DqAScvyGqVL1qk9TZ4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1649,
      "cache_read_input_tokens": 73884,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1649
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

_source line 69 · 2026-05-19T13:35:35.603Z_

<details><summary>↩ Tool result · `toolu_013GcZeq2jPTkSqNZ7Dgh7jp`</summary>

```text
=== exp_016_rerun_1024 FULL ===
{}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "d189835a-adef-4209-a44e-45235a9609d8",
  "tool_use_result": {
    "stdout": "=== exp_016_rerun_1024 FULL ===\n{}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---


### Tool call

_source line 70_

<details open><summary>🔧 Tool call — Bash · `toolu_01Cem3bnZ7LhKadYHydYM3PZ`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Get multi-seed SciERC selection data\nfor eid in ['exp_018_qwen_scierc_seed456', 'exp_018_qwen_scierc_seed123', 'exp_001_seed456_v2_ner_r1024', 'exp_001_seed123_v2_r1024']:\n    e = exps.get(eid, {})\n    if e:\n        print(f'=== {eid} ===')\n        ms = json.dumps(e.get('metrics', {}), indent=2)\n        print(ms[:1500])\n        print()\n\" 2>&1\n",
  "description": "Get multi-seed SciERC QE data"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "b865200f-8644-442d-b01e-db91d81b64b1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EC25DqAScvyGqVL1qk9TZ4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1649,
      "cache_read_input_tokens": 73884,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1649
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

_source line 71 · 2026-05-19T13:35:38.973Z_

<details><summary>↩ Tool result · `toolu_01Cem3bnZ7LhKadYHydYM3PZ`</summary>

```text
=== exp_018_qwen_scierc_seed456 ===
{
  "degen_rate": 0.2042,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered"
}

=== exp_018_qwen_scierc_seed123 ===
{
  "degen_rate": 0.172,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered"
}

=== exp_001_seed456_v2_ner_r1024 ===
{}

=== exp_001_seed123_v2_r1024 ===
{}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "d6732aea-6e24-4430-86d8-96ebaa50563b",
  "tool_use_result": {
    "stdout": "=== exp_018_qwen_scierc_seed456 ===\n{\n  \"degen_rate\": 0.2042,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"\n}\n\n=== exp_018_qwen_scierc_seed123 ===\n{\n  \"degen_rate\": 0.172,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\"\n}\n\n=== exp_001_seed456_v2_ner_r1024 ===\n{}\n\n=== exp_001_seed123_v2_r1024 ===\n{}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---


### Tool call

_source line 72_

<details open><summary>🔧 Tool call — Bash · `toolu_01GDJuhV2hniK8jdtSpsP7aG`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Get exp_002_conll_n16_r1024 and look for CoNLL N=8 data\nfor eid in ['exp_002_conll_n16_r1024', 'exp_002_conll_n16_seed456', 'exp_002_conll_n16_seed123', \n            'exp_002_conll_n16_seed456', 'exp_002_conll_n16_seed123']:\n    e = exps.get(eid, {})\n    if e:\n        print(f'=== {eid} ===')\n        ms = json.dumps(e.get('metrics', {}), indent=2)\n        print(ms[:1500])\n        print()\n        \n# Also check the hidden_state_probe experiments\nfor eid in ['hidden_state_probe_conll_full', 'hidden_state_probe_conll_v2']:\n    e = exps.get(eid, {})\n    if e:\n        print(f'=== {eid} ===')\n        ms = json.dumps(e.get('metrics', {}), indent=2)\n        print(ms[:1500])\n        print()\n\" 2>&1\n",
  "description": "Get CoNLL and hidden probe data"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "cd65982b-27b1-4c91-af2b-70d62061fbbf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01EC25DqAScvyGqVL1qk9TZ4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1649,
      "cache_read_input_tokens": 73884,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1649
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

_source line 73 · 2026-05-19T13:35:43.726Z_

<details><summary>↩ Tool result · `toolu_01GDJuhV2hniK8jdtSpsP7aG`</summary>

```text
=== exp_002_conll_n16_r1024 ===
{}

=== exp_002_conll_n16_seed456 ===
{
  "degen_rate": 0.5544,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered",
  "instance_count": 3453,
  "n_valid": 2756,
  "n_gold_empty": 697,
  "ner_greedy_f1": 0.9074,
  "ner_oracle_f1": 0.9549,
  "rho_fk_ner": 0.4718,
  "rho_sj_ner": 0.4819,
  "sample_f1_pct_zero": 7.02
}

=== exp_002_conll_n16_seed123 ===
{
  "degen_rate": 0.471,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered",
  "instance_count": 3453,
  "n_valid": 2756,
  "n_gold_empty": 697,
  "ner_greedy_f1": 0.9068,
  "ner_oracle_f1": 0.9633,
  "rho_fk_ner": 0.4524,
  "rho_sj_ner": 0.4621,
  "sample_f1_pct_zero": 7.54
}

=== exp_002_conll_n16_seed456 ===
{
  "degen_rate": 0.5544,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered",
  "instance_count": 3453,
  "n_valid": 2756,
  "n_gold_empty": 697,
  "ner_greedy_f1": 0.9074,
  "ner_oracle_f1": 0.9549,
  "rho_fk_ner": 0.4718,
  "rho_sj_ner": 0.4819,
  "sample_f1_pct_zero": 7.02
}

=== exp_002_conll_n16_seed123 ===
{
  "degen_rate": 0.471,
  "degen_rate_source": "unified_metrics_constant_f1_gold_filtered",
  "instance_count": 3453,
  "n_valid": 2756,
  "n_gold_empty": 697,
  "ner_greedy_f1": 0.9068,
  "ner_oracle_f1": 0.9633,
  "rho_fk_ner": 0.4524,
  "rho_sj_ner": 0.4621,
  "sample_f1_pct_zero": 7.54
}

=== hidden_state_probe_conll_full ===
{}

=== hidden_state_probe_conll_v2 ===
{}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "68d5bb2a-67b0-43fc-b45e-85448249e6aa",
  "tool_use_result": {
    "stdout": "=== exp_002_conll_n16_r1024 ===\n{}\n\n=== exp_002_conll_n16_seed456 ===\n{\n  \"degen_rate\": 0.5544,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\",\n  \"instance_count\": 3453,\n  \"n_valid\": 2756,\n  \"n_gold_empty\": 697,\n  \"ner_greedy_f1\": 0.9074,\n  \"ner_oracle_f1\": 0.9549,\n  \"rho_fk_ner\": 0.4718,\n  \"rho_sj_ner\": 0.4819,\n  \"sample_f1_pct_zero\": 7.02\n}\n\n=== exp_002_conll_n16_seed123 ===\n{\n  \"degen_rate\": 0.471,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\",\n  \"instance_count\": 3453,\n  \"n_valid\": 2756,\n  \"n_gold_empty\": 697,\n  \"ner_greedy_f1\": 0.9068,\n  \"ner_oracle_f1\": 0.9633,\n  \"rho_fk_ner\": 0.4524,\n  \"rho_sj_ner\": 0.4621,\n  \"sample_f1_pct_zero\": 7.54\n}\n\n=== exp_002_conll_n16_seed456 ===\n{\n  \"degen_rate\": 0.5544,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\",\n  \"instance_count\": 3453,\n  \"n_valid\": 2756,\n  \"n_gold_empty\": 697,\n  \"ner_greedy_f1\": 0.9074,\n  \"ner_oracle_f1\": 0.9549,\n  \"rho_fk_ner\": 0.4718,\n  \"rho_sj_ner\": 0.4819,\n  \"sample_f1_pct_zero\": 7.02\n}\n\n=== exp_002_conll_n16_seed123 ===\n{\n  \"degen_rate\": 0.471,\n  \"degen_rate_source\": \"unified_metrics_constant_f1_gold_filtered\",\n  \"instance_count\": 3453,\n  \"n_valid\": 2756,\n  \"n_gold_empty\": 697,\n  \"ner_greedy_f1\": 0.9068,\n  \"ner_oracle_f1\": 0.9633,\n  \"rho_fk_ner\": 0.4524,\n  \"rho_sj_ner\": 0.4621,\n  \"sample_f1_pct_zero\": 7.54\n}\n\n=== hidden_state_probe_conll_full ===\n{}\n\n=== hidden_state_probe_conll_v2 ===\n{}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---


### Assistant

_source line 74_

<details><summary>Logged reasoning block</summary>

```text
Let me look for the actual CoNLL N=8 data and the multi-seed selection data for SciERC, as well as the WNUT QE data. Let me also check the table in the paper for SciERC selection (Table 2).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "cdea8dbc-8efb-431d-ad44-a07307231d99",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WDfzemp2ijpxLG2oVxRRpd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3187,
      "cache_read_input_tokens": 75533,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3187
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

_source line 75_

Let me check more experiment data for the specific numbers used in the paper.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "26194510-b58b-49dd-9fa6-b956d14ea542",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WDfzemp2ijpxLG2oVxRRpd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3187,
      "cache_read_input_tokens": 75533,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3187
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

_source line 76_

<details open><summary>🔧 Tool call — Bash · `toolu_013rDMNdM1gv9UZqbYmwG7UH`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# WNUT LP rho\ne = exps.get('exp_003_ner_wnut17', {})\nprint('=== WNUT-17 (exp_003) ===')\nm = e.get('metrics', {})\nprint(f'LP full rho: {m.get(\\\"ner\\\",{}).get(\\\"rho_logprob_full\\\", \\\"?\\\")}')\nprint(f'LP cond rho: {m.get(\\\"ner\\\",{}).get(\\\"rho_logprob_cond\\\", \\\"?\\\")}')\nprint()\n\n# Get CoNLL QE N=8 data\nfor eid in ['exp_002', 'exp_002_ner_conll2003']:\n    e = exps.get(eid, {})\n    if e and e.get('metrics'):\n        print(f'=== {eid} ===')\n        ms = json.dumps(e.get('metrics', {}), indent=2)\n        print(ms[:2000])\n        print()\n\n# Also look for WNUT QE table data  \nfor eid in ['exp_003_wnut17_eval']:\n    e = exps.get(eid, {})\n    if e and e.get('metrics'):\n        print(f'=== {eid} ===')\n        ms = json.dumps(e.get('metrics', {}), indent=2)\n        print(ms[:2000])\n        print()\n\" 2>&1\n",
  "description": "Get WNUT and CoNLL QE baseline data"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "a635ed03-8d5a-4b7c-af7a-3d3bcf45b98f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WDfzemp2ijpxLG2oVxRRpd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3187,
      "cache_read_input_tokens": 75533,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3187
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

_source line 77 · 2026-05-19T13:35:54.575Z_

<details><summary>↩ Tool result · `toolu_013rDMNdM1gv9UZqbYmwG7UH`</summary>

```text
=== WNUT-17 (exp_003) ===
LP full rho: -0.414
LP cond rho: 0.352

=== exp_002 ===
{
  "sj_rho_full": 0.4357,
  "sj_tau_full": 0.3851,
  "sj_auroc_full": 0.8008,
  "sj_rho_cond": 0.4511,
  "fk_rho_full": 0.3998,
  "fk_tau_full": 0.3568,
  "fk_auroc_full": 0.7741,
  "fk_rho_cond": 0.4064,
  "logprob_rho_full": 0.3157,
  "logprob_tau_full": 0.2469,
  "logprob_auroc_full": 0.7532,
  "logprob_rho_cond": 0.3562,
  "em_rho_full": 0.4507,
  "em_tau_full": 0.4002,
  "em_auroc_full": 0.8156,
  "em_rho_cond": 0.4799,
  "ev_rho_full": 0.4237,
  "ev_tau_full": 0.3777,
  "ev_auroc_full": 0.7889,
  "ev_rho_cond": 0.4127,
  "greedy_f1": 0.9123,
  "oracle_f1": 0.9543,
  "voting_f1": 0.9141,
  "oracle_headroom": 0.042,
  "sj_vs_logprob_delta_rho": 0.12,
  "sj_vs_logprob_ci_low": 0.0881,
  "sj_vs_logprob_ci_high": 0.154,
  "sj_vs_logprob_significant": true,
  "n_instances": 3453,
  "n_valid": 2756,
  "n_samples": 8,
  "temperature": 1
}

=== exp_003_wnut17_eval ===
{
  "greedy_f1": 0.523,
  "oracle_f1": 0.664,
  "headroom": 0.141,
  "rho_fk": 0.125,
  "rho_sj": 0.089,
  "rho_fk_cond": 0.169,
  "rho_sj_cond": 0.288,
  "rho_logprob_full": -0.409,
  "rho_logprob_cond": 0.35,
  "structural_beats_surface": false,
  "sample_f1_pct_zero": 53.7,
  "n_instances": 1287,
  "N": 16,
  "T": 1,
  "seed": 42,
  "model": "Qwen3-8B",
  "n_gold_empty_filtered": 598,
  "verdict": "FAIL",
  "verdict_note": "structural_beats_surface=false; >50% samples F1=0"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "883412e9-5b29-4a1b-b25d-573ae02dbdde",
  "tool_use_result": {
    "stdout": "=== WNUT-17 (exp_003) ===\nLP full rho: -0.414\nLP cond rho: 0.352\n\n=== exp_002 ===\n{\n  \"sj_rho_full\": 0.4357,\n  \"sj_tau_full\": 0.3851,\n  \"sj_auroc_full\": 0.8008,\n  \"sj_rho_cond\": 0.4511,\n  \"fk_rho_full\": 0.3998,\n  \"fk_tau_full\": 0.3568,\n  \"fk_auroc_full\": 0.7741,\n  \"fk_rho_cond\": 0.4064,\n  \"logprob_rho_full\": 0.3157,\n  \"logprob_tau_full\": 0.2469,\n  \"logprob_auroc_full\": 0.7532,\n  \"logprob_rho_cond\": 0.3562,\n  \"em_rho_full\": 0.4507,\n  \"em_tau_full\": 0.4002,\n  \"em_auroc_full\": 0.8156,\n  \"em_rho_cond\": 0.4799,\n  \"ev_rho_full\": 0.4237,\n  \"ev_tau_full\": 0.3777,\n  \"ev_auroc_full\": 0.7889,\n  \"ev_rho_cond\": 0.4127,\n  \"greedy_f1\": 0.9123,\n  \"oracle_f1\": 0.9543,\n  \"voting_f1\": 0.9141,\n  \"oracle_headroom\": 0.042,\n  \"sj_vs_logprob_delta_rho\": 0.12,\n  \"sj_vs_logprob_ci_low\": 0.0881,\n  \"sj_vs_logprob_ci_high\": 0.154,\n  \"sj_vs_logprob_significant\": true,\n  \"n_instances\": 3453,\n  \"n_valid\": 2756,\n  \"n_samples\": 8,\n  \"temperature\": 1\n}\n\n=== exp_003_wnut17_eval ===\n{\n  \"greedy_f1\": 0.523,\n  \"oracle_f1\": 0.664,\n  \"headroom\": 0.141,\n  \"rho_fk\": 0.125,\n  \"rho_sj\": 0.089,\n  \"rho_fk_cond\": 0.169,\n  \"rho_sj_cond\": 0.288,\n  \"rho_logprob_full\": -0.409,\n  \"rho_logprob_cond\": 0.35,\n  \"structural_beats_surface\": false,\n  \"sample_f1_pct_zero\": 53.7,\n  \"n_instances\": 1287,\n  \"N\": 16,\n  \"T\": 1,\n  \"seed\": 42,\n  \"model\": \"Qwen3-8B\",\n  \"n_gold_empty_filtered\": 598,\n  \"verdict\": \"FAIL\",\n  \"verdict_note\": \"structural_beats_surface=false; >50% samples F1=0\"\n}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---


### Tool call

_source line 78_

<details open><summary>🔧 Tool call — Bash · `toolu_01P15YdAbkTBansCH7oEJ81u`</summary>

```json
{
  "command": "cat /home/ubuntu/.claude-account-5/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-1-projects-struct-self-consist-ie/e21c3add-633d-4663-b1eb-e2854d1b8be8/tool-results/mcp-agent-ml-research-read_registry-1779197616177.txt | python3 -c \"\nimport json, sys\ndata = json.load(sys.stdin)\nresult = json.loads(data['result'])\nexps = result['data']['experiments']\n\n# Find selection experiments with 2-seed means for SciERC (paper Table 2)\n# exp_016_rerun_1024 seems empty - check related experiments\nfor eid in ['exp_016_v2', 'exp_015_v2', 'exp_010_selection_curves']:\n    e = exps.get(eid, {})\n    if e and e.get('metrics'):\n        print(f'=== {eid} ===')\n        ms = json.dumps(e.get('metrics', {}), indent=2)\n        print(ms[:2000])\n        print()\n\" 2>&1\n",
  "description": "Get selection experiment data"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "49619f48-61c2-4960-bd88-5e9259525bc2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WDfzemp2ijpxLG2oVxRRpd",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3187,
      "cache_read_input_tokens": 75533,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3187
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

_source line 79 · 2026-05-19T13:35:57.690Z_

<details><summary>↩ Tool result · `toolu_01P15YdAbkTBansCH7oEJ81u`</summary>

```text
=== exp_016_v2 ===
{
  "ner_conditional": {
    "n": 529,
    "best_single_signal_rho": {
      "soft_jaccard": 0.4412
    },
    "best_combo_rho": {
      "sj+vc_a0.55": 0.4552
    },
    "ensemble_auroc": 0.7141,
    "best_single_auroc": {
      "soft_jaccard": 0.7166
    },
    "selection_f1": {
      "greedy": 0.6442,
      "logprob_best": 0.6505,
      "ensemble_best": 0.6475,
      "sj_best": 0.6471,
      "oracle": 0.8442
    }
  },
  "re_conditional": {
    "n": 397,
    "best_single_signal_rho": {
      "voting_confidence": 0.3849
    },
    "best_combo_rho": {
      "logprob+vc_a0.25": 0.3936
    },
    "ensemble_auroc": 0.6916,
    "best_single_auroc": {
      "voting_confidence": 0.7023
    },
    "selection_f1": {
      "greedy": 0.403,
      "logprob_best": 0.4097,
      "ensemble_best": 0.4227,
      "oracle": 0.6306
    }
  },
  "re_full": {
    "ensemble_auroc": 0.8608,
    "best_single_auroc": {
      "voting_confidence": 0.8248
    }
  }
}

=== exp_015_v2 ===
{
  "scierc_ner_avg": {
    "sj_auroc": 0.7394,
    "fk_auroc": 0.6172,
    "em_auroc": 0.7873,
    "voting_auroc": 0.7367,
    "logprob_auroc": 0.5918
  },
  "scierc_re_avg": {
    "sj_auroc": 0.6746,
    "fk_auroc": 0.5939,
    "em_auroc": 0.715,
    "voting_auroc": 0.7234,
    "logprob_auroc": 0.5849
  }
}

=== exp_010_selection_curves ===
{
  "scierc_ner": {
    "n_instances": 551,
    "greedy_f1": 0.618,
    "N16": {
      "oracle": 0.787,
      "SJ": 0.62,
      "FK": 0.621,
      "logprob": 0.621,
      "voting_conf": 0.585,
      "EM": 0.606,
      "random": 0.595
    },
    "N8": {
      "oracle": 0.752,
      "SJ": 0.614,
      "FK": 0.614,
      "logprob": 0.619,
      "voting_conf": 0.591,
      "EM": 0.603,
      "random": 0.589
    },
    "N4": {
      "oracle": 0.714,
      "SJ": 0.607,
      "FK": 0.608,
      "logprob": 0.616,
      "voting_conf": 0.594,
      "EM": 0.6,
      "random": 0.587
    }
  },
  "scierc_re": {
    "n_instances": 397,
    "greedy_f1": 0.403,
    "N16": {
      "oracle": 0.631,
      "SJ": 0.397,
      "FK": 0.396,
      "logprob": 0.41,
      "voting_conf": 0.408,
      "EM": 0.381,
      "random": 0.364
    },
    "N8": {
      "oracle": 0.583,
      "SJ": 0.393,
      "FK": 0.394,
      "logprob": 0.413,
      "voting_conf": 0.398,
      "EM": 0.381,
      "random": 0.363
    }
  },
  "conll_ner": {
    "n_instances": 3453,
    "greedy_f1": 0.725,
    "N8": {
      "oracle": 0.757,
      "SJ": 0.718,
      "FK": 0.717,
      "logprob": 0.716,
      "voting_conf": 0.714,
      "EM": 0.716,
      "random": 0.69
    },
    "N4": {
      "oracle": 0.746,
      "SJ": 0.714,
      "FK": 0.714,
      "logprob": 0.715,
      "voting_conf": 0.714,
      "EM": 0.712,
      "random": 0.692
    }
  }
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "d8adcc54-c0a3-4645-aa2c-ae074153a1aa",
  "tool_use_result": {
    "stdout": "=== exp_016_v2 ===\n{\n  \"ner_conditional\": {\n    \"n\": 529,\n    \"best_single_signal_rho\": {\n      \"soft_jaccard\": 0.4412\n    },\n    \"best_combo_rho\": {\n      \"sj+vc_a0.55\": 0.4552\n    },\n    \"ensemble_auroc\": 0.7141,\n    \"best_single_auroc\": {\n      \"soft_jaccard\": 0.7166\n    },\n    \"selection_f1\": {\n      \"greedy\": 0.6442,\n      \"logprob_best\": 0.6505,\n      \"ensemble_best\": 0.6475,\n      \"sj_best\": 0.6471,\n      \"oracle\": 0.8442\n    }\n  },\n  \"re_conditional\": {\n    \"n\": 397,\n    \"best_single_signal_rho\": {\n      \"voting_confidence\": 0.3849\n    },\n    \"best_combo_rho\": {\n      \"logprob+vc_a0.25\": 0.3936\n    },\n    \"ensemble_auroc\": 0.6916,\n    \"best_single_auroc\": {\n      \"voting_confidence\": 0.7023\n    },\n    \"selection_f1\": {\n      \"greedy\": 0.403,\n      \"logprob_best\": 0.4097,\n      \"ensemble_best\": 0.4227,\n      \"oracle\": 0.6306\n    }\n  },\n  \"re_full\": {\n    \"ensemble_auroc\": 0.8608,\n    \"best_single_auroc\": {\n      \"voting_confidence\": 0.8248\n    }\n  }\n}\n\n=== exp_015_v2 ===\n{\n  \"scierc_ner_avg\": {\n    \"sj_auroc\": 0.7394,\n    \"fk_auroc\": 0.6172,\n    \"em_auroc\": 0.7873,\n    \"voting_auroc\": 0.7367,\n    \"logprob_auroc\": 0.5918\n  },\n  \"scierc_re_avg\": {\n    \"sj_auroc\": 0.6746,\n    \"fk_auroc\": 0.5939,\n    \"em_auroc\": 0.715,\n    \"voting_auroc\": 0.7234,\n    \"logprob_auroc\": 0.5849\n  }\n}\n\n=== exp_010_selection_curves ===\n{\n  \"scierc_ner\": {\n    \"n_instances\": 551,\n    \"greedy_f1\": 0.618,\n    \"N16\": {\n      \"oracle\": 0.787,\n      \"SJ\": 0.62,\n      \"FK\": 0.621,\n      \"logprob\": 0.621,\n      \"voting_conf\": 0.585,\n      \"EM\": 0.606,\n      \"random\": 0.595\n    },\n    \"N8\": {\n      \"oracle\": 0.752,\n      \"SJ\": 0.614,\n      \"FK\": 0.614,\n      \"logprob\": 0.619,\n      \"voting_conf\": 0.591,\n      \"EM\": 0.603,\n      \"random\": 0.589\n    },\n    \"N4\": {\n      \"oracle\": 0.714,\n      \"SJ\": 0.607,\n      \"FK\": 0.608,\n      \"logprob\": 0.616,\n      \"voting_conf\": 0.594,\n      \"EM\": 0.6,\n      \"random\": 0.587\n    }\n  },\n  \"scierc_re\": {\n    \"n_instances\": 397,\n    \"greedy_f1\": 0.403,\n    \"N16\": {\n      \"oracle\": 0.631,\n      \"SJ\": 0.397,\n      \"FK\": 0.396,\n      \"logprob\": 0.41,\n      \"voting_conf\": 0.408,\n      \"EM\": 0.381,\n      \"random\": 0.364\n    },\n    \"N8\": {\n      \"oracle\": 0.583,\n      \"SJ\": 0.393,\n      \"FK\": 0.394,\n      \"logprob\": 0.413,\n      \"voting_conf\": 0.398,\n      \"EM\": 0.381,\n      \"random\": 0.363\n    }\n  },\n  \"conll_ner\": {\n    \"n_instances\": 3453,\n    \"greedy_f1\": 0.725,\n    \"N8\": {\n      \"oracle\": 0.757,\n      \"SJ\": 0.718,\n      \"FK\": 0.717,\n      \"logprob\": 0.716,\n      \"voting_conf\": 0.714,\n      \"EM\": 0.716,\n      \"random\": 0.69\n    },\n    \"N4\": {\n      \"oracle\": 0.746,\n      \"SJ\": 0.714,\n      \"FK\": 0.714,\n      \"logprob\": 0.715,\n      \"voting_conf\": 0.714,\n      \"EM\": 0.712,\n      \"random\": 0.692\n    }\n  }\n}",
    "stderr": "",
    "interrupted": false,
    "isImage": false,
    "noOutputExpected": false
  }
}
```

</details>

---


### Assistant

_source line 80_

<details><summary>Logged reasoning block</summary>

```text
Now I have a good amount of data. Let me also look at the appendix for additional tables and numbers, and check the paper's WNUT-17 and CoNLL-specific claims. Let me also look for the actual multi-seed entity construction results that the paper cites.

Let me now read the appendix sections. The appendix is too large, so I'll read specific sections.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "9b93be23-0daa-422c-a6af-ad7f28aea8d6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ARwiwv6EymbapXSumvuJxf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3271,
      "cache_read_input_tokens": 78720,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3271
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

_source line 81_

Now let me check the appendix for specific tables referenced in the paper.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "e0354e8f-8e21-461b-acca-e4579f65f91a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ARwiwv6EymbapXSumvuJxf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3271,
      "cache_read_input_tokens": 78720,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3271
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

_source line 82_

<details open><summary>🔧 Tool call — Read · `toolu_01VHDMEDWRtXdBmh41rC5Mvv`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
  "offset": 0,
  "limit": 200
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "d639cac8-c108-452b-a137-cdfbd603d60d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01ARwiwv6EymbapXSumvuJxf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3271,
      "cache_read_input_tokens": 78720,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3271
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

_source line 83 · 2026-05-19T13:36:03.463Z_

<details><summary>↩ Tool result · `toolu_01VHDMEDWRtXdBmh41rC5Mvv`</summary>

```text
0	\section{Notation}\label{app:notation}
1	
2	Table~\ref{tab:notation} summarizes the notation used throughout the paper.
3	
4	\begin{table}[h]
5	\centering
6	\small
7	\begin{tabular}{cl}
8	\toprule
9	Symbol & Meaning \\
10	\midrule
11	$\mathcal{M}$ & Language model \\
12	$x$ & Input instance \\
13	$y_i$ & $i$-th stochastic sample \\
14	$N$ & Number of samples \\
15	$T$ & Sampling temperature \\
16	$c(\cdot)$ & Confidence signal \\
17	SJ & Soft Jaccard similarity \\
18	FK & Fleiss' $\kappa$ \\
19	EM & Exact-match voting rate \\
20	VC ($c_{\mathrm{vc}}$) & Entity voting confidence \\
21	LP ($c_{\mathrm{lp}}$) & Log-probability (mean token log-likelihood) \\
22	\bottomrule
23	\end{tabular}
24	\caption{Notation used throughout the paper.}
25	\label{tab:notation}
26	\end{table}
27	
28	\section{Robustness Analysis}\label{app:robustness}
29	
30	We exclude instances with empty gold annotations from all correlation analyses (CoNLL: 697/3{,}453 instances, 20.2\%; SciERC: 22/551, 4.0\%).
31	For these instances, F1 is trivially zero regardless of prediction quality, and consistency signals reflect agreement on the empty set rather than extraction quality. Including them inflates or deflates Spearman $\rho$ depending on signal behavior at the boundary.
32	
33	\begin{table}[t]
34	\centering
35	\small
36	\caption{Signal robustness across configurations (Spearman $\rho$). Top: temperature on Qwen SciERC. Middle: sample size on Qwen SciERC. Bottom: transfer across model families (both 8B) (LLaMA CoNLL $N{=}16$, 3-seed mean $\pm\sigma$). $^\dagger$Mean over 3 seeds ($\sigma{=}0.013$; individual: 0.398, 0.423, 0.410). $\sigma$ computed as sample standard deviation.}
37	\label{tab:robustness}
38	\begin{tabular}{llcc}
39	\toprule
40	& & NER $\rho$ & RE $\rho$ \\
41	\midrule
42	\multicolumn{4}{l}{\textit{Temperature} (Qwen SciERC, $N{=}8$)} \\
43	\quad SJ & $T{=}0.7$ & 0.364 & 0.234 \\
44	\quad SJ & $T{=}1.0$ & 0.360 & 0.250 \\
45	\quad FK & $T{=}0.7$ & 0.289 & 0.184 \\
46	\quad FK & $T{=}1.0$ & 0.267 & 0.275 \\
47	\quad LP & $T{=}0.7$ & 0.249 & --- \\
48	\quad LP & $T{=}1.0$ & 0.205 & 0.266 \\
49	\midrule
50	\multicolumn{4}{l}{\textit{Sample size} (Qwen SciERC, $T{=}1.0$)} \\
51	\quad SJ & $N{=}8$  & 0.360 & 0.250 \\
52	\quad SJ & $N{=}16$ & 0.411$^\dagger$ & 0.281 \\
53	\quad FK & $N{=}8$  & 0.267 & 0.275 \\
54	\quad FK & $N{=}16$ & 0.283 & 0.279 \\
55	\midrule
56	\multicolumn{4}{l}{\textit{Across model families} (LLaMA CoNLL, $N{=}16$, 3 seeds)} \\
57	\quad SJ &  & $0.474{\pm}0.009$ & --- \\
58	\quad FK &  & $0.467{\pm}0.009$ & --- \\
59	\quad EM &  & $0.473{\pm}0.010$ & --- \\
60	\quad VC &  & $0.470{\pm}0.006$ & --- \\
61	\quad LP &  & $0.311{\pm}0.003$ & --- \\
62	\bottomrule
63	\end{tabular}
64	\end{table}
65	
66	\begin{figure}[t]
67	\centering
68	\includegraphics[width=\columnwidth]{fig_temperature_robustness}
69	\caption{Temperature robustness on SciERC ($N{=}8$). Top: NER; bottom: RE. SJ maintains stable $\rho$ across $T{=}0.7$ and $T{=}1.0$, while FK shows mixed sensitivity. LP shows the largest NER temperature effect ($\Delta\rho{=}{+}0.044$); RE $T{=}0.7$ LP data unavailable.}
70	\label{fig:temperature_robustness}
71	\end{figure}
72	
73	\paragraph{Temperature sensitivity.}
74	SJ NER $\rho$ shifts from 0.364 ($T{=}0.7$) to 0.360 ($T{=}1.0$), a difference of 0.004.
75	FK NER $\rho$ drops by 0.022, while RE $\rho$ increases by 0.091, likely reflecting reduced diversity at lower temperature interacting differently across tasks.
76	LP exhibits the largest temperature effect on NER ($\rho{=}0.249$ at $T{=}0.7$ vs.\ $0.205$ at $T{=}1.0$, $\Delta{=}{+}0.044$), consistent with lower temperature concentrating probability mass and improving LP's discriminative power for quality estimation; RE $T{=}0.7$ LP data is not available.
77	Across all comparisons, the signal hierarchy is preserved at both temperatures on NER (SJ${>}$FK${>}$LP at $T{=}0.7$: $0.364{>}0.289{>}0.249$; at $T{=}1.0$: $0.360{>}0.267{>}0.205$).
78	
79	\paragraph{Sample size scaling.}
80	Increasing from $N{=}8$ to $N{=}16$ improves SJ on Qwen SciERC NER: $\rho$ rises from 0.360 to $0.411{\pm}0.010$ (three seeds: 0.398, 0.423, 0.410), a gain of $+0.047$.
81	The magnitude of $N$-scaling gains is setting-dependent (LLaMA SciERC NER yields $+0.016$ and Qwen CoNLL NER $+0.014$), though the direction is consistently positive.
82	LLaMA CoNLL exhibits the most uniform scaling: all four consistency signals gain $\Delta\rho{\approx}{+}0.042$ (range: $+0.039$ to $+0.044$) while LP gains only $+0.004$ (Table~\ref{tab:quality_estimation}).
83	FK $N$-scaling is seed-dependent: Qwen SciERC gains range from $+0.005$ to $+0.023$ across seeds (mean $+0.016$), while LLaMA CoNLL yields $+0.039$ (3-seed mean); individual seed FK shifts vary substantially under the unified pipeline, so this should not be interpreted as a robust trend.
84	VC $N$-scaling is consistently positive ($+0.005$ on Qwen CoNLL, $+0.018$ on LLaMA SciERC, $+0.030$ on Qwen SciERC), while LP is approximately $N$-invariant ($\Delta{\leq}0.034$).
85	SJ, EM, and VC scale consistently across all tested settings; only FK shows seed-dependent variation that does not constitute a reliable trend, structural and binary-agreement signals are the most robust to $N$.
86	At $N{=}16$, SJ converges to comparable NER performance with VC ($\Delta{=}0.002$) while exhibiting lower cross-seed variance ($\sigma{=}0.010$ vs.\ $0.026$), a more stable alternative at higher sample sizes.
87	
88	\paragraph{Transfer across model families.}
89	LLaMA-3.1-8B-Instruct shows a similar SJ--FK ordering on SciERC NER (SJ $\rho{=}0.325{\pm}0.021$, FK $\rho{=}0.256{\pm}0.024$, $\Delta\rho{=}0.069$; permutation $p{=}0.06$, borderline).
90	On CoNLL, the gap across model families is minimal (Table~\ref{tab:quality_estimation}): SJ achieves $\rho{=}0.431$ (LLaMA) vs.\ 0.436 (Qwen), $\Delta{=}0.005$.
91	At $N{=}16$, the structural-over-LP advantage holds across all four tested NER settings: Qwen SciERC (VC $\rho{=}0.409$ vs.\ LP 0.239, $\Delta{=}{+}0.170$), Qwen CoNLL (EM $\rho{=}0.463$ vs.\ LP 0.328, $\Delta{=}{+}0.135$),\footnote{Qwen CoNLL $N{=}16$ was not recomputed under the unified pipeline; LP $\rho{=}0.328$ may differ slightly from the registry value (0.315) due to instance filtering.} LLaMA SciERC (VC $\rho{=}0.452$ vs.\ LP 0.277, $\Delta{=}{+}0.175$), and LLaMA CoNLL 3-seed (SJ $\rho{=}0.474{\pm}0.009$ vs.\ LP $0.311{\pm}0.003$, $\Delta{=}{+}0.163$).
92	
93	\paragraph{FK independence: instance-level permutation test.}\label{app:fk_independence}
94	
95	To verify that Fleiss' $\kappa$ reflects genuine within-instance agreement rather than marginal-rate artifacts, we conduct instance-level permutation tests across three configurations.
96	For each instance, we permute sample labels 10{,}000 times to generate a null distribution of FK under independence, then compare the observed FK against this null via a one-sample $t$-test and permutation $p$-value.
97	
98	\begin{table}[t]
99	\centering
100	\small
101	\caption{Instance-level FK independence test. Permutation tests confirm FK reflects true within-instance agreement (all $p{<}0.001$). Split-half reliability $r$ computed by randomly partitioning $N$ samples into two halves and correlating their FK scores.}
102	\label{tab:fk_independence}
103	\begin{tabular}{lrcccc}
104	\toprule
105	Config & $n$ & FK mean & 95\% CI & $t$ & Split-half $r$ \\
106	\midrule
107	SciERC (Qwen) & 529 & 0.402 & [0.376, 0.428] & 30.8 & 0.395 \\
108	CoNLL (LLaMA) & 2{,}756 & 0.927 & [0.919, 0.935] & 225.9 & 0.578 \\
109	CoNLL (Qwen) & 2{,}756 & 0.720 & [0.706, 0.734] & 102.1 & 0.520 \\
110	\bottomrule
111	\end{tabular}
112	\end{table}
113	
114	Table~\ref{tab:fk_independence} reports the results.
115	All configurations reject the independence null at $p{<}0.001$ ($n{=}529$--$2{,}756$), FK captures genuine inter-sample agreement rather than chance label co-occurrence.
116	Split-half reliability ranges from $r{=}0.395$ (SciERC) to $r{=}0.578$ (CoNLL LLaMA), moderate stability: FK estimates from half the samples correlate positively with those from the other half, though the SciERC value suggests noisier estimation on harder tasks with fewer samples.
117	The higher FK means on CoNLL ($0.720$--$0.927$) vs.\ SciERC ($0.402$) mirror the difficulty gradient observed in the main quality estimation results.
118	
119	\section{Calibration Analysis}\label{app:calibration}
120	
121	\begin{figure*}[t]
122	\centering
123	\includegraphics[width=\textwidth]{fig_reliability}
124	\caption{Reliability diagrams on SciERC ($N{=}8$, $T{=}1.0$). Top: mean F1 vs.\ binned confidence; bottom: instance counts per bin. Left: NER; right: RE. NER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE shows greater miscalibration (ECE 0.109--0.339), RE calibration remains challenging for compound extraction tasks.}
125	\label{fig:reliability}
126	\end{figure*}
127	
128	Reliability diagrams use 10 equal-width bins.
129	NER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE exhibits greater miscalibration (ECE 0.109--0.339), translating consistency scores into calibrated confidence estimates is feasible for NER but remains challenging for compound extraction tasks.
130	
131	\section{Additional Analyses}\label{app:additional}
132	
133	\begin{figure*}[t]
134	\centering
135	\includegraphics[width=\textwidth]{fig_signal_heatmap}
136	\caption{Quality estimation heatmap (Spearman $\rho$) across five signals and four configurations. Left: full evaluation set; right: conditional set (non-zero F1 instances). On the full set, structural signals dominate on SciERC NER while all signals converge on CoNLL. On the conditional set, EM emerges as the strongest signal on both NER ($\rho{=}0.360$) and RE ($\rho{=}0.417$), while LP RE collapses to near-zero ($\rho{=}0.011$).}
137	\label{fig:signal_heatmap}
138	\end{figure*}
139	
140	\paragraph{Per-relation diagnostic.}
141	RE signal degradation is relation-specific.
142	\textsc{Feature-Of} has near-zero correlation ($\rho{=}0.004$), while \textsc{Hyponym-Of} achieves $\rho{=}0.646$.
143	The primary bottleneck is entity span errors, which account for 55.5\% of RE false negatives. This is a prerequisite failure that consistency signals cannot detect, as they measure agreement among equally incorrect extractions.
144	We note that RE analysis relies on a single dataset (SciERC); generalization to other RE benchmarks remains to be validated.
145	
146	\paragraph{Capability stratification.}
147	For NER, SJ effectiveness scales with structural complexity: on SciERC instances with 6+ entities, $\rho{=}0.547$, compared to $\rho{=}0.415$ for 1--2 entities.
148	The SJ advantage over LP remains stable across sentence-length quartiles ($\Delta\rho{\approx}0.08$--$0.20$).
149	For RE, SJ $\rho$ increases monotonically with sentence length (Q1: 0.110 $\to$ Q4: 0.473; Fisher $z$-test $p{=}0.004$): longer, more relation-dense sentences provide richer structure for consistency-based estimation.
150	Both proxies are weakly correlated with F1 ($|r|{<}0.15$), they capture input complexity rather than directly predicting output quality; however, entity count and sentence length are themselves moderately correlated ($\rho{=}0.650$), so they reflect overlapping rather than independent complexity dimensions.
151	For RE, entity count and relation count are strongly correlated ($\rho{=}0.769$) and thus reflect a single structural complexity dimension rather than independent axes.
152	On the high-complexity RE subset ($n{=}81$, high relation count), signals improve substantially: VC reaches $\rho{=}0.630$, LP $\rho{=}0.554$, and SJ $\rho{=}0.502$, all far above the full-set levels.
153	Richer relational structure provides more signal for consistency-based estimation, complementing the task-level boundary established by WNUT-17: structural signals are most effective within a ``sweet spot'' of sufficient model capability and sufficient output complexity.
154	
155	\paragraph{Length vs.\ log-probability.}
156	Figure~\ref{fig:length_logprob_scatter} shows that mean log-probability is weakly positively correlated with output length (NER: $\rho{=}0.386$, $n{=}4{,}232$; RE: $\rho{=}0.326$, $n{=}3{,}176$), ruling out length-penalty confounding as an explanation for LP's selection failure: longer outputs receive \textit{higher}, not lower, token-averaged log-probability under constrained decoding.
157	
158	\begin{figure}[t]
159	\centering
160	\includegraphics[width=\columnwidth]{fig_length_logprob_scatter}
161	\caption{Output length vs.\ mean log-probability on SciERC ($N{=}8$, $T{=}1.0$). Positive correlations (NER: $\rho{=}0.386$; RE: $\rho{=}0.326$) rule out length-penalty confounding.}
162	\label{fig:length_logprob_scatter}
163	\end{figure}
164	
165	\paragraph{Evaluation circularity and LOO-SJ equivalence.}
166	Consensus-proximity selection chooses $\hat{y} = \arg\max_{y_i} \sum_{j \neq i} \text{SJ}(y_i, y_j)$.
167	Leave-one-out SJ (LOO-SJ) for sample $y_i$ is $\text{LOO-SJ}_i = \frac{1}{N-1}\sum_{j \neq i} \text{SJ}(y_i, y_j)$.
168	Since the $\frac{1}{N-1}$ constant is shared across all candidates within an instance, $\arg\max_{y_i} \text{LOO-SJ}_i = \arg\max_{y_i} \sum_{j \neq i} \text{SJ}(y_i, y_j)$; the two selection rules are equivalent.
169	Standard (non-LOO) SJ adds the self-comparison term $\text{SJ}(y_i, y_i) = 1$ to each candidate, which is constant and thus does not affect ranking.
170	Empirically, LOO-SJ yields $\Delta\rho{=}{-}0.014$ relative to standard SJ (a correlation-level difference), with a maximum per-instance score difference of $3.1{\times}10^{-4}$ (negligible at the individual prediction level).
171	Evaluation circularity is negligible.
172	
173	\paragraph{SJ normalizer robustness.}
174	Equation~\ref{eq:sj} uses $\max(|g_i|, |g_j|)$ as the denominator; an alternative is the union size $|g_i \cup g_j|$.
175	Table~\ref{tab:sj_normalizer} compares the two normalizers across all six model--dataset combinations ($N{=}8$, $T{=}1.0$, seed${=}42$): $|\Delta\rho|{<}0.01$ in every case, the choice between max and union normalization does not affect conclusions.
176	
177	\begin{table}[h]
178	\centering
179	\small
180	\caption{SJ normalizer comparison (Spearman $\rho$; $N{=}8$, $T{=}1.0$, seed${=}42$). Max: $\max(|g_i|,|g_j|)$; Union: $|g_i \cup g_j|$.}
181	\label{tab:sj_normalizer}
182	\begin{tabular}{@{}ll ccc@{}}
183	\toprule
184	Dataset & Model & $\rho$(max) & $\rho$(union) & $\Delta\rho$ \\
185	\midrule
186	CoNLL & Qwen3-8B & .436 & .438 & $-$.002 \\
187	CoNLL & Qwen3-4B & .422 & .421 & $+$.000 \\
188	CoNLL & LLaMA-8B & .431 & .432 & $-$.000 \\
189	SciERC & Qwen3-8B & .360 & .365 & $-$.005 \\
190	SciERC & Qwen3-4B & .422 & .423 & $-$.001 \\
191	SciERC & LLaMA-8B & .363 & .372 & $-$.009 \\
192	\bottomrule
193	\end{tabular}
194	\end{table}
195	
196	\paragraph{Conditional filtering details.}
197	On LLaMA conditional RE (non-zero F1 instances), SJ recovers to $\rho{=}0.405$ while FK drops to $\rho{=}0.259$, consistent with the NER structural advantage; on full-set RE, however, the SJ--FK difference is non-significant ($\Delta\rho{=}{-}0.005$, $p{=}0.53$; preliminary).
198	At $N{=}16$, the divergence persists: SJ maintains $\rho{=}0.308$ on conditional RE while LP drops to $\rho{=}{-}0.026$.
199	EM ranks first across all four tested conditional configurations: SciERC NER ($\rho{=}0.360$), CoNLL Qwen $N{=}16$ ($\rho{=}0.466$), CoNLL LLaMA 3-seed ($\rho{=}0.462$), and SciERC RE ($\rho{=}0.417$). This holds despite full-set rankings ranging from \#1 (CoNLL Qwen) to \#5 (SciERC RE).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "3708f55b-e0f8-4600-ac3b-6759cb7a4e35",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
      "content": "\\section{Notation}\\label{app:notation}\n\nTable~\\ref{tab:notation} summarizes the notation used throughout the paper.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\begin{tabular}{cl}\n\\toprule\nSymbol & Meaning \\\\\n\\midrule\n$\\mathcal{M}$ & Language model \\\\\n$x$ & Input instance \\\\\n$y_i$ & $i$-th stochastic sample \\\\\n$N$ & Number of samples \\\\\n$T$ & Sampling temperature \\\\\n$c(\\cdot)$ & Confidence signal \\\\\nSJ & Soft Jaccard similarity \\\\\nFK & Fleiss' $\\kappa$ \\\\\nEM & Exact-match voting rate \\\\\nVC ($c_{\\mathrm{vc}}$) & Entity voting confidence \\\\\nLP ($c_{\\mathrm{lp}}$) & Log-probability (mean token log-likelihood) \\\\\n\\bottomrule\n\\end{tabular}\n\\caption{Notation used throughout the paper.}\n\\label{tab:notation}\n\\end{table}\n\n\\section{Robustness Analysis}\\label{app:robustness}\n\nWe exclude instances with empty gold annotations from all correlation analyses (CoNLL: 697/3{,}453 instances, 20.2\\%; SciERC: 22/551, 4.0\\%).\nFor these instances, F1 is trivially zero regardless of prediction quality, and consistency signals reflect agreement on the empty set rather than extraction quality. Including them inflates or deflates Spearman $\\rho$ depending on signal behavior at the boundary.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Signal robustness across configurations (Spearman $\\rho$). Top: temperature on Qwen SciERC. Middle: sample size on Qwen SciERC. Bottom: transfer across model families (both 8B) (LLaMA CoNLL $N{=}16$, 3-seed mean $\\pm\\sigma$). $^\\dagger$Mean over 3 seeds ($\\sigma{=}0.013$; individual: 0.398, 0.423, 0.410). $\\sigma$ computed as sample standard deviation.}\n\\label{tab:robustness}\n\\begin{tabular}{llcc}\n\\toprule\n& & NER $\\rho$ & RE $\\rho$ \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{Temperature} (Qwen SciERC, $N{=}8$)} \\\\\n\\quad SJ & $T{=}0.7$ & 0.364 & 0.234 \\\\\n\\quad SJ & $T{=}1.0$ & 0.360 & 0.250 \\\\\n\\quad FK & $T{=}0.7$ & 0.289 & 0.184 \\\\\n\\quad FK & $T{=}1.0$ & 0.267 & 0.275 \\\\\n\\quad LP & $T{=}0.7$ & 0.249 & --- \\\\\n\\quad LP & $T{=}1.0$ & 0.205 & 0.266 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{Sample size} (Qwen SciERC, $T{=}1.0$)} \\\\\n\\quad SJ & $N{=}8$  & 0.360 & 0.250 \\\\\n\\quad SJ & $N{=}16$ & 0.411$^\\dagger$ & 0.281 \\\\\n\\quad FK & $N{=}8$  & 0.267 & 0.275 \\\\\n\\quad FK & $N{=}16$ & 0.283 & 0.279 \\\\\n\\midrule\n\\multicolumn{4}{l}{\\textit{Across model families} (LLaMA CoNLL, $N{=}16$, 3 seeds)} \\\\\n\\quad SJ &  & $0.474{\\pm}0.009$ & --- \\\\\n\\quad FK &  & $0.467{\\pm}0.009$ & --- \\\\\n\\quad EM &  & $0.473{\\pm}0.010$ & --- \\\\\n\\quad VC &  & $0.470{\\pm}0.006$ & --- \\\\\n\\quad LP &  & $0.311{\\pm}0.003$ & --- \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_temperature_robustness}\n\\caption{Temperature robustness on SciERC ($N{=}8$). Top: NER; bottom: RE. SJ maintains stable $\\rho$ across $T{=}0.7$ and $T{=}1.0$, while FK shows mixed sensitivity. LP shows the largest NER temperature effect ($\\Delta\\rho{=}{+}0.044$); RE $T{=}0.7$ LP data unavailable.}\n\\label{fig:temperature_robustness}\n\\end{figure}\n\n\\paragraph{Temperature sensitivity.}\nSJ NER $\\rho$ shifts from 0.364 ($T{=}0.7$) to 0.360 ($T{=}1.0$), a difference of 0.004.\nFK NER $\\rho$ drops by 0.022, while RE $\\rho$ increases by 0.091, likely reflecting reduced diversity at lower temperature interacting differently across tasks.\nLP exhibits the largest temperature effect on NER ($\\rho{=}0.249$ at $T{=}0.7$ vs.\\ $0.205$ at $T{=}1.0$, $\\Delta{=}{+}0.044$), consistent with lower temperature concentrating probability mass and improving LP's discriminative power for quality estimation; RE $T{=}0.7$ LP data is not available.\nAcross all comparisons, the signal hierarchy is preserved at both temperatures on NER (SJ${>}$FK${>}$LP at $T{=}0.7$: $0.364{>}0.289{>}0.249$; at $T{=}1.0$: $0.360{>}0.267{>}0.205$).\n\n\\paragraph{Sample size scaling.}\nIncreasing from $N{=}8$ to $N{=}16$ improves SJ on Qwen SciERC NER: $\\rho$ rises from 0.360 to $0.411{\\pm}0.010$ (three seeds: 0.398, 0.423, 0.410), a gain of $+0.047$.\nThe magnitude of $N$-scaling gains is setting-dependent (LLaMA SciERC NER yields $+0.016$ and Qwen CoNLL NER $+0.014$), though the direction is consistently positive.\nLLaMA CoNLL exhibits the most uniform scaling: all four consistency signals gain $\\Delta\\rho{\\approx}{+}0.042$ (range: $+0.039$ to $+0.044$) while LP gains only $+0.004$ (Table~\\ref{tab:quality_estimation}).\nFK $N$-scaling is seed-dependent: Qwen SciERC gains range from $+0.005$ to $+0.023$ across seeds (mean $+0.016$), while LLaMA CoNLL yields $+0.039$ (3-seed mean); individual seed FK shifts vary substantially under the unified pipeline, so this should not be interpreted as a robust trend.\nVC $N$-scaling is consistently positive ($+0.005$ on Qwen CoNLL, $+0.018$ on LLaMA SciERC, $+0.030$ on Qwen SciERC), while LP is approximately $N$-invariant ($\\Delta{\\leq}0.034$).\nSJ, EM, and VC scale consistently across all tested settings; only FK shows seed-dependent variation that does not constitute a reliable trend, structural and binary-agreement signals are the most robust to $N$.\nAt $N{=}16$, SJ converges to comparable NER performance with VC ($\\Delta{=}0.002$) while exhibiting lower cross-seed variance ($\\sigma{=}0.010$ vs.\\ $0.026$), a more stable alternative at higher sample sizes.\n\n\\paragraph{Transfer across model families.}\nLLaMA-3.1-8B-Instruct shows a similar SJ--FK ordering on SciERC NER (SJ $\\rho{=}0.325{\\pm}0.021$, FK $\\rho{=}0.256{\\pm}0.024$, $\\Delta\\rho{=}0.069$; permutation $p{=}0.06$, borderline).\nOn CoNLL, the gap across model families is minimal (Table~\\ref{tab:quality_estimation}): SJ achieves $\\rho{=}0.431$ (LLaMA) vs.\\ 0.436 (Qwen), $\\Delta{=}0.005$.\nAt $N{=}16$, the structural-over-LP advantage holds across all four tested NER settings: Qwen SciERC (VC $\\rho{=}0.409$ vs.\\ LP 0.239, $\\Delta{=}{+}0.170$), Qwen CoNLL (EM $\\rho{=}0.463$ vs.\\ LP 0.328, $\\Delta{=}{+}0.135$),\\footnote{Qwen CoNLL $N{=}16$ was not recomputed under the unified pipeline; LP $\\rho{=}0.328$ may differ slightly from the registry value (0.315) due to instance filtering.} LLaMA SciERC (VC $\\rho{=}0.452$ vs.\\ LP 0.277, $\\Delta{=}{+}0.175$), and LLaMA CoNLL 3-seed (SJ $\\rho{=}0.474{\\pm}0.009$ vs.\\ LP $0.311{\\pm}0.003$, $\\Delta{=}{+}0.163$).\n\n\\paragraph{FK independence: instance-level permutation test.}\\label{app:fk_independence}\n\nTo verify that Fleiss' $\\kappa$ reflects genuine within-instance agreement rather than marginal-rate artifacts, we conduct instance-level permutation tests across three configurations.\nFor each instance, we permute sample labels 10{,}000 times to generate a null distribution of FK under independence, then compare the observed FK against this null via a one-sample $t$-test and permutation $p$-value.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Instance-level FK independence test. Permutation tests confirm FK reflects true within-instance agreement (all $p{<}0.001$). Split-half reliability $r$ computed by randomly partitioning $N$ samples into two halves and correlating their FK scores.}\n\\label{tab:fk_independence}\n\\begin{tabular}{lrcccc}\n\\toprule\nConfig & $n$ & FK mean & 95\\% CI & $t$ & Split-half $r$ \\\\\n\\midrule\nSciERC (Qwen) & 529 & 0.402 & [0.376, 0.428] & 30.8 & 0.395 \\\\\nCoNLL (LLaMA) & 2{,}756 & 0.927 & [0.919, 0.935] & 225.9 & 0.578 \\\\\nCoNLL (Qwen) & 2{,}756 & 0.720 & [0.706, 0.734] & 102.1 & 0.520 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nTable~\\ref{tab:fk_independence} reports the results.\nAll configurations reject the independence null at $p{<}0.001$ ($n{=}529$--$2{,}756$), FK captures genuine inter-sample agreement rather than chance label co-occurrence.\nSplit-half reliability ranges from $r{=}0.395$ (SciERC) to $r{=}0.578$ (CoNLL LLaMA), moderate stability: FK estimates from half the samples correlate positively with those from the other half, though the SciERC value suggests noisier estimation on harder tasks with fewer samples.\nThe higher FK means on CoNLL ($0.720$--$0.927$) vs.\\ SciERC ($0.402$) mirror the difficulty gradient observed in the main quality estimation results.\n\n\\section{Calibration Analysis}\\label{app:calibration}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_reliability}\n\\caption{Reliability diagrams on SciERC ($N{=}8$, $T{=}1.0$). Top: mean F1 vs.\\ binned confidence; bottom: instance counts per bin. Left: NER; right: RE. NER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE shows greater miscalibration (ECE 0.109--0.339), RE calibration remains challenging for compound extraction tasks.}\n\\label{fig:reliability}\n\\end{figure*}\n\nReliability diagrams use 10 equal-width bins.\nNER signals are reasonably well-calibrated (calibration ECE 0.069--0.096), while RE exhibits greater miscalibration (ECE 0.109--0.339), translating consistency scores into calibrated confidence estimates is feasible for NER but remains challenging for compound extraction tasks.\n\n\\section{Additional Analyses}\\label{app:additional}\n\n\\begin{figure*}[t]\n\\centering\n\\includegraphics[width=\\textwidth]{fig_signal_heatmap}\n\\caption{Quality estimation heatmap (Spearman $\\rho$) across five signals and four configurations. Left: full evaluation set; right: conditional set (non-zero F1 instances). On the full set, structural signals dominate on SciERC NER while all signals converge on CoNLL. On the conditional set, EM emerges as the strongest signal on both NER ($\\rho{=}0.360$) and RE ($\\rho{=}0.417$), while LP RE collapses to near-zero ($\\rho{=}0.011$).}\n\\label{fig:signal_heatmap}\n\\end{figure*}\n\n\\paragraph{Per-relation diagnostic.}\nRE signal degradation is relation-specific.\n\\textsc{Feature-Of} has near-zero correlation ($\\rho{=}0.004$), while \\textsc{Hyponym-Of} achieves $\\rho{=}0.646$.\nThe primary bottleneck is entity span errors, which account for 55.5\\% of RE false negatives. This is a prerequisite failure that consistency signals cannot detect, as they measure agreement among equally incorrect extractions.\nWe note that RE analysis relies on a single dataset (SciERC); generalization to other RE benchmarks remains to be validated.\n\n\\paragraph{Capability stratification.}\nFor NER, SJ effectiveness scales with structural complexity: on SciERC instances with 6+ entities, $\\rho{=}0.547$, compared to $\\rho{=}0.415$ for 1--2 entities.\nThe SJ advantage over LP remains stable across sentence-length quartiles ($\\Delta\\rho{\\approx}0.08$--$0.20$).\nFor RE, SJ $\\rho$ increases monotonically with sentence length (Q1: 0.110 $\\to$ Q4: 0.473; Fisher $z$-test $p{=}0.004$): longer, more relation-dense sentences provide richer structure for consistency-based estimation.\nBoth proxies are weakly correlated with F1 ($|r|{<}0.15$), they capture input complexity rather than directly predicting output quality; however, entity count and sentence length are themselves moderately correlated ($\\rho{=}0.650$), so they reflect overlapping rather than independent complexity dimensions.\nFor RE, entity count and relation count are strongly correlated ($\\rho{=}0.769$) and thus reflect a single structural complexity dimension rather than independent axes.\nOn the high-complexity RE subset ($n{=}81$, high relation count), signals improve substantially: VC reaches $\\rho{=}0.630$, LP $\\rho{=}0.554$, and SJ $\\rho{=}0.502$, all far above the full-set levels.\nRicher relational structure provides more signal for consistency-based estimation, complementing the task-level boundary established by WNUT-17: structural signals are most effective within a ``sweet spot'' of sufficient model capability and sufficient output complexity.\n\n\\paragraph{Length vs.\\ log-probability.}\nFigure~\\ref{fig:length_logprob_scatter} shows that mean log-probability is weakly positively correlated with output length (NER: $\\rho{=}0.386$, $n{=}4{,}232$; RE: $\\rho{=}0.326$, $n{=}3{,}176$), ruling out length-penalty confounding as an explanation for LP's selection failure: longer outputs receive \\textit{higher}, not lower, token-averaged log-probability under constrained decoding.\n\n\\begin{figure}[t]\n\\centering\n\\includegraphics[width=\\columnwidth]{fig_length_logprob_scatter}\n\\caption{Output length vs.\\ mean log-probability on SciERC ($N{=}8$, $T{=}1.0$). Positive correlations (NER: $\\rho{=}0.386$; RE: $\\rho{=}0.326$) rule out length-penalty confounding.}\n\\label{fig:length_logprob_scatter}\n\\end{figure}\n\n\\paragraph{Evaluation circularity and LOO-SJ equivalence.}\nConsensus-proximity selection chooses $\\hat{y} = \\arg\\max_{y_i} \\sum_{j \\neq i} \\text{SJ}(y_i, y_j)$.\nLeave-one-out SJ (LOO-SJ) for sample $y_i$ is $\\text{LOO-SJ}_i = \\frac{1}{N-1}\\sum_{j \\neq i} \\text{SJ}(y_i, y_j)$.\nSince the $\\frac{1}{N-1}$ constant is shared across all candidates within an instance, $\\arg\\max_{y_i} \\text{LOO-SJ}_i = \\arg\\max_{y_i} \\sum_{j \\neq i} \\text{SJ}(y_i, y_j)$; the two selection rules are equivalent.\nStandard (non-LOO) SJ adds the self-comparison term $\\text{SJ}(y_i, y_i) = 1$ to each candidate, which is constant and thus does not affect ranking.\nEmpirically, LOO-SJ yields $\\Delta\\rho{=}{-}0.014$ relative to standard SJ (a correlation-level difference), with a maximum per-instance score difference of $3.1{\\times}10^{-4}$ (negligible at the individual prediction level).\nEvaluation circularity is negligible.\n\n\\paragraph{SJ normalizer robustness.}\nEquation~\\ref{eq:sj} uses $\\max(|g_i|, |g_j|)$ as the denominator; an alternative is the union size $|g_i \\cup g_j|$.\nTable~\\ref{tab:sj_normalizer} compares the two normalizers across all six model--dataset combinations ($N{=}8$, $T{=}1.0$, seed${=}42$): $|\\Delta\\rho|{<}0.01$ in every case, the choice between max and union normalization does not affect conclusions.\n\n\\begin{table}[h]\n\\centering\n\\small\n\\caption{SJ normalizer comparison (Spearman $\\rho$; $N{=}8$, $T{=}1.0$, seed${=}42$). Max: $\\max(|g_i|,|g_j|)$; Union: $|g_i \\cup g_j|$.}\n\\label{tab:sj_normalizer}\n\\begin{tabular}{@{}ll ccc@{}}\n\\toprule\nDataset & Model & $\\rho$(max) & $\\rho$(union) & $\\Delta\\rho$ \\\\\n\\midrule\nCoNLL & Qwen3-8B & .436 & .438 & $-$.002 \\\\\nCoNLL & Qwen3-4B & .422 & .421 & $+$.000 \\\\\nCoNLL & LLaMA-8B & .431 & .432 & $-$.000 \\\\\nSciERC & Qwen3-8B & .360 & .365 & $-$.005 \\\\\nSciERC & Qwen3-4B & .422 & .423 & $-$.001 \\\\\nSciERC & LLaMA-8B & .363 & .372 & $-$.009 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{Conditional filtering details.}\nOn LLaMA conditional RE (non-zero F1 instances), SJ recovers to $\\rho{=}0.405$ while FK drops to $\\rho{=}0.259$, consistent with the NER structural advantage; on full-set RE, however, the SJ--FK difference is non-significant ($\\Delta\\rho{=}{-}0.005$, $p{=}0.53$; preliminary).\nAt $N{=}16$, the divergence persists: SJ maintains $\\rho{=}0.308$ on conditional RE while LP drops to $\\rho{=}{-}0.026$.\nEM ranks first across all four tested conditional configurations: SciERC NER ($\\rho{=}0.360$), CoNLL Qwen $N{=}16$ ($\\rho{=}0.466$), CoNLL LLaMA 3-seed ($\\rho{=}0.462$), and SciERC RE ($\\rho{=}0.417$). This holds despite full-set rankings ranging from \\#1 (CoNLL Qwen) to \\#5 (SciERC RE).",
      "numLines": 200,
      "startLine": 0,
      "totalLines": 1572
    }
  }
}
```

</details>

---


### Assistant

_source line 84_

<details><summary>Logged reasoning block</summary>

```text
Now I have a lot of data. Let me also read the sections about the cross-selection table and more data from the appendix that contains the WNUT table data and the multi-seed data. But let me also search for the specific QE and selection data referenced in the paper.

Let me now systematically build the audit. I'll focus on the key quantitative claims in each section and cross-reference them with registry data.

### Key claims to audit:

**Abstract:**
1. "ρ up to 0.45 on CoNLL-2003" → Registry: CoNLL Qwen N=8 SJ ρ=0.436, EM ρ=0.451. 

The paper's Table 1 shows EM ρ=0.451, which matches the registry data and rounds to the stated 0.45. For AUROC, the registry shows CoNLL EM AUROC=0.816, which the paper also reports in Table 1 and rounds to the claimed 0.82. Both metrics check out. Now I need to verify the F1 improvement claim of +5-8pp at 80% coverage.

Looking at the registry's selective prediction experiments, I see SciERC improved by +5.0pp, CoNLL by +8.4pp, and FewNERD by +6.2pp, which confirms the +5-8pp range. For the LP-weighted aggregation claim, the paper's Table 5 reports +1.40pp on FewNERD and +1.02pp on SciERC as multi-seed means with significance testing, but the registry shows different values in the n8_fair_cv results. I need to reconcile this—the registry appears to show single-fold cross-validation values while the paper reports multi-seed averages, so I should check whether these are measuring the same thing. from averaging results across multiple training seeds. Looking at the specific numbers in Table 5 versus what's recorded in the registry, there's a discrepancy—the paper reports LP-weighted construction gains of +1.40±0.51pp for Few-NERD, but the registry shows +0.88pp for the cross-validation run, which suggests these might be measuring slightly different experimental setups or the registry value is from a single seed rather than the multi-seed average reported in the paper. The registry uses different evaluation protocols than the paper—cross-validation on single models versus multi-seed means across different training runs—which explains why the numbers don't align. The paper's reported improvements like +1.02pp on SciERC and +1.40pp on FewNERD come from averaging across multiple seeds, so I need to verify the introduction claims against the actual multi-seed results rather than individual registry entries.

For the Few-NERD claim of +1.39pp, the registry shows a four-seed mean of 1.38pp with a confidence interval of [1.32, 1.44], which is close enough that rounding from 1.385 could explain the discrepancy. I can see individual seed results for seeds 42 and 789 both showing +1.36pp, but the registry doesn't have LP delta values for seeds 123 and 456, so I can't fully reconstruct how the four-seed mean was calculated.

For SciERC, the paper claims a +0.2pp LP gain with p=0.29, and Table 2 confirms this with LP at 0.647 versus greedy at 0.645. But I'm noticing inconsistencies in the framing document—it mentions both "+0.6pp" and "+0.2pp" in different places, and the bootstrap confidence interval is reported as [-0.030, +0.042], which doesn't quite align with the +0.2pp claim.

Looking at Table 3, the single-seed SciERC result shows +0.61pp with p=0.193, which differs from the 2-seed mean in Table 2 because they're using different experimental setups. The framing doc compounds this confusion by stating "LP full-set: +0.6pp, bootstrap p=0.39" while also reporting that same bootstrap CI that centers closer to +0.2pp. The 2-seed mean shows 0.2pp difference between LP selection and greedy, while the single-seed bootstrap gives 0.6pp—these are measuring different things. The intro reports the 2-seed result of +0.2pp with p=0.29. The MDE calculation of 1.5pp at 80% power with n=529 is a theoretical statistical bound, not an empirical finding. For instance degeneracy, the paper shows a range across datasets (13.8% to 67.9%), and the intro's "13-87%" claim doesn't quite match the actual table values. I'm trying to pin down where the 87% figure comes from in the paper's claim about instance degeneracy ranging from 13-87%. The main table shows values of 13.8% (FewNERD), 17.8% (SciERC), 48.4% (CoNLL), and 67.9% (WNUT), but none reach 87%, so it must be coming from either a different model configuration or the appendix that I haven't fully checked yet. Looking at the actual data across the four datasets, the range only goes from about 13.8% to 67.9%, so the 87% figure in the intro doesn't match "across our benchmarks" unless it's pulling from a different table that includes model and configuration variations. I need to check if there's a degeneracy table that might clarify whether "benchmarks" here means just the datasets or all experimental configurations combined.

Now I'm cross-referencing the paper's quality estimation results against the registry data. The voting confidence and Spearman metrics for SciERC are matching up closely with the experimental runs, which is a good sign for consistency.

However, I'm noticing a potential discrepancy with the AUROC value for voting confidence on SciERC—the registry shows 0.6841 but the paper reports 0.663. I need to verify which experimental configuration the paper actually used, since this could be a meaningful difference. I'm comparing the paper's reported AUROC values against what's in the registry for the same experiments, and there are consistent gaps across all methods—VC is off by 0.021, SJ by 0.042, and FK by 0.027—which suggests either different evaluation settings or a systematic difference in how the metrics were computed.

But EM is a massive outlier: the paper shows 0.614 while the registry has 0.7493, a 0.135 discrepancy that's way too large to ignore, especially since the framing document actually lists 0.749, which matches the registry almost exactly. The paper table header explicitly says "AUROC," so either the paper used a different calculation method, or these might actually be AUPRC values mislabeled as AUROC.

Looking deeper, the paper mentions excluding instances with no gold annotations (529 instances removed from SciERC), which could affect the AUROC calculation. There's also a footnote about how gold-filtered versus full-set evaluations differ by 0.03-0.05 on CoNLL due to boundary effects. The table header says "AUC" rather than "AUROC," which might indicate a different metric altogether.

Comparing the actual numbers: CoNLL values like EM's 0.816 match the framing doc, but SciERC values are consistently lower than what I'd expect. The registry shows higher AUROC scores for SciERC (SJ at 0.6917, FK at 0.629), suggesting the paper's table might use a different pipeline or metric variant than what's in the registry. Looking at the discrepancy pattern more carefully, EM shows a massive gap of 0.135 while LP matches perfectly at 0.578, which suggests the paper might be using different seeds or configurations than the registry data—yet the ρ values align exactly with exp_012_rerun_1024, so something else is going on. The possibility that the paper is reporting AUPRC instead of AUROC for certain columns keeps nagging at me, though that would be a significant labeling error.

Wait, I'm noticing both EM and VC are consistently lower in the paper than the registry. The paper's Method section specifies "AUROC classifying instances as above/below median F1," and if SciERC has many tied F1 values at the median, how those ties are handled could shift the AUROC—with EM being a binary signal, it would be most sensitive to threshold definition changes. This discrepancy is substantial enough that it needs investigation.

Actually, let me check the CoNLL numbers more carefully. Comparing the paper's reported values against the registry experiment, all five metrics are nearly identical—EM, SJ, VC, FK, and LP all match within rounding error. So the CoNLL results align perfectly.

But SciERC is a different story. The ρ values from exp_012_rerun_1024 match what's in the paper exactly, yet the AUROC values don't line up at all. This suggests either the paper uses a different AUROC calculation method than the registry, or there's something else going on with how that column was populated.

The discrepancy is pretty stark—the paper shows EM at 0.614 while the registry has 0.749. I'm wondering if the paper might have been revised with a different AUROC computation approach, or if the registry values are from a later update that the paper doesn't reflect.

Now I'm shifting focus to check another inconsistency the task flagged: the Discussion mentions "+0.1pp over single-sample" while the Limitations section says "+0.4pp over greedy". Let me search for these exact phrases to see what's actually being compared.

Looking through the Discussion, I found "LP selection yields +2.9pp (p=0.004; Table N)" for the non-tied subset, but I'm not seeing the "+0.1pp over single-sample" phrasing. In the Limitations section, I see "Ad-hoc LP×VC combinations yield at most +0.2pp over greedy (not significant)" rather than "+0.4pp". These specific numbers don't match what the task mentioned, so either they're from an earlier version or I need to search more carefully.

Wait—I found them in the experiments.tex file. The "+0.1pp" and "−0.4pp" are actually about LP selection failures in the 72B zero-shot regime: SciERC shows −0.1pp and CoNLL shows −0.4pp. These are describing where LP selection breaks down, not construction improvements. I'm realizing these are just different results across datasets rather than actual contradictions—the negative deltas for LP selection on SciERC and CoNLL are separate findings. The framing document mentions specific positive values in different sections, so I should search the actual tex files directly to verify those exact claims rather than continuing to parse them from memory. Let me shift focus to compiling the verifiable claims I need to audit, starting with checking the Abstract's correlation coefficient against Table 1. I'm checking the greedy baseline at 0.645 which gives the 0.2pp difference on SciERC. Moving through the verification checklist—the instance degeneracy range is suspicious since WNUT only reaches 67.9% in the table but the paper claims up to 87%, and I need to track down where that higher number comes from. The correlation and AUROC values are mostly matching the registry, though there's a discrepancy on SciERC where the paper shows .614 but the registry has .749, and I still need to verify the LLaMA CoNLL numbers in Table 1.

For Table 2, the selection method values are checking out so far—Oracle at 0.775, Greedy at 0.645, and LP at 0.647 all match—but I need to verify the remaining methods like SJ, FK, EM, VC, and Random. In Table 3, the cross-dataset results are mostly aligning with the registry, though the WNUT degeneracy metric is confusing since the registry shows 53.7% sample_f1_pct_zero rather than the 67.9% reported, and these appear to be measuring different things. CoNLL and SciERC greedy scores and degeneracy rates are matching up correctly.

Now I'm noticing the SciERC values across tables—the paper shows greedy at 0.6439 in the framing and 0.644 in Table 3, which is consistent with the 0.645±0.001 mean from Table 2 when accounting for single-seed versus two-seed averaging. FewNERD also checks out at 0.748 greedy with 13.8% degeneracy. Still need to verify the WNUT LP value.

For WNUT, I'm seeing a mismatch between what the paper reports (ρ = -0.446) and what's in the registry and framing doc—the registry shows -0.414 or -0.409 depending on the experiment, while the framing doc says -0.410. None of these align with the paper's -0.446, so there's a discrepancy I need to track down.

Looking at the experimental setup, the paper's Table 3 uses N=8 samples, but the WNUT entries in the registry are all N=16. This suggests the paper's -0.446 value might come from a separate N=8 experiment that isn't currently in the registry, which could explain why I'm not finding a matching value.

Now checking FewNERD: the paper reports LP ρ = .220, but the registry shows exp_021_fewnerd_full with lp_global_rho = 0.4215. That's a massive discrepancy—nearly double the reported value. Let me look more carefully at what this registry entry actually contains. the registry has logprob rho=0.2052, which matches. For FewNERD though, the registry shows lp_global_rho=0.4215 but the paper reports .220—these don't align, so either the paper used a different LP metric for FewNERD or it came from a separate run. Let me look more carefully at what Table 3 is actually measuring versus Table 1. I'm noticing the FewNERD models were only trained for 3 epochs, and when I look at the individual seed results, they vary dramatically—seed 42 gives an LP ρ of 0.4215 while seed 789 shows 0.1788, which means any multi-seed average would fall somewhere between these values depending on which seeds are included in the calculation. Looking at the SciERC row in Table 3 where LP ρ = .205 matches Table 1's QE correlation, I can confirm that LP ρ represents the cross-instance QE metric. So FewNERD's .220 should also be a cross-instance correlation, but the seed 42 value of 0.4215 is much higher, suggesting either the paper averages multiple seeds with lower values or there's a different calculation being used. The table notes might clarify this discrepancy. The 3-seed mean of 0.220 for FewNERD's LP ρ suggests seeds 123 and 456 have much lower correlations than seed 42's 0.422. Looking at the actual experiment data, seeds 123 and 456 achieve higher greedy F1 scores (0.789 vs 0.748), indicating better-trained models with potentially higher degeneracy rates that could explain the divergent LP correlations.

But there's a discrepancy: the paper framing document reports LP ρ=0.22 for FewNERD from exp_021_fewnerd_full, yet that experiment shows lp_global_rho=0.4215. Either the framing doc is pulling from a multi-seed average, or there's a mismatch in what data was actually used.

Looking at the individual seed values I have—seed 42 gives 0.422, while seeds 123 and 456 are missing but likely around 0.12 based on patterns—averaging those three would land near 0.22, which matches the paper's reported value. So the registry entry might be from a single seed run, while the paper used a three-seed mean.

Now let me verify some of the other reported results, particularly the entity construction improvements shown in Table 5 across both datasets and sampling strategies.

Looking at the registry data for the same experiments, I'm seeing some notable discrepancies between what the paper reports and what's actually stored. For SciERC with the LP weighting, the paper claims a +1.02pp improvement but the registry shows +1.67pp—that's a meaningful gap. The uniform sampling results also don't quite align, and when I check the CoNLL results, the paper reports a small negative effect while the registry indicates this difference isn't statistically significant.

The core issue is that these two sources are using completely different evaluation methodologies. The paper averaged improvements across multiple random seeds, whereas the registry employed 5-fold cross-validation with bootstrap resampling and paired statistical tests. These fundamentally different approaches to measuring performance would naturally produce different numbers, so the discrepancies might not indicate an error so much as a methodological divergence.

To actually verify the paper's multi-seed averaging approach, I'd need access to the individual seed results from the registry data and reconstruct the mean myself. Looking at SciERC specifically, the registry shows a weighted confirmation value of +1.67pp, but the paper reports a multi-seed mean of +1.02pp for the same metric—there's still a gap I can't easily reconcile without seeing the underlying per-seed breakdown.

The registry's evaluation protocol uses 5-fold cross-validation with bootstrap resampling, which is different from the paper's direct application of the threshold. This methodological difference could explain why the numbers diverge. Since I can't access the raw per-seed construction data needed to verify the paper's multi-seed calculations, I'll mark this as unverifiable from the registry alone due to the different evaluation protocols being used.

Now I'm moving on to check the discussion section claims, starting with the MBR SJ median correlation coefficient.

The paper reports ρ=0.524 for MBR utility correlation with F1 on non-degenerate instances, which matches the framing document. However, there's a discrepancy in the p-value for the non-tied subset comparison: the paper states p=0.004 while the framing document says p=0.01. The degeneracy rate at T=1.2 checks out correctly at 14.9%. Moving into the experiments section, I'm verifying the dataset specifications like SciERC with 551 test instances and 6 entity types, and now checking the Few-NERD dataset details. I'm noticing some inconsistencies in the WNUT-17 results—the paper mentions both 51% and 52% for instances with zero F1, and there's a discrepancy with the VC ρ values too, where I'm seeing 0.724 in one place and 0.730 in Table 8. Let me verify these numbers more carefully before moving on to check the SciERC findings. I'm noticing a discrepancy between the N=16 degeneracy rate (0.4844 or 48.4%) and what the paper claims for N=8 in Table 3. Intuitively, N=8 should have higher degeneracy than N=16 since fewer samples means less variation, but the paper lists 48.4% for N=8. I'm also seeing two slightly different values in the data (0.4844 vs 0.474) that are close but not exact, so I need to flag this inconsistency.

Now looking at Few-NERD, the registry shows 10.1% degeneracy but the paper claims 13.8%—a notable gap. When I check the individual seed results (42: 10.1%, 123: 13.1%, 456: 12.1%), averaging just the first three seeds gives 11.77%, which still doesn't match the paper's 13.8%. I'm trying to figure out which seeds were actually used for the FewNERD results—the caption says 3-seed means, but none of my calculations match the reported 13.8% degeneracy. Let me reconsider whether the paper might be using a different set of seeds or if the column actually reports single-seed results despite what the caption claims. The framing document mentions specific degeneracy percentages for different datasets, so I should check if there's a discrepancy between what the caption describes and what's actually computed. The 13.8% figure might stem from a different definition of degeneracy altogether—perhaps counting instances where the majority of samples share the same F1 rather than requiring perfect uniformity across all samples. Or it could reference a separate FewNERD experiment with different training parameters that I haven't located yet. Either way, there's a clear discrepancy between the paper's reported 13.8% and the ~10-13% range I'm seeing across available seeds, with no combination yielding that exact figure. Checking the LoRA rank ablation claims now. The rank=8 degeneracy of 7.2% matches the registry exactly, but the LP correlation shows a discrepancy—the paper reports within-instance ρ≈0.24 while the cross-instance value is 0.2105, so these are measuring different things. Moving on to verify the 72B zero-shot claims in Table 4, starting with SciERC.

The 72B experiments are still running, so I can't fully verify the greedy baseline and headroom values yet. However, the LP correlation values check out—SciERC shows ρ=0.081 and CoNLL shows ρ=-0.002, both consistent with the framing section. The LP-weighted construction improvement of +1.5pp for SciERC aligns with the framing's +1.53pp, though I can't verify the selection failure claims without the complete 72B results.

Now looking at the scale ablation results—the 8B and 4B Spearman values across both datasets are matching the registry outputs when rounded, confirming those measurements are accurate.

For the LP gating claims, I'm verifying the ρ_adj values and threshold stability across the three datasets, and the registry shows the robust range aligns with what's claimed in the paper. Finally, I'm cross-referencing the Few-NERD improvement claim between the introduction and Table 5 to check for consistency.

I'm noticing there's actually a distinction here—the introduction mentions +1.39pp for LP selection but +1.40pp for entity construction, which are different components. Looking more carefully at the introduction's third contribution, it specifies that LP-weighted construction yields +1.40pp on Few-NERD, so the two numbers refer to different ablations rather than being a true inconsistency.

Now examining the SciERC numbers across tables: Table 3 reports +0.61pp for single-seed LP, while Table 2 shows 0.647 for the 2-seed mean, which is about +0.2pp improvement over baseline. The difference in magnitude makes sense given they're using different seed protocols—single-seed versus multi-seed averaging naturally produces different effect sizes.

Looking at the bootstrap results, the primary seed shows a delta of 0.6pp, and when averaged with a second seed's lower delta, the mean drops to around 0.2pp. This explains why the paper correctly reports the larger single-seed effect in Table 3 and the smaller 2-seed mean in Table 2. The variance across seeds accounts for the discrepancy.

Now checking the claim about the three factors not forming a predictive model with R² values below zero across the configurations.

For the supposed contradiction between Discussion and Limitations about the performance deltas, I'm searching for the exact phrases. It looks like these might actually be referring to the 72B zero-shot results in the Scaling section showing negative effects on SciERC and CoNLL, not separate contradictory statements in different sections. Let me verify whether this contradiction actually exists in the paper or if it's already been resolved.

Now I'm shifting focus to document the critical issues I've found. The main one is a significant discrepancy in the SciERC AUROC values—the paper shows .614 for EM AUROC in Table 1, but the registry shows 0.7493 for the same experiment. Before I finalize this as a critical issue, I need to double-check whether the "AUC" column in the table might be measuring something different than what the registry reports.

The paper's Section 3.2 defines AUROC as classifying instances above or below median F1, which seems straightforward. But I'm noticing the registry has both full and conditional metrics, and I should verify whether the paper is actually using the conditional AUROC values instead. Let me pull the conditional metrics from the registry data to see if those align better with what's reported in the table. Looking at the results from exp_015_v2, I'm seeing different AUROC values across the pipeline variants—the averaged approach gives different numbers than what's in the paper. The Spearman ρ values match exactly, which makes sense since that metric is unambiguous, but AUROC is sensitive to how the threshold for binarization is set. This suggests the paper might have recomputed or updated the AUROC calculations after the registry was created, so I should flag this as a discrepancy worth investigating rather than treating it as a straightforward error.

Now looking at the other metrics, there are several inconsistencies: FewNERD's LP ρ shows 0.22 in the paper but 0.4215 in the registry for seed 42, though the framing document also says 0.22—the 3-seed average might explain the gap but I can't verify it from what's available. FewNERD's degeneracy rate is reported as 13.8% in the paper while the registry shows a range of 10.1-13.1% across seeds with a mean around 11.8%. For WNUT, the LP ρ discrepancy could stem from different sample sizes—the paper shows -.446 while the registry gives -.414 or -.409 depending on whether N=16 or if the paper used N=8. The zero-F1 rate for WNUT is also inconsistent within the paper itself, claiming both "52%" and "51%" while the registry shows 53.7%. Additionally, the VC ρ value for WNUT appears to differ between sections 4.2 and 4.3 of the paper.

There are also some minor issues: the introduction mentions a "13-87%" degeneracy range that I can't locate in any N=8 results, FewNERD's LP selection shows a trivial 1.39 vs 1.38 rounding difference, and the entity construction numbers use different methodologies between the registry's cross-validation approach and the paper's multi-seed means. I'm searching through the tex files to track down the specific phrases about performance improvements mentioned in the task—the closest match I've found is in the Scaling section where 72B zero-shot LP selection shows different effects on SciERC and CoNLL, but these appear to be separate datasets rather than contradictory claims.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "98d539be-1ce9-4010-8286-4451e76cd360",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011kHLZ5gF3ps9DsJobCW3cM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6278,
      "cache_read_input_tokens": 81991,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6278
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

_source line 85_

Let me search for the known contradiction and verify specific WNUT numbers.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "9dac5d94-2071-40ee-8c69-eafebc56427b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011kHLZ5gF3ps9DsJobCW3cM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6278,
      "cache_read_input_tokens": 81991,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6278
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

_source line 86_

<details open><summary>🔧 Tool call — Grep · `toolu_01K5BC8hQFNqtDhVdDzhjKXk`</summary>

```json
{
  "pattern": "0\\.1.*pp|0\\.4.*pp|\\+0\\.1|\\+0\\.4",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/discussion.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "45ef4f1e-3bff-4e28-90d9-1021a87b773b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011kHLZ5gF3ps9DsJobCW3cM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6278,
      "cache_read_input_tokens": 81991,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6278
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

_source line 87 · 2026-05-19T13:41:39.495Z_

<details><summary>↩ Tool result · `toolu_01K5BC8hQFNqtDhVdDzhjKXk`</summary>

```text
5:Where compression is mitigated (LP range ${\geq}0.05$, $n{=}210$), LP selection yields $+2.9$~pp ($p{=}0.004$; Table~\ref{tab:nontied_main}), but $\varepsilon{=}0.05$ is post-hoc ($p_{\text{adj}}{=}0.14$ after joint correction; Appendix~\ref{app:epsilon_robustness}), so this is exploratory evidence.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "80c13dd0-0233-4290-a794-2987d2981887",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "5:Where compression is mitigated (LP range ${\\geq}0.05$, $n{=}210$), LP selection yields $+2.9$~pp ($p{=}0.004$; Table~\\ref{tab:nontied_main}), but $\\varepsilon{=}0.05$ is post-hoc ($p_{\\text{adj}}{=}0.14$ after joint correction; Appendix~\\ref{app:epsilon_robustness}), so this is exploratory evidence.",
    "numLines": 1
  }
}
```

</details>

---


### Tool call

_source line 88_

<details open><summary>🔧 Tool call — Grep · `toolu_018LT9ZqNLuit5SEAJoCaTFz`</summary>

```json
{
  "pattern": "0\\.1.*pp|0\\.4.*pp|\\+0\\.1|\\+0\\.4|single.sample|over greedy",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/limitations.tex",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "021bf4e5-8e36-4f94-baae-0e9646824adc",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011kHLZ5gF3ps9DsJobCW3cM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6278,
      "cache_read_input_tokens": 81991,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6278
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

_source line 89 · 2026-05-19T13:41:40.918Z_

<details><summary>↩ Tool result · `toolu_018LT9ZqNLuit5SEAJoCaTFz`</summary>

```text
3:Entity-level construction assumes the model produces useful partial outputs across samples; when model capability is insufficient (WNUT-17, 51\% F1${=}0$), this precondition fails and construction cannot improve over greedy.
12:Ad-hoc LP${\times}$VC combinations yield at most $+0.2$~pp over greedy (not significant; \S\ref{sec:discussion}); whether \textit{learned} combinations could close the gap remains open.
16:Our selection experiments use 3 training seeds for Few-NERD and CoNLL (stability $\sigma{\leq}0.04$~pp for LP selection); these confirm robustness on the key positive and negative datasets. SciERC uses 1 primary seed with high seed sensitivity ($\sigma{=}0.48$~pp, $n{=}529$), which reflects limited within-seed statistical power.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "3cbb62fa-39ed-4061-8a83-a34449c06d01",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "3:Entity-level construction assumes the model produces useful partial outputs across samples; when model capability is insufficient (WNUT-17, 51\\% F1${=}0$), this precondition fails and construction cannot improve over greedy.\n12:Ad-hoc LP${\\times}$VC combinations yield at most $+0.2$~pp over greedy (not significant; \\S\\ref{sec:discussion}); whether \\textit{learned} combinations could close the gap remains open.\n16:Our selection experiments use 3 training seeds for Few-NERD and CoNLL (stability $\\sigma{\\leq}0.04$~pp for LP selection); these confirm robustness on the key positive and negative datasets. SciERC uses 1 primary seed with high seed sensitivity ($\\sigma{=}0.48$~pp, $n{=}529$), which reflects limited within-seed statistical power.",
    "numLines": 3
  }
}
```

</details>

---


### Tool call

_source line 90_

<details open><summary>🔧 Tool call — Grep · `toolu_01GdPg246zhVERmZrqfFyT7J`</summary>

```json
{
  "pattern": "0\\.724|0\\.730|WNUT.*VC|VC.*WNUT",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "8980df3a-e84a-4c2b-8216-b1df042d3fcf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011kHLZ5gF3ps9DsJobCW3cM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6278,
      "cache_read_input_tokens": 81991,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6278
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

_source line 91 · 2026-05-19T13:41:41.893Z_

<details><summary>↩ Tool result · `toolu_01GdPg246zhVERmZrqfFyT7J`</summary>

```text
docs/paper/sections/experiments.tex:48:At the signal-collapse boundary (WNUT-17, macro F1${\approx}$42\%), full-set correlations are dominated by the zero/non-zero boundary (VC $\rho{=}0.724$ but conditional $\rho{=}0.038$; Table~\ref{tab:wnut}); LP shows the reverse (conditional $\rho{=}0.350$; Figure~\ref{fig:signal_heatmap}).
docs/paper/sections/experiments.tex:104:Yet QE remains effective on WNUT-17 (VC $\rho{=}0.730$; Table~\ref{tab:wnut}), confirming QE-selection decoupling at this boundary.
docs/paper/sections/appendix.tex:226:VC's high full-set $\rho{=}0.724$ is entirely driven by the zero/non-zero boundary (conditional $\rho{=}0.038$, $p{=}0.49$), while LP's conditional $\rho{=}0.350$ is the highest among all signals on the non-zero subset, full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "79dea783-8ffd-402a-b459-7b5ad08116ee",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:48:At the signal-collapse boundary (WNUT-17, macro F1${\\approx}$42\\%), full-set correlations are dominated by the zero/non-zero boundary (VC $\\rho{=}0.724$ but conditional $\\rho{=}0.038$; Table~\\ref{tab:wnut}); LP shows the reverse (conditional $\\rho{=}0.350$; Figure~\\ref{fig:signal_heatmap}).\ndocs/paper/sections/experiments.tex:104:Yet QE remains effective on WNUT-17 (VC $\\rho{=}0.730$; Table~\\ref{tab:wnut}), confirming QE-selection decoupling at this boundary.\ndocs/paper/sections/appendix.tex:226:VC's high full-set $\\rho{=}0.724$ is entirely driven by the zero/non-zero boundary (conditional $\\rho{=}0.038$, $p{=}0.49$), while LP's conditional $\\rho{=}0.350$ is the highest among all signals on the non-zero subset, full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.",
    "numLines": 3
  }
}
```

</details>

---


### Tool call

_source line 92_

<details open><summary>🔧 Tool call — Grep · `toolu_01WLNh2mN3T9fTrEjmAoGtke`</summary>

```json
{
  "pattern": "87\\\\\\\\%|87\\%|87.*degen",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "d2de31f8-b37b-40d1-96e2-1d8c3758cb48",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011kHLZ5gF3ps9DsJobCW3cM",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 6278,
      "cache_read_input_tokens": 81991,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 6278
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

_source line 93 · 2026-05-19T13:41:43.045Z_

<details><summary>↩ Tool result · `toolu_01WLNh2mN3T9fTrEjmAoGtke`</summary>

```text
docs/paper/sections/introduction.tex:15:Three factors qualitatively shape this gap: (a)~\textit{instance degeneracy} (13\textendash 87\% across our benchmarks) compresses the candidate space; (b)~\textit{oracle headroom} bounds the achievable gain; (c)~\textit{LP-quality alignment} (within-instance $\rho(\text{LP}, \text{F1})$) determines whether LP can discriminate candidates in non-degenerate instances (\S\ref{sec:selection_gap}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "4da8522b-f390-412c-86c5-08bd54faa888",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/introduction.tex:15:Three factors qualitatively shape this gap: (a)~\\textit{instance degeneracy} (13\\textendash 87\\% across our benchmarks) compresses the candidate space; (b)~\\textit{oracle headroom} bounds the achievable gain; (c)~\\textit{LP-quality alignment} (within-instance $\\rho(\\text{LP}, \\text{F1})$) determines whether LP can discriminate candidates in non-degenerate instances (\\S\\ref{sec:selection_gap}).",
    "numLines": 1
  }
}
```

</details>

---


### Assistant

_source line 94_

<details><summary>Logged reasoning block</summary>

```text
Now I see:

1. **WNUT VC ρ inconsistency**: 
   - Section 4.2 (line 48): "VC ρ=0.724"
   - Section 4.3 (line 104): "VC ρ=0.730"
   - Appendix: "VC's high full-set ρ=0.724"
   
   So it appears 0.724 is the correct value (used twice vs 0.730 once). The 0.730 on line 104 is likely a typo. ❌
   
2. **"13-87%" degeneracy range**: This appears only in the introduction at line 15, but I can't find where the 87% figure is actually documented in any table or figure. I need to track down the source of that number.

3. **Performance improvement claims**: I'm looking for specific mentions of "+0.1pp over single-sample" or "+0.4pp over greedy" in the Discussion or Limitations sections, but I'm only finding "+2.9pp for non-tied subset" in the Discussion and "+0.2pp for LP×VC" in the Limitations. The 72B numbers showing -0.1pp on SciERC and -0.4pp on CoNLL appear elsewhere in the document.

The framing document might be referencing these 72B results differently—the "+0.1pp" could correspond to the SciERC LP selection result and "+0.4pp" to the CoNLL result, but they're actually negative improvements across different datasets, so there's no real contradiction there. Let me search the Discussion section more carefully to see if these exact phrasings appear somewhere I missed.

Looking at the Discussion text, I'm seeing analysis of how single-metric evaluation creates selection risks and how multiple factors constrain what gains are actually achievable—instance degeneracy compresses the candidate space significantly, oracle headroom limits potential improvements, and LP compression prevents fully exploiting remaining signal. Within non-degenerate instances, there's a positive correlation between MBR utility and F1. When compression is mitigated with a higher LP range threshold, LP selection shows a substantial +2.9pp improvement, though that threshold was determined post-hoc. Temperature appears to help separate degeneracy effects from alignment issues, reducing degeneracy to 14.9% at T=1.2, though the thought cuts off there.

Now I'm searching through the paper to verify some specific numbers and claims—checking the Discussion section for "+0.1pp" and the Limitations for those other metrics, trying to track down whether there's a contradiction or if it's already been resolved in the current version.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "fe8050d3-94b4-44f6-8b41-d07675c9e32c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HobSazo5V7vzsceuibXQzq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18679,
      "cache_read_input_tokens": 88269,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 18679
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

_source line 95_

<details open><summary>🔧 Tool call — Grep · `toolu_01HnqhbFLXDX1nJaJshQKUaF`</summary>

```json
{
  "pattern": "single.sample|\\+0\\.1[^0-9]",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "57cb33dc-a633-429a-9d18-984d5c243c46",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HobSazo5V7vzsceuibXQzq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18679,
      "cache_read_input_tokens": 88269,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 18679
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

_source line 96 · 2026-05-19T13:42:12.596Z_

<details><summary>↩ Tool result · `toolu_01HnqhbFLXDX1nJaJshQKUaF`</summary>

```text
docs/paper/main.log:914:\T1/ptm/m/n/10.95 (+20) single-sample ($\OT1/cmr/m/n/10.95 +2\OML/cmm/m/it/10.9
docs/paper/sections/experiments.tex:47:On CoNLL (single-sample F1${\approx}$0.91), EM leads both $\rho$ and AUROC ($0.816$).
docs/paper/sections/experiments.tex:246:[Omitted long matching line]
docs/paper/sections/appendix.tex:230:On LLaMA SciERC, where output diversity remains substantial (18\% identical outputs, 39\% unique), LP achieves the highest selection F1 (0.652) at $N{=}8$ but still falls within bootstrap noise of single-sample (0.646), replicating the gap observed on Qwen SciERC (Table~\ref{tab:selection}).
docs/paper/sections/appendix.tex:232:On CoNLL, 48--87\% of instances produce identical outputs across all $N$ samples; this reflects a ceiling effect (single-sample F1 ${\approx}$0.91--0.92) rather than signal failure, and selection analysis on these configurations is uninformative because there is little per-sample variance for any signal to exploit.
docs/paper/sections/appendix.tex:264:VC achieves the largest gain over single-sample ($+0.28$~pp, $p{=}0.003$--$0.027$ across 3 seeds, all significant), with SJ, FK, and EM at $+0.22$--$0.23$~pp and LP at $+0.12$~pp (2/3 seeds significant).
docs/paper/sections/appendix.tex:320:On CoNLL, diversity collapses: 59\% (Qwen) to 89\% (LLaMA) of instances produce identical outputs across all $N$ samples; this reflects a ceiling effect where single-sample F1 already exceeds 0.90.
docs/paper/sections/appendix.tex:342:[Omitted long matching line]
docs/paper/sections/appendix.tex:346:On the 44\% of Qwen SciERC instances with high diversity (${\geq}4$ unique outputs among 8 samples, $n{=}232$), oracle headroom reaches $+$16.3~pp, yet all consistency-based signals (SJ, FK, EM, VC) select at or below single-sample, and LP, the only per-sample signal, achieves merely $+$0.8~pp.
docs/paper/sections/appendix.tex:347:LLaMA replicates this pattern: on its high-diversity subset ($n{=}186$), oracle headroom reaches $+$20.1~pp while consistency signals remain at or below single-sample and LP captures only $+$2.0~pp.
docs/paper/sections/appendix.tex:372:Table~\ref{tab:tost} supplements this with two one-sided tests (TOST), testing whether each signal's selection F1 is equivalent to single-sample within a bound $\delta$.
docs/paper/sections/appendix.tex:377:On NER ($n{=}529$), at $\delta{=}{\pm}2$~pp, SJ and LP are confirmed equivalent to single-sample (TOST $p{<}0.05$); at $\delta{=}{\pm}3$~pp, four of five signals pass; at $\delta{=}{\pm}5$~pp, all five pass.
docs/paper/sections/appendix.tex:384:\caption{TOST equivalence testing: signals vs.\ single-sample on SciERC ($N{=}8$, $T{=}1.0$). \checkmark: equivalent at $p{<}0.05$; \texttimes: not equivalent. $\Delta$: mean F1 difference (signal $-$ single-sample).}
docs/paper/sections/appendix.tex:393:SJ & +0.1 & \checkmark & \checkmark & \checkmark & $-$1.8 & \texttimes & \texttimes & \checkmark \\
docs/paper/sections/appendix.tex:404:(1) $\delta_{\mathrm{SEM}}$: the bootstrapped standard error of single-sample F1 (0.43--1.33~pp depending on configuration), which represents measurement noise;
docs/paper/sections/appendix.tex:410:On Qwen CoNLL ($n{=}2{,}756$), no signal passes at any external $\delta$: selection F1 degrades by 0.9--1.5~pp relative to single-sample, which exceeds even $\delta_{\mathrm{literature}}$.
docs/paper/sections/appendix.tex:412:These external anchors confirm that the equivalence conclusion is configuration-dependent: LLaMA CoNLL selection is robustly equivalent to single-sample under any reasonable margin, while SciERC and Qwen CoNLL selection shows detectable degradation at externally calibrated thresholds.
docs/paper/sections/appendix.tex:608:Among instances with LP range ${\geq}0.05$ ($n{=}210$, 40\% of total), log-probability selection \textit{significantly} outperforms single-sample ($+2.9$~pp F1, $p{=}0.004$), and within-instance $\rho(\text{LP}, \text{F1})$ rises from 0.08 (tied subset) to 0.39 (non-tied subset).
docs/paper/sections/appendix.tex:620:\caption{$\varepsilon$ sensitivity sweep for LP selection on SciERC NER ($N{=}8$, seed${=}42$, $n{=}529$). ``Tied\%'' = fraction with within-instance LP range ${<}\varepsilon$. $\Delta$: selection F1 gain over single-sample on the non-tied subset. The tied fraction increases smoothly; $\varepsilon{=}0.05$ yields the strongest statistical separation.}
docs/paper/sections/appendix.tex:710:Table~\ref{tab:vc_quartile} stratifies SciERC instances by voting confidence (VC) quartiles and reports selection $\Delta$ (gain over single-sample) for LP and SJ.
docs/paper/sections/appendix.tex:715:\caption{Selection $\Delta$ (pp over single-sample) stratified by VC quartile on SciERC ($N{=}8$, Qwen3-8B). Oracle headroom collapses at Q4; LP rankings are unreliable at Q1--Q2. Neither quartile supports consistent selection gains.}
docs/paper/sections/appendix.tex:756:Table~\ref{tab:re_cond_selection} presents RE selection at $N{=}8$: no signal outperforms single-sample (0.404) on the full set ($n{=}397$) or the non-zero subset ($n{=}238$), with 18.1~pp of unrealized oracle headroom.
docs/paper/sections/appendix.tex:761:Selection remains below single-sample on RE ($\Delta$ up to $-3.4$~pp) despite 17.1~pp of oracle headroom.
docs/paper/sections/appendix.tex:770:All five signals underperform single-sample on both subsets.
docs/paper/sections/appendix.tex:771:On the non-zero subset, selection performance is \textit{worse} than on the full set (e.g., VC: $-10.0$~pp on non-zero vs.\ $-4.5$~pp on full set), because single-sample is already strong on non-zero instances (F1${=}0.674$) and signals actively select inferior samples.
docs/paper/sections/appendix.tex:798:All four consistency signals underperform single-sample, with EM showing the largest deficit ($\Delta{=}{-}1.5$~pp, Fisher $p{>}0.99$).
docs/paper/sections/appendix.tex:799:LP is the only positive signal ($\Delta{=}{+}0.7$~pp, Fisher $p{=}0.058$), driven primarily by seed~456 ($\Delta{=}{+}1.5$~pp, $p{=}0.026$); the remaining seeds show smaller effects ($+0.1$ and $+0.6$~pp, $p{>}0.20$).
docs/paper/sections/appendix.tex:930:Free-form decoding reduces the tied fraction modestly, yet selection remains below single-sample: LP-selected F1${=}0.896$ vs.\ single-sample $0.904$ ($\Delta{=}{-}0.77$~pp).
docs/paper/sections/appendix.tex:939:LP selection failures (instances where LP-selected F1 $<$ single-sample F1) show moderate cross-seed stability: the average pairwise Jaccard similarity is 0.42 (range: 0.38--0.46); failures are partially systematic (driven by instance complexity) but not fully deterministic.
docs/paper/sections/appendix.tex:944:Stable failures (all 3 seeds) involve more gold relations (2.12 vs.\ 1.62 for never-fail instances) and higher single-sample F1 (0.688 vs.\ 0.429); LP mis-selects on instances where the model already performs well, precisely the instances where selection would be most valuable.
docs/paper/sections/appendix.tex:950:\caption{RE LP selection failure stability across 3 seeds (SciERC, $N{=}8$). Stable failures concentrate on relation-dense instances with high single-sample F1.}
docs/paper/sections/appendix.tex:1167:The wider training schema subsumes CoNLL's narrower schema, so the model produces reasonable outputs even out-of-domain (single-sample F1${=}0.522$), and structural signals benefit from the simpler target schema's reduced output ambiguity.
docs/paper/sections/appendix.tex:1171:The CoNLL-trained model recognizes only 4 news entity types (PER, ORG, LOC, MISC) and has no relation extraction capability; when applied to SciERC's 6 scientific entity types and 7 relation types, the model cannot produce meaningful structured outputs (single-sample NER F1${=}0.009$, RE F1${=}0.001$).
docs/paper/sections/appendix.tex:1207:VerbConf exhibits extreme score compression: mean confidence is 8.58/10 on SciERC (single-sample F1${=}0.645$) and 9.24/10 on CoNLL (single-sample F1${=}0.904$), with most scores concentrated in the 8--10 range.
docs/paper/main.aux:1912:\@writefile{lot}{\contentsline {table}{\numberline {16}{\ignorespaces TOST equivalence testing: signals vs.\ single-sample on SciERC ($N{=}8$, $T{=}1.0$). \text  {$\mathsurround \z@ \mathchar "558$}: equivalent at $p{<}0.05$; \texttimes : not equivalent. $\Delta $: mean F1 difference (signal $-$ single-sample).}}{21}{table.caption.77}\protected@file@percent }
docs/paper/main.aux:1913:\newlabel{tab:tost}{{16}{21}{TOST equivalence testing: signals vs.\ single-sample on SciERC ($N{=}8$, $T{=}1.0$). \checkmark : equivalent at $p{<}0.05$; \texttimes : not equivalent. $\Delta $: mean F1 difference (signal $-$ single-sample)}{table.caption.77}{}}
docs/paper/main.aux:2216:\@writefile{lot}{\contentsline {table}{\numberline {21}{\ignorespaces $\varepsilon $ sensitivity sweep for LP selection on SciERC NER ($N{=}8$, seed${=}42$, $n{=}529$). ``Tied\%'' = fraction with within-instance LP range ${<}\varepsilon $. $\Delta $: selection F1 gain over single-sample on the non-tied subset. The tied fraction increases smoothly; $\varepsilon {=}0.05$ yields the strongest statistical separation.}}{24}{table.caption.95}\protected@file@percent }
docs/paper/main.aux:2217:\newlabel{tab:epsilon_sweep}{{21}{24}{$\varepsilon $ sensitivity sweep for LP selection on SciERC NER ($N{=}8$, seed${=}42$, $n{=}529$). ``Tied\%'' = fraction with within-instance LP range ${<}\varepsilon $. $\Delta $: selection F1 gain over single-sample on the non-tied subset. The tied fraction increases smoothly; $\varepsilon {=}0.05$ yields the strongest statistical separation}{table.caption.95}{}}
docs/paper/main.aux:2287:\@writefile{lot}{\contentsline {table}{\numberline {25}{\ignorespaces Selection $\Delta $ (pp over single-sample) stratified by VC quartile on SciERC ($N{=}8$, Qwen3-8B). Oracle headroom collapses at Q4; LP rankings are unreliable at Q1--Q2. Neither quartile supports consistent selection gains.}}{25}{table.caption.102}\protected@file@percent }
docs/paper/main.aux:2288:\newlabel{tab:vc_quartile}{{25}{25}{Selection $\Delta $ (pp over single-sample) stratified by VC quartile on SciERC ($N{=}8$, Qwen3-8B). Oracle headroom collapses at Q4; LP rankings are unreliable at Q1--Q2. Neither quartile supports consistent selection gains}{table.caption.102}{}}
docs/paper/main.aux:2527:\@writefile{lot}{\contentsline {table}{\numberline {29}{\ignorespaces RE LP selection failure stability across 3 seeds (SciERC, $N{=}8$). Stable failures concentrate on relation-dense instances with high single-sample F1.}}{28}{table.caption.115}\protected@file@percent }
docs/paper/main.aux:2528:\newlabel{tab:stable_failures}{{29}{28}{RE LP selection failure stability across 3 seeds (SciERC, $N{=}8$). Stable failures concentrate on relation-dense instances with high single-sample F1}{table.caption.115}{}}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "5371dc0f-3ff3-4a1b-96ff-d69ed17a9784",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/main.log:914:\\T1/ptm/m/n/10.95 (+20) single-sample ($\\OT1/cmr/m/n/10.95 +2\\OML/cmm/m/it/10.9\ndocs/paper/sections/experiments.tex:47:On CoNLL (single-sample F1${\\approx}$0.91), EM leads both $\\rho$ and AUROC ($0.816$).\ndocs/paper/sections/experiments.tex:246:[Omitted long matching line]\ndocs/paper/sections/appendix.tex:230:On LLaMA SciERC, where output diversity remains substantial (18\\% identical outputs, 39\\% unique), LP achieves the highest selection F1 (0.652) at $N{=}8$ but still falls within bootstrap noise of single-sample (0.646), replicating the gap observed on Qwen SciERC (Table~\\ref{tab:selection}).\ndocs/paper/sections/appendix.tex:232:On CoNLL, 48--87\\% of instances produce identical outputs across all $N$ samples; this reflects a ceiling effect (single-sample F1 ${\\approx}$0.91--0.92) rather than signal failure, and selection analysis on these configurations is uninformative because there is little per-sample variance for any signal to exploit.\ndocs/paper/sections/appendix.tex:264:VC achieves the largest gain over single-sample ($+0.28$~pp, $p{=}0.003$--$0.027$ across 3 seeds, all significant), with SJ, FK, and EM at $+0.22$--$0.23$~pp and LP at $+0.12$~pp (2/3 seeds significant).\ndocs/paper/sections/appendix.tex:320:On CoNLL, diversity collapses: 59\\% (Qwen) to 89\\% (LLaMA) of instances produce identical outputs across all $N$ samples; this reflects a ceiling effect where single-sample F1 already exceeds 0.90.\ndocs/paper/sections/appendix.tex:342:[Omitted long matching line]\ndocs/paper/sections/appendix.tex:346:On the 44\\% of Qwen SciERC instances with high diversity (${\\geq}4$ unique outputs among 8 samples, $n{=}232$), oracle headroom reaches $+$16.3~pp, yet all consistency-based signals (SJ, FK, EM, VC) select at or below single-sample, and LP, the only per-sample signal, achieves merely $+$0.8~pp.\ndocs/paper/sections/appendix.tex:347:LLaMA replicates this pattern: on its high-diversity subset ($n{=}186$), oracle headroom reaches $+$20.1~pp while consistency signals remain at or below single-sample and LP captures only $+$2.0~pp.\ndocs/paper/sections/appendix.tex:372:Table~\\ref{tab:tost} supplements this with two one-sided tests (TOST), testing whether each signal's selection F1 is equivalent to single-sample within a bound $\\delta$.\ndocs/paper/sections/appendix.tex:377:On NER ($n{=}529$), at $\\delta{=}{\\pm}2$~pp, SJ and LP are confirmed equivalent to single-sample (TOST $p{<}0.05$); at $\\delta{=}{\\pm}3$~pp, four of five signals pass; at $\\delta{=}{\\pm}5$~pp, all five pass.\ndocs/paper/sections/appendix.tex:384:\\caption{TOST equivalence testing: signals vs.\\ single-sample on SciERC ($N{=}8$, $T{=}1.0$). \\checkmark: equivalent at $p{<}0.05$; \\texttimes: not equivalent. $\\Delta$: mean F1 difference (signal $-$ single-sample).}\ndocs/paper/sections/appendix.tex:393:SJ & +0.1 & \\checkmark & \\checkmark & \\checkmark & $-$1.8 & \\texttimes & \\texttimes & \\checkmark \\\\\ndocs/paper/sections/appendix.tex:404:(1) $\\delta_{\\mathrm{SEM}}$: the bootstrapped standard error of single-sample F1 (0.43--1.33~pp depending on configuration), which represents measurement noise;\ndocs/paper/sections/appendix.tex:410:On Qwen CoNLL ($n{=}2{,}756$), no signal passes at any external $\\delta$: selection F1 degrades by 0.9--1.5~pp relative to single-sample, which exceeds even $\\delta_{\\mathrm{literature}}$.\ndocs/paper/sections/appendix.tex:412:These external anchors confirm that the equivalence conclusion is configuration-dependent: LLaMA CoNLL selection is robustly equivalent to single-sample under any reasonable margin, while SciERC and Qwen CoNLL selection shows detectable degradation at externally calibrated thresholds.\ndocs/paper/sections/appendix.tex:608:Among instances with LP range ${\\geq}0.05$ ($n{=}210$, 40\\% of total), log-probability selection \\textit{significantly} outperforms single-sample ($+2.9$~pp F1, $p{=}0.004$), and within-instance $\\rho(\\text{LP}, \\text{F1})$ rises from 0.08 (tied subset) to 0.39 (non-tied subset).\ndocs/paper/sections/appendix.tex:620:\\caption{$\\varepsilon$ sensitivity sweep for LP selection on SciERC NER ($N{=}8$, seed${=}42$, $n{=}529$). ``Tied\\%'' = fraction with within-instance LP range ${<}\\varepsilon$. $\\Delta$: selection F1 gain over single-sample on the non-tied subset. The tied fraction increases smoothly; $\\varepsilon{=}0.05$ yields the strongest statistical separation.}\ndocs/paper/sections/appendix.tex:710:Table~\\ref{tab:vc_quartile} stratifies SciERC instances by voting confidence (VC) quartiles and reports selection $\\Delta$ (gain over single-sample) for LP and SJ.\ndocs/paper/sections/appendix.tex:715:\\caption{Selection $\\Delta$ (pp over single-sample) stratified by VC quartile on SciERC ($N{=}8$, Qwen3-8B). Oracle headroom collapses at Q4; LP rankings are unreliable at Q1--Q2. Neither quartile supports consistent selection gains.}\ndocs/paper/sections/appendix.tex:756:Table~\\ref{tab:re_cond_selection} presents RE selection at $N{=}8$: no signal outperforms single-sample (0.404) on the full set ($n{=}397$) or the non-zero subset ($n{=}238$), with 18.1~pp of unrealized oracle headroom.\ndocs/paper/sections/appendix.tex:761:Selection remains below single-sample on RE ($\\Delta$ up to $-3.4$~pp) despite 17.1~pp of oracle headroom.\ndocs/paper/sections/appendix.tex:770:All five signals underperform single-sample on both subsets.\ndocs/paper/sections/appendix.tex:771:On the non-zero subset, selection performance is \\textit{worse} than on the full set (e.g., VC: $-10.0$~pp on non-zero vs.\\ $-4.5$~pp on full set), because single-sample is already strong on non-zero instances (F1${=}0.674$) and signals actively select inferior samples.\ndocs/paper/sections/appendix.tex:798:All four consistency signals underperform single-sample, with EM showing the largest deficit ($\\Delta{=}{-}1.5$~pp, Fisher $p{>}0.99$).\ndocs/paper/sections/appendix.tex:799:LP is the only positive signal ($\\Delta{=}{+}0.7$~pp, Fisher $p{=}0.058$), driven primarily by seed~456 ($\\Delta{=}{+}1.5$~pp, $p{=}0.026$); the remaining seeds show smaller effects ($+0.1$ and $+0.6$~pp, $p{>}0.20$).\ndocs/paper/sections/appendix.tex:930:Free-form decoding reduces the tied fraction modestly, yet selection remains below single-sample: LP-selected F1${=}0.896$ vs.\\ single-sample $0.904$ ($\\Delta{=}{-}0.77$~pp).\ndocs/paper/sections/appendix.tex:939:LP selection failures (instances where LP-selected F1 $<$ single-sample F1) show moderate cross-seed stability: the average pairwise Jaccard similarity is 0.42 (range: 0.38--0.46); failures are partially systematic (driven by instance complexity) but not fully deterministic.\ndocs/paper/sections/appendix.tex:944:Stable failures (all 3 seeds) involve more gold relations (2.12 vs.\\ 1.62 for never-fail instances) and higher single-sample F1 (0.688 vs.\\ 0.429); LP mis-selects on instances where the model already performs well, precisely the instances where selection would be most valuable.\ndocs/paper/sections/appendix.tex:950:\\caption{RE LP selection failure stability across 3 seeds (SciERC, $N{=}8$). Stable failures concentrate on relation-dense instances with high single-sample F1.}\ndocs/paper/sections/appendix.tex:1167:The wider training schema subsumes CoNLL's narrower schema, so the model produces reasonable outputs even out-of-domain (single-sample F1${=}0.522$), and structural signals benefit from the simpler target schema's reduced output ambiguity.\ndocs/paper/sections/appendix.tex:1171:The CoNLL-trained model recognizes only 4 news entity types (PER, ORG, LOC, MISC) and has no relation extraction capability; when applied to SciERC's 6 scientific entity types and 7 relation types, the model cannot produce meaningful structured outputs (single-sample NER F1${=}0.009$, RE F1${=}0.001$).\ndocs/paper/sections/appendix.tex:1207:VerbConf exhibits extreme score compression: mean confidence is 8.58/10 on SciERC (single-sample F1${=}0.645$) and 9.24/10 on CoNLL (single-sample F1${=}0.904$), with most scores concentrated in the 8--10 range.\ndocs/paper/main.aux:1912:\\@writefile{lot}{\\contentsline {table}{\\numberline {16}{\\ignorespaces TOST equivalence testing: signals vs.\\ single-sample on SciERC ($N{=}8$, $T{=}1.0$). \\text  {$\\mathsurround \\z@ \\mathchar \"558$}: equivalent at $p{<}0.05$; \\texttimes : not equivalent. $\\Delta $: mean F1 difference (signal $-$ single-sample).}}{21}{table.caption.77}\\protected@file@percent }\ndocs/paper/main.aux:1913:\\newlabel{tab:tost}{{16}{21}{TOST equivalence testing: signals vs.\\ single-sample on SciERC ($N{=}8$, $T{=}1.0$). \\checkmark : equivalent at $p{<}0.05$; \\texttimes : not equivalent. $\\Delta $: mean F1 difference (signal $-$ single-sample)}{table.caption.77}{}}\ndocs/paper/main.aux:2216:\\@writefile{lot}{\\contentsline {table}{\\numberline {21}{\\ignorespaces $\\varepsilon $ sensitivity sweep for LP selection on SciERC NER ($N{=}8$, seed${=}42$, $n{=}529$). ``Tied\\%'' = fraction with within-instance LP range ${<}\\varepsilon $. $\\Delta $: selection F1 gain over single-sample on the non-tied subset. The tied fraction increases smoothly; $\\varepsilon {=}0.05$ yields the strongest statistical separation.}}{24}{table.caption.95}\\protected@file@percent }\ndocs/paper/main.aux:2217:\\newlabel{tab:epsilon_sweep}{{21}{24}{$\\varepsilon $ sensitivity sweep for LP selection on SciERC NER ($N{=}8$, seed${=}42$, $n{=}529$). ``Tied\\%'' = fraction with within-instance LP range ${<}\\varepsilon $. $\\Delta $: selection F1 gain over single-sample on the non-tied subset. The tied fraction increases smoothly; $\\varepsilon {=}0.05$ yields the strongest statistical separation}{table.caption.95}{}}\ndocs/paper/main.aux:2287:\\@writefile{lot}{\\contentsline {table}{\\numberline {25}{\\ignorespaces Selection $\\Delta $ (pp over single-sample) stratified by VC quartile on SciERC ($N{=}8$, Qwen3-8B). Oracle headroom collapses at Q4; LP rankings are unreliable at Q1--Q2. Neither quartile supports consistent selection gains.}}{25}{table.caption.102}\\protected@file@percent }\ndocs/paper/main.aux:2288:\\newlabel{tab:vc_quartile}{{25}{25}{Selection $\\Delta $ (pp over single-sample) stratified by VC quartile on SciERC ($N{=}8$, Qwen3-8B). Oracle headroom collapses at Q4; LP rankings are unreliable at Q1--Q2. Neither quartile supports consistent selection gains}{table.caption.102}{}}\ndocs/paper/main.aux:2527:\\@writefile{lot}{\\contentsline {table}{\\numberline {29}{\\ignorespaces RE LP selection failure stability across 3 seeds (SciERC, $N{=}8$). Stable failures concentrate on relation-dense instances with high single-sample F1.}}{28}{table.caption.115}\\protected@file@percent }\ndocs/paper/main.aux:2528:\\newlabel{tab:stable_failures}{{29}{28}{RE LP selection failure stability across 3 seeds (SciERC, $N{=}8$). Stable failures concentrate on relation-dense instances with high single-sample F1}{table.caption.115}{}}",
    "numLines": 42
  }
}
```

</details>

---


### Tool call

_source line 97_

<details open><summary>🔧 Tool call — Grep · `toolu_015948hcXPvBKVAn3ZsvMrA8`</summary>

```json
{
  "pattern": "over greedy|\\+0\\.4[^0-9]",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper",
  "output_mode": "content"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "62dea9f5-444a-4dbd-b997-0216eb03cd31",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01HobSazo5V7vzsceuibXQzq",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 18679,
      "cache_read_input_tokens": 88269,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 18679
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

_source line 98 · 2026-05-19T13:42:12.988Z_

<details><summary>↩ Tool result · `toolu_015948hcXPvBKVAn3ZsvMrA8`</summary>

```text
docs/paper/sections/experiments.tex:93:Instance-level signals assign identical QE scores to all candidates; MBR conversion does not improve over greedy on the primary test bed (Table~\ref{tab:selection}; Figure~\ref{fig:selection_gap}).
docs/paper/sections/experiments.tex:102:[Omitted long matching line]
docs/paper/sections/experiments.tex:246:[Omitted long matching line]
docs/paper/sections/limitations.tex:3:Entity-level construction assumes the model produces useful partial outputs across samples; when model capability is insufficient (WNUT-17, 51\% F1${=}0$), this precondition fails and construction cannot improve over greedy.
docs/paper/sections/limitations.tex:12:Ad-hoc LP${\times}$VC combinations yield at most $+0.2$~pp over greedy (not significant; \S\ref{sec:discussion}); whether \textit{learned} combinations could close the gap remains open.
docs/paper/main.aux:2971:[Omitted long matching line]
docs/paper/main.aux:2972:[Omitted long matching line]
docs/paper/sections/appendix.tex:1065:No signal achieves significant improvement over greedy at $\alpha{=}0.05$ (LP: $p{=}0.091$; FK: $p{=}0.101$), while VC is significantly \textit{worse} ($-4.36$~pp, $p{=}1.0$).
docs/paper/sections/appendix.tex:1418:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "23442d80-d2f4-4547-b2ce-3a4ca61779e9",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/sections/experiments.tex:93:Instance-level signals assign identical QE scores to all candidates; MBR conversion does not improve over greedy on the primary test bed (Table~\\ref{tab:selection}; Figure~\\ref{fig:selection_gap}).\ndocs/paper/sections/experiments.tex:102:[Omitted long matching line]\ndocs/paper/sections/experiments.tex:246:[Omitted long matching line]\ndocs/paper/sections/limitations.tex:3:Entity-level construction assumes the model produces useful partial outputs across samples; when model capability is insufficient (WNUT-17, 51\\% F1${=}0$), this precondition fails and construction cannot improve over greedy.\ndocs/paper/sections/limitations.tex:12:Ad-hoc LP${\\times}$VC combinations yield at most $+0.2$~pp over greedy (not significant; \\S\\ref{sec:discussion}); whether \\textit{learned} combinations could close the gap remains open.\ndocs/paper/main.aux:2971:[Omitted long matching line]\ndocs/paper/main.aux:2972:[Omitted long matching line]\ndocs/paper/sections/appendix.tex:1065:No signal achieves significant improvement over greedy at $\\alpha{=}0.05$ (LP: $p{=}0.091$; FK: $p{=}0.101$), while VC is significantly \\textit{worse} ($-4.36$~pp, $p{=}1.0$).\ndocs/paper/sections/appendix.tex:1418:[Omitted long matching line]",
    "numLines": 9
  }
}
```

</details>

---


### Assistant

_source line 99_

<details><summary>Logged reasoning block</summary>

```text
I found the key information. Let me now trace the "87%" degeneracy claim. Looking at the appendix line 232:
"On CoNLL, 48--87\% of instances produce identical outputs across all N samples"

This is the source of the 87% figure! It refers to CoNLL, where different model/seed configurations produce 48-87% degeneracy. Specifically:
- Qwen CoNLL: 48% (N=8)
- LLaMA CoNLL: up to 87%

Looking at the registry: exp_017_llama_conll_n16_r1024 has degen_rate=0.8647 (86.5%). 

The 87% comes from specific LLaMA+CoNLL configurations at N=16, not from comparing across different benchmarks. The intro's claim of "13-87% across our benchmarks" is misleading—the actual range across datasets at N=8 is roughly 10-68%, while pushing to N=16 with specific model/seed combinations reaches that 87% ceiling.

Now checking the TOST table for the "+0.1pp" claim. The appendix shows SJ NER improved by +0.1pp, though this is a marginal gain that doesn't pass significance thresholds. Meanwhile, on Qwen CoNLL with n=2,756, the selection actually degrades by 0.9–1.5pp compared to single-sample baseline, which contradicts any claim of consistent improvements.

Looking back at the experiments section, I see LP selection actually fails on both datasets with negative deltas (SciERC −0.1pp, CoNLL −0.4pp), not positive ones. These are in the Scaling section, not Discussion or Limitations. The "known contradiction" mentioned in the task—comparing "+0.1pp over single-sample" against "+0.4pp over greedy"—doesn't appear to exist in the current paper version. The Discussion mentions "+2.9pp" for non-tied LP and "14.9%" for T=1.2 degeneracy, but no "+0.1pp" reference, and the Limitations section cuts off mid-sentence.

The contradiction might have been resolved in a recent revision, or it could refer to different numbers than what I'm finding. I'll proceed with the audit report based on what's actually in the paper, then check the WNUT table in the appendix to verify those specific numbers.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "f3a0803b-f4c2-425f-bf2e-daf5156fa37c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01G7h3w4Auu7R9cNDohCcHoH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5190,
      "cache_read_input_tokens": 106948,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5190
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

_source line 100_

Let me check the WNUT table and the degeneracy table in the appendix.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "f714b023-a843-4914-944b-128054465c1b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01G7h3w4Auu7R9cNDohCcHoH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5190,
      "cache_read_input_tokens": 106948,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5190
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

_source line 101_

<details open><summary>🔧 Tool call — Grep · `toolu_01C2EK8c8ivdeQG6ugy2g54A`</summary>

```json
{
  "pattern": "tab:wnut|WNUT.*table|wnut.*rho|0\\\\.724|0\\\\.452",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "e5f13b46-d27c-4413-8556-b0f05df46be9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01G7h3w4Auu7R9cNDohCcHoH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5190,
      "cache_read_input_tokens": 106948,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5190
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

_source line 102 · 2026-05-19T13:42:39.308Z_

<details><summary>↩ Tool result · `toolu_01C2EK8c8ivdeQG6ugy2g54A`</summary>

```text
206:Table~\ref{tab:wnut} reports all five signals on WNUT-17 with full-set and conditional $\rho$.
212:\label{tab:wnut}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "956eadec-b3bd-433a-a7e5-35dae1d5867f",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "206:Table~\\ref{tab:wnut} reports all five signals on WNUT-17 with full-set and conditional $\\rho$.\n212:\\label{tab:wnut}",
    "numLines": 2
  }
}
```

</details>

---


### Tool call

_source line 103_

<details open><summary>🔧 Tool call — Grep · `toolu_01XxqwG5Z9bP3twj2J6RskL6`</summary>

```json
{
  "pattern": "tab:degeneracy|degeneracy.*table|48.*87",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
  "output_mode": "content",
  "-n": true
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "bbfbbdb6-2016-4169-b0b1-90ee99a8e0ed",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01G7h3w4Auu7R9cNDohCcHoH",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 5190,
      "cache_read_input_tokens": 106948,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 5190
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

_source line 104 · 2026-05-19T13:42:40.277Z_

<details><summary>↩ Tool result · `toolu_01XxqwG5Z9bP3twj2J6RskL6`</summary>

```text
232:On CoNLL, 48--87\% of instances produce identical outputs across all $N$ samples; this reflects a ceiling effect (single-sample F1 ${\approx}$0.91--0.92) rather than signal failure, and selection analysis on these configurations is uninformative because there is little per-sample variance for any signal to exploit.
351:Table~\ref{tab:degeneracy} quantifies instance degeneracy across configurations. ``Constant F1'' denotes instances where all $N$ samples receive identical instance-level F1; ``Constant utility'' denotes instances where MBR (SJ) utility is identical across candidates, preventing ranking.
357:\label{tab:degeneracy}
1122:This confirms that temperature controls degeneracy but cannot improve LP-quality alignment, which is largely determined by task structure and remains relatively stable across generation configurations (\S\ref{app:epoch_confound}). LP-quality alignment, not degeneracy, is the primary predictor of LP selection direction (\S\ref{sec:discussion}).
1265:\multicolumn{3}{l}{Greedy: 0.748 \quad Oracle: 0.872} & \multicolumn{2}{l}{Headroom: 12.4\,pp} \\
1444:On SciERC, DALS yields $+0.71{\pm}0.48$~pp (3-seed mean; individual seeds: $+0.19$ to $+1.14$~pp); on Few-NERD, $+0.30$~pp ($p{<}0.001$; gain remains positive across $\tau \in [0.01, 0.15]$); on CoNLL, where pure LP selection degrades F1 ($-0.85$~pp), DALS shows comparable degradation (Qwen: $-0.87$~pp; LLaMA: neutral).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "467ab946-4e83-41f1-bdc2-47b39fa8cfef",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "232:On CoNLL, 48--87\\% of instances produce identical outputs across all $N$ samples; this reflects a ceiling effect (single-sample F1 ${\\approx}$0.91--0.92) rather than signal failure, and selection analysis on these configurations is uninformative because there is little per-sample variance for any signal to exploit.\n351:Table~\\ref{tab:degeneracy} quantifies instance degeneracy across configurations. ``Constant F1'' denotes instances where all $N$ samples receive identical instance-level F1; ``Constant utility'' denotes instances where MBR (SJ) utility is identical across candidates, preventing ranking.\n357:\\label{tab:degeneracy}\n1122:This confirms that temperature controls degeneracy but cannot improve LP-quality alignment, which is largely determined by task structure and remains relatively stable across generation configurations (\\S\\ref{app:epoch_confound}). LP-quality alignment, not degeneracy, is the primary predictor of LP selection direction (\\S\\ref{sec:discussion}).\n1265:\\multicolumn{3}{l}{Greedy: 0.748 \\quad Oracle: 0.872} & \\multicolumn{2}{l}{Headroom: 12.4\\,pp} \\\\\n1444:On SciERC, DALS yields $+0.71{\\pm}0.48$~pp (3-seed mean; individual seeds: $+0.19$ to $+1.14$~pp); on Few-NERD, $+0.30$~pp ($p{<}0.001$; gain remains positive across $\\tau \\in [0.01, 0.15]$); on CoNLL, where pure LP selection degrades F1 ($-0.85$~pp), DALS shows comparable degradation (Qwen: $-0.87$~pp; LLaMA: neutral).",
    "numLines": 6
  }
}
```

</details>

---


### Tool call

_source line 105_

<details open><summary>🔧 Tool call — Read · `toolu_01Jur9JVUZTjPZ3DAqg5zGT7`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
  "offset": 206,
  "limit": 40
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "221a2a85-6158-4210-a672-3dccbf100ca6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XfisQZnU9TEJ6NPpMuNZ9V",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1740,
      "cache_read_input_tokens": 112138,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1740
      },
      "output_tokens": 69,
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

_source line 106 · 2026-05-19T13:42:43.644Z_

<details><summary>↩ Tool result · `toolu_01Jur9JVUZTjPZ3DAqg5zGT7`</summary>

```text
206	Table~\ref{tab:wnut} reports all five signals on WNUT-17 with full-set and conditional $\rho$.
207	
208	\begin{table}[t]
209	\centering
210	\small
211	\caption{Quality estimation on WNUT-17 (Qwen, $N{=}16$, $T{=}1.0$, $n{=}689$). Cond: non-zero F1 instances ($n{=}334$). Full-set $\rho$ reflects binary success prediction; conditional $\rho$ measures quality gradation. LP's conditional $\rho$ is highest despite negative full-set $\rho$.}
212	\label{tab:wnut}
213	\begin{tabular}{lcccc}
214	\toprule
215	Signal & $\rho$ & AUROC & Cond.\ $\rho$ & Cond.\ $p$ \\
216	\midrule
217	VC      & .724 & .913 & .038 & .487 \\
218	FK      & .125 & .555 & .169 & .002 \\
219	SJ      & .089 & .517 & .288 & ${<}$1e-7 \\
220	EM      & .050 & .487 & .333 & ${<}$1e-9 \\
221	LP & $-$.410 & .219 & .350 & ${<}$1e-10 \\
222	\bottomrule
223	\end{tabular}
224	\end{table}
225	The full-set $p$-values are: VC ${<}$1e-112, FK $p{=}0.001$, SJ $p{=}0.020$, EM $p{=}0.194$, LP ${<}$1e-28.
226	VC's high full-set $\rho{=}0.724$ is entirely driven by the zero/non-zero boundary (conditional $\rho{=}0.038$, $p{=}0.49$), while LP's conditional $\rho{=}0.350$ is the highest among all signals on the non-zero subset, full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.
227	
228	\paragraph{Cross-configuration selection analysis.}
229	Table~\ref{tab:cross_selection} extends the selection analysis to five additional configurations.
230	On LLaMA SciERC, where output diversity remains substantial (18\% identical outputs, 39\% unique), LP achieves the highest selection F1 (0.652) at $N{=}8$ but still falls within bootstrap noise of single-sample (0.646), replicating the gap observed on Qwen SciERC (Table~\ref{tab:selection}).
231	On LLaMA FewNERD ($n{=}32{,}565$, 3-seed mean), LP is the only signal with positive selection ($+0.36$~pp), confirming LP as the most robust selection signal across model families (Qwen FewNERD: $+1.39$~pp, Table~\ref{tab:fewnerd}). All structural signals degrade selection (VC $-2.39$~pp, SJ $-0.52$~pp), consistent with the Qwen pattern. LLaMA FewNERD degeneracy ($23.4{\pm}4.7$\%, 3 seeds) is higher than Qwen ($12.7$\%), illustrating the capability-diversity tension: LLaMA achieves stronger greedy F1 ($0.784$ vs.\ $0.748$, $+3.6$~pp) but at the cost of higher degeneracy ($+10.7$~pp) and reduced oracle headroom ($10.0$ vs.\ $12.4$~pp).
232	On CoNLL, 48--87\% of instances produce identical outputs across all $N$ samples; this reflects a ceiling effect (single-sample F1 ${\approx}$0.91--0.92) rather than signal failure, and selection analysis on these configurations is uninformative because there is little per-sample variance for any signal to exploit.
233	
234	\begin{table*}[t]
235	\centering
236	\small
237	\caption{Best-of-$N$ selection F1 (macro, instance-averaged) across configurations ($T{=}1.0$, 3-seed mean). Best non-oracle signal per row in \textbf{bold}. LP is the only signal with positive selection on both FewNERD configurations (Qwen $+1.39$~pp, Table~\ref{tab:fewnerd}; LLaMA $+0.36$~pp). At $N{=}16$ on LLaMA CoNLL, VC achieves small but significant gains ($+0.28$~pp, $p{<}0.03$; see text below). CoNLL shows especially tight clustering where greedy already exceeds 0.90.}
238	\label{tab:cross_selection}
239	\begin{tabular}{llccccccc}
240	\toprule
241	Config & $n$ & Greedy & Oracle & SJ & FK & EM & LP & VC \\
242	\midrule
243	LLaMA/SciERC $N{=}8$ & 529 & .646 & .778 & .643 & .639 & .634 & \textbf{.652} & .633 \\
244	LLaMA/SciERC $N{=}16$ & 529 & .645 & .806 & \textbf{.649} & \textbf{.649} & .640 & .646 & .640 \\
245	\addlinespace
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "25169cba-e38e-4096-912f-f3302ff74709",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
      "content": "Table~\\ref{tab:wnut} reports all five signals on WNUT-17 with full-set and conditional $\\rho$.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Quality estimation on WNUT-17 (Qwen, $N{=}16$, $T{=}1.0$, $n{=}689$). Cond: non-zero F1 instances ($n{=}334$). Full-set $\\rho$ reflects binary success prediction; conditional $\\rho$ measures quality gradation. LP's conditional $\\rho$ is highest despite negative full-set $\\rho$.}\n\\label{tab:wnut}\n\\begin{tabular}{lcccc}\n\\toprule\nSignal & $\\rho$ & AUROC & Cond.\\ $\\rho$ & Cond.\\ $p$ \\\\\n\\midrule\nVC      & .724 & .913 & .038 & .487 \\\\\nFK      & .125 & .555 & .169 & .002 \\\\\nSJ      & .089 & .517 & .288 & ${<}$1e-7 \\\\\nEM      & .050 & .487 & .333 & ${<}$1e-9 \\\\\nLP & $-$.410 & .219 & .350 & ${<}$1e-10 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\nThe full-set $p$-values are: VC ${<}$1e-112, FK $p{=}0.001$, SJ $p{=}0.020$, EM $p{=}0.194$, LP ${<}$1e-28.\nVC's high full-set $\\rho{=}0.724$ is entirely driven by the zero/non-zero boundary (conditional $\\rho{=}0.038$, $p{=}0.49$), while LP's conditional $\\rho{=}0.350$ is the highest among all signals on the non-zero subset, full-set correlations on high-failure-rate datasets conflate binary success prediction with quality gradation.\n\n\\paragraph{Cross-configuration selection analysis.}\nTable~\\ref{tab:cross_selection} extends the selection analysis to five additional configurations.\nOn LLaMA SciERC, where output diversity remains substantial (18\\% identical outputs, 39\\% unique), LP achieves the highest selection F1 (0.652) at $N{=}8$ but still falls within bootstrap noise of single-sample (0.646), replicating the gap observed on Qwen SciERC (Table~\\ref{tab:selection}).\nOn LLaMA FewNERD ($n{=}32{,}565$, 3-seed mean), LP is the only signal with positive selection ($+0.36$~pp), confirming LP as the most robust selection signal across model families (Qwen FewNERD: $+1.39$~pp, Table~\\ref{tab:fewnerd}). All structural signals degrade selection (VC $-2.39$~pp, SJ $-0.52$~pp), consistent with the Qwen pattern. LLaMA FewNERD degeneracy ($23.4{\\pm}4.7$\\%, 3 seeds) is higher than Qwen ($12.7$\\%), illustrating the capability-diversity tension: LLaMA achieves stronger greedy F1 ($0.784$ vs.\\ $0.748$, $+3.6$~pp) but at the cost of higher degeneracy ($+10.7$~pp) and reduced oracle headroom ($10.0$ vs.\\ $12.4$~pp).\nOn CoNLL, 48--87\\% of instances produce identical outputs across all $N$ samples; this reflects a ceiling effect (single-sample F1 ${\\approx}$0.91--0.92) rather than signal failure, and selection analysis on these configurations is uninformative because there is little per-sample variance for any signal to exploit.\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\caption{Best-of-$N$ selection F1 (macro, instance-averaged) across configurations ($T{=}1.0$, 3-seed mean). Best non-oracle signal per row in \\textbf{bold}. LP is the only signal with positive selection on both FewNERD configurations (Qwen $+1.39$~pp, Table~\\ref{tab:fewnerd}; LLaMA $+0.36$~pp). At $N{=}16$ on LLaMA CoNLL, VC achieves small but significant gains ($+0.28$~pp, $p{<}0.03$; see text below). CoNLL shows especially tight clustering where greedy already exceeds 0.90.}\n\\label{tab:cross_selection}\n\\begin{tabular}{llccccccc}\n\\toprule\nConfig & $n$ & Greedy & Oracle & SJ & FK & EM & LP & VC \\\\\n\\midrule\nLLaMA/SciERC $N{=}8$ & 529 & .646 & .778 & .643 & .639 & .634 & \\textbf{.652} & .633 \\\\\nLLaMA/SciERC $N{=}16$ & 529 & .645 & .806 & \\textbf{.649} & \\textbf{.649} & .640 & .646 & .640 \\\\\n\\addlinespace",
      "numLines": 40,
      "startLine": 206,
      "totalLines": 1572
    }
  }
}
```

</details>

---


### Tool call

_source line 107_

<details open><summary>🔧 Tool call — Read · `toolu_01TY1DyaYbNpt67YH1vqnoPx`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
  "offset": 351,
  "limit": 40
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "fb8e7229-30ac-4899-bcac-34ee78834460",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XfisQZnU9TEJ6NPpMuNZ9V",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1740,
      "cache_read_input_tokens": 112138,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1740
      },
      "output_tokens": 69,
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

_source line 108 · 2026-05-19T13:42:44.526Z_

<details><summary>↩ Tool result · `toolu_01TY1DyaYbNpt67YH1vqnoPx`</summary>

```text
351	Table~\ref{tab:degeneracy} quantifies instance degeneracy across configurations. ``Constant F1'' denotes instances where all $N$ samples receive identical instance-level F1; ``Constant utility'' denotes instances where MBR (SJ) utility is identical across candidates, preventing ranking.
352	
353	\begin{table}[t]
354	\centering
355	\small
356	\caption{Instance degeneracy statistics ($T{=}1.0$). ``Constant F1'': all $N$ samples receive identical instance-level F1. ``Constant utility'': MBR (SJ) utility identical across candidates. 4B data confirms degeneracy scales with model capability.}
357	\label{tab:degeneracy}
358	\begin{tabular}{lccc}
359	\toprule
360	& \shortstack{SciERC 8B\\($N{=}8$)} & \shortstack{SciERC 4B\\($N{=}8$)} & \shortstack{CoNLL 8B\\($N{=}16$)} \\
361	\midrule
362	Constant F1 & 17.8\% & 10.4\% & 48.4\% \\
363	Constant utility & 13\% & 7.0\% & 49\% \\
364	Oracle gap closed (non-deg.) & 23\% & 25.2\% & 41\% \\
365	Within-inst.\ SJ $\rho$ (median) & 0.524 & 0.550 & 0.994 \\
366	\bottomrule
367	\end{tabular}
368	\end{table}
369	
370	\paragraph{TOST equivalence testing.}\label{app:tost}
371	The primary evidence against selection gains comes from effect sizes and confidence intervals: Cohen's $d{=}0.038$ for the best signal (NER LP) and bootstrap 95\% CI [$-$3.0, $+$4.2]~pp spanning zero.
372	Table~\ref{tab:tost} supplements this with two one-sided tests (TOST), testing whether each signal's selection F1 is equivalent to single-sample within a bound $\delta$.
373	The $\delta$ values are contextualized against oracle headroom (12--18~pp): $\delta{=}5$~pp corresponds to forgoing 28--38\% of the available headroom, $\delta{=}3$~pp forgoing 17--23\%, and $\delta{=}2$~pp less than 15\%.
374	These proportions use the same test data that defines the headroom, introducing circularity: $\delta$ is anchored to the very quantity it contextualizes.
375	We address this below with externally anchored equivalence margins.
376	The breakpoint $\delta^*$, the minimum equivalence margin at which each signal passes TOST, ranges from approximately 1.3~pp (SJ, ${\sim}$10\% of oracle headroom) to 3.4~pp (FK, ${\sim}$26\%) on NER, and from approximately 2.9~pp (LP, ${\sim}$16\%) to 6.5~pp (VC, ${\sim}$36\%) on RE.
377	On NER ($n{=}529$), at $\delta{=}{\pm}2$~pp, SJ and LP are confirmed equivalent to single-sample (TOST $p{<}0.05$); at $\delta{=}{\pm}3$~pp, four of five signals pass; at $\delta{=}{\pm}5$~pp, all five pass.
378	On RE ($n{=}397$, preliminary), EM and VC fail equivalence even at $\delta{=}{\pm}5$~pp due to systematic underperformance ($\Delta{=}{-}3.2$~pp and $-4.5$~pp respectively).
379	The effect sizes are negligible ($d{=}0.038$) and confidence intervals span zero, with TOST confirming equivalence at practically meaningful margins.
380	
381	\begin{table}[t]
382	\centering
383	\small
384	\caption{TOST equivalence testing: signals vs.\ single-sample on SciERC ($N{=}8$, $T{=}1.0$). \checkmark: equivalent at $p{<}0.05$; \texttimes: not equivalent. $\Delta$: mean F1 difference (signal $-$ single-sample).}
385	\label{tab:tost}
386	\begin{tabular}{l cccc cccc}
387	\toprule
388	& \multicolumn{4}{c}{\textbf{NER}} & \multicolumn{4}{c}{\textbf{RE}} \\
389	\cmidrule(lr){2-5} \cmidrule(lr){6-9}
390	Signal & $\Delta$ & $\pm$2 & $\pm$3 & $\pm$5 & $\Delta$ & $\pm$2 & $\pm$3 & $\pm$5 \\
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "38a8593e-7f68-4524-93ff-741e66dece53",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
      "content": "Table~\\ref{tab:degeneracy} quantifies instance degeneracy across configurations. ``Constant F1'' denotes instances where all $N$ samples receive identical instance-level F1; ``Constant utility'' denotes instances where MBR (SJ) utility is identical across candidates, preventing ranking.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{Instance degeneracy statistics ($T{=}1.0$). ``Constant F1'': all $N$ samples receive identical instance-level F1. ``Constant utility'': MBR (SJ) utility identical across candidates. 4B data confirms degeneracy scales with model capability.}\n\\label{tab:degeneracy}\n\\begin{tabular}{lccc}\n\\toprule\n& \\shortstack{SciERC 8B\\\\($N{=}8$)} & \\shortstack{SciERC 4B\\\\($N{=}8$)} & \\shortstack{CoNLL 8B\\\\($N{=}16$)} \\\\\n\\midrule\nConstant F1 & 17.8\\% & 10.4\\% & 48.4\\% \\\\\nConstant utility & 13\\% & 7.0\\% & 49\\% \\\\\nOracle gap closed (non-deg.) & 23\\% & 25.2\\% & 41\\% \\\\\nWithin-inst.\\ SJ $\\rho$ (median) & 0.524 & 0.550 & 0.994 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\n\\paragraph{TOST equivalence testing.}\\label{app:tost}\nThe primary evidence against selection gains comes from effect sizes and confidence intervals: Cohen's $d{=}0.038$ for the best signal (NER LP) and bootstrap 95\\% CI [$-$3.0, $+$4.2]~pp spanning zero.\nTable~\\ref{tab:tost} supplements this with two one-sided tests (TOST), testing whether each signal's selection F1 is equivalent to single-sample within a bound $\\delta$.\nThe $\\delta$ values are contextualized against oracle headroom (12--18~pp): $\\delta{=}5$~pp corresponds to forgoing 28--38\\% of the available headroom, $\\delta{=}3$~pp forgoing 17--23\\%, and $\\delta{=}2$~pp less than 15\\%.\nThese proportions use the same test data that defines the headroom, introducing circularity: $\\delta$ is anchored to the very quantity it contextualizes.\nWe address this below with externally anchored equivalence margins.\nThe breakpoint $\\delta^*$, the minimum equivalence margin at which each signal passes TOST, ranges from approximately 1.3~pp (SJ, ${\\sim}$10\\% of oracle headroom) to 3.4~pp (FK, ${\\sim}$26\\%) on NER, and from approximately 2.9~pp (LP, ${\\sim}$16\\%) to 6.5~pp (VC, ${\\sim}$36\\%) on RE.\nOn NER ($n{=}529$), at $\\delta{=}{\\pm}2$~pp, SJ and LP are confirmed equivalent to single-sample (TOST $p{<}0.05$); at $\\delta{=}{\\pm}3$~pp, four of five signals pass; at $\\delta{=}{\\pm}5$~pp, all five pass.\nOn RE ($n{=}397$, preliminary), EM and VC fail equivalence even at $\\delta{=}{\\pm}5$~pp due to systematic underperformance ($\\Delta{=}{-}3.2$~pp and $-4.5$~pp respectively).\nThe effect sizes are negligible ($d{=}0.038$) and confidence intervals span zero, with TOST confirming equivalence at practically meaningful margins.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{TOST equivalence testing: signals vs.\\ single-sample on SciERC ($N{=}8$, $T{=}1.0$). \\checkmark: equivalent at $p{<}0.05$; \\texttimes: not equivalent. $\\Delta$: mean F1 difference (signal $-$ single-sample).}\n\\label{tab:tost}\n\\begin{tabular}{l cccc cccc}\n\\toprule\n& \\multicolumn{4}{c}{\\textbf{NER}} & \\multicolumn{4}{c}{\\textbf{RE}} \\\\\n\\cmidrule(lr){2-5} \\cmidrule(lr){6-9}\nSignal & $\\Delta$ & $\\pm$2 & $\\pm$3 & $\\pm$5 & $\\Delta$ & $\\pm$2 & $\\pm$3 & $\\pm$5 \\\\",
      "numLines": 40,
      "startLine": 351,
      "totalLines": 1572
    }
  }
}
```

</details>

---


### Assistant

_source line 109_

<details><summary>Logged reasoning block</summary>

```text
Now I have very important findings:

1. **WNUT table (tab:wnut)** is at N=16, not N=8! The caption says "Qwen, N=16, T=1.0, n=689". But the main paper Table 3 says N=8. So:
   - WNUT VC ρ=0.724 in tab:wnut is at N=16
   - Paper experiments section line 48: "VC ρ=0.724 but conditional ρ=0.038; Table~\ref{tab:wnut}" — correct reference to N=16 table
   - But then line 104 claims "VC ρ=0.730; Table~\ref{tab:wnut}" which doesn't match the actual table value of 0.724, so that's an error.

2. **WNUT LP ρ**: The tab:wnut shows LP ρ=-.410 at N=16, while the main paper Table 3 shows WNUT LP ρ=-.446 at N=8. These different sample sizes explain the different values, but the text cites "LP ρ=−0.446" without clarifying which table it's from.

3. **Degeneracy table mismatch**: Table 3's caption specifies N=8 for all rows, yet the CoNLL degeneracy value of 48.4% appears to come from tab:degeneracy which shows N=16 data. I'm checking whether this 48.4% constant F1 value is actually consistent across both sample sizes or if there's a mismatch in which table the value was pulled from. NLL have 48.4% degeneracy at BOTH N=8 and N=16? That's unusual — with more samples (N=16), you'd expect slightly different degeneracy. Let me check.

From exp_002 (N=8 CoNLL): degen_rate not explicitly given. From exp_002_conll_n16: degen_rate = 0.4844 (N=16).

So the 48.4% is from the N=16 experiment. If the paper's Table 3 uses this value but claims N=8, that's a potential error. Unless the N=8 value happens to be the same.

Actually, the degeneracy table (tab:degeneracy) explicitly says "CoNLL 8B (N=16)" and shows 48.4%. So the 48.4% is definitely N=16. If Table 3 also shows 48.4% at N=8, either the N=8 value coincidentally matches or the N=16 result was mistakenly used. Looking at the N=16 results across different seeds — 0.5544, 0.471, and 0.4844 — I'd actually expect N=8 degeneracy to be higher since fewer samples make it more likely all of them produce identical F1 scores. than N=16 degeneracy. So if N=16 is 48.4%, N=8 should be ≥ 48.4%.

Hmm, actually, let me think about this differently. "Degeneracy" = all N samples have identical F1. With more samples, it's HARDER for all to agree. So N=16 degeneracy should be LOWER than N=8. So if N=16 is 48.4%, N=8 should be > 48.4%.

But Table 3 shows CoNLL N=8 degeneracy as 48.4%. This seems like it might be the N=16 value. The N=8 value should be higher.

This is a potential error ⚠️. The degeneracy value in Table 3 might be from N=16, not N=8.

4. **"13-87%" in introduction**: The appendix confirms this range for CoNLL across all configurations, with 87% from LLaMA and 13% from FewNERD. So this spans the full experimental space of model and dataset combinations, not just datasets. The intro's phrasing "across our benchmarks" is misleading—it should clarify this includes model variation.

5. **WNUT zero-F1 rate**: I'm seeing inconsistent numbers across different sections—52% in the experiments description, 51% in section 4.3, and 53.7% in the registry. The WNUT tab data suggests around 53% at N=16, which aligns with the registry value.

I think the 52% and 51% might be referring to instances where all samples yield zero F1, while the registry's 53.7% is the percentage of individual samples with F1=0—a different metric entirely. The minor discrepancy between 51% and 52% within the paper should be standardized.

Now I'm ready to compile the full audit report with all the inconsistencies I've found. Let me also double-check the SciERC AUROC values one more time by looking at the selection table data more carefully.

The ρ values match exp_012_rerun_1024 exactly, but the AUROC values don't align at all. Looking at the specific numbers, there are substantial gaps—VC is off by 2.1 percentage points, SJ by 4.2, FK by 2.7, and EM by a dramatic 13.5 percentage points. This suggests either the AUROC was recomputed through a different pipeline or there's an error somewhere in the paper or registry.

I'm considering whether the paper might use an inverted AUROC calculation—like treating "below median" as positive instead of "above median"—but that doesn't produce matching values either. I'm also wondering if the paper uses AUPRC instead of AUROC, or perhaps F1 percentiles rather than median as the threshold. The EM discrepancy is particularly suspicious and makes me think there could be a calculation bug specific to the SciERC NER task. Let me check what the averaged AUROC looks like in exp_015_v2 to see if that provides any clarity.

Looking at the averaged metrics from that experiment, they're also misaligned with the paper's reported values. And the best single NER AUROC from exp_016_signal_ensemble is 0.7, which doesn't match either. At this point I'm convinced the paper's SciERC AUROC values come from a different computational pipeline or threshold than what's in the registry—the ρ correlations match perfectly, so it's definitely the same underlying data, but the AUROC methodology must differ. I should document this as a key discrepancy and move forward with writing up the audit findings.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "a4084b54-ac7a-4baa-9f1e-b67f05507dac",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GQCbz46m4q8zeX9vG7mFc1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3027,
      "cache_read_input_tokens": 113878,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3027
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

_source line 110_

Now I have comprehensive data. Let me also check one more thing: the CoNLL N=8 selection data and verify the exact Table 2 numbers.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "93ac4687-440a-4661-a8c1-f06683f439e7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GQCbz46m4q8zeX9vG7mFc1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3027,
      "cache_read_input_tokens": 113878,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3027
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

_source line 111_

<details open><summary>🔧 Tool call — Read · `toolu_01FEXMM9eUuhUyaBDAT3yeGz`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
  "offset": 234,
  "limit": 40
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "d51023dd-bae0-4354-91b9-ca2d22236d10",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GQCbz46m4q8zeX9vG7mFc1",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3027,
      "cache_read_input_tokens": 113878,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3027
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

_source line 112 · 2026-05-19T13:43:36.852Z_

<details><summary>↩ Tool result · `toolu_01FEXMM9eUuhUyaBDAT3yeGz`</summary>

```text
234	\begin{table*}[t]
235	\centering
236	\small
237	\caption{Best-of-$N$ selection F1 (macro, instance-averaged) across configurations ($T{=}1.0$, 3-seed mean). Best non-oracle signal per row in \textbf{bold}. LP is the only signal with positive selection on both FewNERD configurations (Qwen $+1.39$~pp, Table~\ref{tab:fewnerd}; LLaMA $+0.36$~pp). At $N{=}16$ on LLaMA CoNLL, VC achieves small but significant gains ($+0.28$~pp, $p{<}0.03$; see text below). CoNLL shows especially tight clustering where greedy already exceeds 0.90.}
238	\label{tab:cross_selection}
239	\begin{tabular}{llccccccc}
240	\toprule
241	Config & $n$ & Greedy & Oracle & SJ & FK & EM & LP & VC \\
242	\midrule
243	LLaMA/SciERC $N{=}8$ & 529 & .646 & .778 & .643 & .639 & .634 & \textbf{.652} & .633 \\
244	LLaMA/SciERC $N{=}16$ & 529 & .645 & .806 & \textbf{.649} & \textbf{.649} & .640 & .646 & .640 \\
245	\addlinespace
246	LLaMA/FewNERD $N{=}8$ & 32{,}565 & .784 & .884 & .779 & .779 & .774 & \textbf{.788} & .760 \\
247	\addlinespace
248	Qwen/CoNLL $N{=}8$ & 2{,}756 & .908 & .957 & \textbf{.899} & .893 & .898 & .897 & .895 \\
249	LLaMA/CoNLL $N{=}8$ & 2{,}756 & .924 & .943 & .924 & \textbf{.925} & .924 & .924 & .923 \\
250	\bottomrule
251	\end{tabular}
252	\end{table*}
253	
254	\paragraph{Diminishing returns of $N$-scaling.}
255	Our $N{=}8$ and $N{=}16$ comparisons (Table~\ref{tab:robustness}) characterize the marginal value of additional samples for test-time scaling \cite{brown2024monkeys, snell2025scaling}.
256	For quality estimation, structural signals benefit consistently but sublinearly: SJ $\rho$ improves by $+0.047$ (Qwen SciERC, 3-seed mean) and $+0.032$ (LLaMA CoNLL, 3-seed mean) when doubling from $N{=}8$ to $N{=}16$, while log-probability is approximately $N$-invariant ($\Delta\rho{\leq}0.021$).
257	Structural signals use $\binom{N}{2}$ pairwise comparisons (28 pairs at $N{=}8$, 120 at $N{=}16$), but the $\rho$ improvement is far less than proportional, each additional comparison yields diminishing information.
258	This asymmetry gives structural signals a relative advantage in the compute-constrained regime: at $N{=}8$, SJ already achieves $\rho{=}0.431$ on LLaMA CoNLL (vs.\ LP $\rho{=}0.307$, $\Delta{=}{+}0.124$), and the gap \textit{widens} at $N{=}16$ ($\Delta{=}{+}0.163$) because structural signals continue to benefit from additional pairwise evidence while LP does not.
259	For sample selection, additional samples increase the oracle upper bound (more draws raise the probability of a high-quality candidate), but signal-based selection remains flat because the selector's inability to identify the best candidate is a granularity limitation, not a sample size limitation.
260	The practical implication is that $N{=}8$ captures most of the achievable quality estimation benefit; further scaling widens rather than closes the correlation-selection gap absent stronger per-sample selectors.
261	
262	\paragraph{$N{=}16$ CoNLL selection: small but significant.}
263	While quality estimation benefits sublinearly from $N$-scaling, selection behavior at $N{=}16$ reveals a nuanced exception on LLaMA CoNLL.
264	VC achieves the largest gain over single-sample ($+0.28$~pp, $p{=}0.003$--$0.027$ across 3 seeds, all significant), with SJ, FK, and EM at $+0.22$--$0.23$~pp and LP at $+0.12$~pp (2/3 seeds significant).
265	These gains are statistically significant but practically minimal: oracle headroom at $N{=}16$ is only 2.5~pp, so VC captures approximately 10\% of the available headroom.
266	This reinforces the primary finding: even under the most favorable conditions (high baseline performance, more candidates, and aggregated multi-seed evidence), signal-based selection recovers only a fraction of the oracle headroom available.
267	
268	\section{Bootstrap CI for Signal Comparisons}\label{app:bootstrap_signal}
269	
270	Table~\ref{tab:bootstrap_signal_ci} reports bootstrap confidence intervals for individual signal $\rho$ and pairwise $\Delta\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$).
271	The SJ--LP gap ($\Delta\rho{=}{+}0.155$) is clearly significant, the structural advantage reported in \S\ref{sec:qe_results} is robust.
272	The VC--SJ gap ($\Delta\rho{=}{+}0.019$) is not significant; these two structural signals perform comparably.
273	The SJ--EM gap ($\Delta\rho{=}{+}0.065$) is borderline significant, with the CI lower bound at $+0.003$ and upper bound at $+0.130$.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "02547541-e236-436b-a25d-560646c709f1",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_1/projects/struct_self_consist_ie/docs/paper/sections/appendix.tex",
      "content": "\\begin{table*}[t]\n\\centering\n\\small\n\\caption{Best-of-$N$ selection F1 (macro, instance-averaged) across configurations ($T{=}1.0$, 3-seed mean). Best non-oracle signal per row in \\textbf{bold}. LP is the only signal with positive selection on both FewNERD configurations (Qwen $+1.39$~pp, Table~\\ref{tab:fewnerd}; LLaMA $+0.36$~pp). At $N{=}16$ on LLaMA CoNLL, VC achieves small but significant gains ($+0.28$~pp, $p{<}0.03$; see text below). CoNLL shows especially tight clustering where greedy already exceeds 0.90.}\n\\label{tab:cross_selection}\n\\begin{tabular}{llccccccc}\n\\toprule\nConfig & $n$ & Greedy & Oracle & SJ & FK & EM & LP & VC \\\\\n\\midrule\nLLaMA/SciERC $N{=}8$ & 529 & .646 & .778 & .643 & .639 & .634 & \\textbf{.652} & .633 \\\\\nLLaMA/SciERC $N{=}16$ & 529 & .645 & .806 & \\textbf{.649} & \\textbf{.649} & .640 & .646 & .640 \\\\\n\\addlinespace\nLLaMA/FewNERD $N{=}8$ & 32{,}565 & .784 & .884 & .779 & .779 & .774 & \\textbf{.788} & .760 \\\\\n\\addlinespace\nQwen/CoNLL $N{=}8$ & 2{,}756 & .908 & .957 & \\textbf{.899} & .893 & .898 & .897 & .895 \\\\\nLLaMA/CoNLL $N{=}8$ & 2{,}756 & .924 & .943 & .924 & \\textbf{.925} & .924 & .924 & .923 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\paragraph{Diminishing returns of $N$-scaling.}\nOur $N{=}8$ and $N{=}16$ comparisons (Table~\\ref{tab:robustness}) characterize the marginal value of additional samples for test-time scaling \\cite{brown2024monkeys, snell2025scaling}.\nFor quality estimation, structural signals benefit consistently but sublinearly: SJ $\\rho$ improves by $+0.047$ (Qwen SciERC, 3-seed mean) and $+0.032$ (LLaMA CoNLL, 3-seed mean) when doubling from $N{=}8$ to $N{=}16$, while log-probability is approximately $N$-invariant ($\\Delta\\rho{\\leq}0.021$).\nStructural signals use $\\binom{N}{2}$ pairwise comparisons (28 pairs at $N{=}8$, 120 at $N{=}16$), but the $\\rho$ improvement is far less than proportional, each additional comparison yields diminishing information.\nThis asymmetry gives structural signals a relative advantage in the compute-constrained regime: at $N{=}8$, SJ already achieves $\\rho{=}0.431$ on LLaMA CoNLL (vs.\\ LP $\\rho{=}0.307$, $\\Delta{=}{+}0.124$), and the gap \\textit{widens} at $N{=}16$ ($\\Delta{=}{+}0.163$) because structural signals continue to benefit from additional pairwise evidence while LP does not.\nFor sample selection, additional samples increase the oracle upper bound (more draws raise the probability of a high-quality candidate), but signal-based selection remains flat because the selector's inability to identify the best candidate is a granularity limitation, not a sample size limitation.\nThe practical implication is that $N{=}8$ captures most of the achievable quality estimation benefit; further scaling widens rather than closes the correlation-selection gap absent stronger per-sample selectors.\n\n\\paragraph{$N{=}16$ CoNLL selection: small but significant.}\nWhile quality estimation benefits sublinearly from $N$-scaling, selection behavior at $N{=}16$ reveals a nuanced exception on LLaMA CoNLL.\nVC achieves the largest gain over single-sample ($+0.28$~pp, $p{=}0.003$--$0.027$ across 3 seeds, all significant), with SJ, FK, and EM at $+0.22$--$0.23$~pp and LP at $+0.12$~pp (2/3 seeds significant).\nThese gains are statistically significant but practically minimal: oracle headroom at $N{=}16$ is only 2.5~pp, so VC captures approximately 10\\% of the available headroom.\nThis reinforces the primary finding: even under the most favorable conditions (high baseline performance, more candidates, and aggregated multi-seed evidence), signal-based selection recovers only a fraction of the oracle headroom available.\n\n\\section{Bootstrap CI for Signal Comparisons}\\label{app:bootstrap_signal}\n\nTable~\\ref{tab:bootstrap_signal_ci} reports bootstrap confidence intervals for individual signal $\\rho$ and pairwise $\\Delta\\rho$ on SciERC NER ($N{=}8$, $n{=}529$, $B{=}10{,}000$, seed${=}42$).\nThe SJ--LP gap ($\\Delta\\rho{=}{+}0.155$) is clearly significant, the structural advantage reported in \\S\\ref{sec:qe_results} is robust.\nThe VC--SJ gap ($\\Delta\\rho{=}{+}0.019$) is not significant; these two structural signals perform comparably.\nThe SJ--EM gap ($\\Delta\\rho{=}{+}0.065$) is borderline significant, with the CI lower bound at $+0.003$ and upper bound at $+0.130$.",
      "numLines": 40,
      "startLine": 234,
      "totalLines": 1572
    }
  }
}
```

</details>

---


### Assistant

_source line 113_

<details><summary>Logged reasoning block</summary>

```text
Now I have critical data from the cross-selection table (tab:cross_selection). Let me verify a few specific claims:

1. **Qwen CoNLL N=8 selection**: Table shows greedy .908, Oracle .957, SJ .899, FK .893, EM .898, LP .897, VC .895. All signals BELOW greedy! This confirms selection fails on CoNLL. The table 3 says CoNLL LP Δ = -0.85pp, which is .908 - .897 = 1.1pp ≈ -1.1pp... 

Wait, there's a discrepancy here. The paper reports -0.85pp for CoNLL LP delta, but my calculation from the cross-selection table gives -1.1pp. Both tables claim to use 3-seed means, so the difference is puzzling. Looking more carefully at the table notes, both should be using the same 3-seed mean methodology, so the LP values ought to align—but they don't. Table 3 gives LP Δ of -0.85pp (implying LP ≈ .8995), while the cross-selection table shows LP at .897, which would be a -1.1pp delta. I'm wondering if there's a subtle difference in how the metrics are computed between the two tables, or if one is reporting macro F1 while the other uses a different aggregation method.

Actually, I think I see the issue: the mean of individual deltas across seeds won't necessarily equal the delta of the means. If greedy performance varies across seeds while LP performance also varies, then averaging the per-seed deltas could give a different result than computing the delta from the averaged values. Let me work through an example to verify this discrepancy.

Wait, that's not right—since averaging is linear, the mean of deltas should equal the delta of means. So if I'm getting -0.85pp versus -1.1pp, either the seed populations differ between tables or there's something else going on computationally.

I'm also noticing another inconsistency: Table 3 reports CoNLL LP ρ as .302, but Table 1 shows .316 for the same condition. These don't match, which suggests either different experimental setups or a data entry error.

Looking closer, Table 1's .316 aligns with the registry entry for seed 42, while Table 3's .302 is the 3-seed average—meaning seeds 123 and 456 must have lower values to pull the mean down. For the LP delta discrepancy, I need to check whether the cross-selection table is actually using the same seeds as Table 3, since both claim to report 3-seed means. I'm flagging this discrepancy and moving forward with compiling the audit report. I've identified three critical issues: the SciERC AUROC values are systematically lower in the paper than the registry (except for LP which matches), suggesting a different computation method; there's an internal inconsistency in the paper where WNUT VC ρ is reported as both 0.724 and 0.730, with the appendix confirming 0.724 as correct; and the CoNLL LP selection delta shows -0.85pp in Table 3 but the cross-selection table indicates a different value, likely due to different seed combinations.

Beyond these critical issues, I'm also noting several major concerns: the "13-87% degeneracy" claim in the introduction is misleading because the 87% refers specifically to LLaMA on CoNLL, not across benchmarks; there's a potential mismatch between the N=8 degeneracy value reported in Table 3 versus what appears in the degeneracy table; and the FewNERD degeneracy figure of 13.8% doesn't align with the 3-seed mean from the registry data, which comes out to around 11.8%.

Looking at the remaining discrepancies, I see WNUT is cited with both "52%" and "51%" in different places, the FewNERD LP selection improvement rounds 1.38pp up to 1.39pp, and there's a known contradiction about "+0.1pp" versus "+0.4pp" that may have already been resolved in the current version since the paper shows different datasets rather than conflicting claims. The entity construction numbers are harder to pin down since the registry uses 5-fold cross-validation while the paper reports multi-seed means, making direct comparison difficult even though the protocols are legitimately different.

For the remaining minor issues, FewNERD's LP correlation coefficient shows high seed variance—seed 42 alone gives 0.422 while the 3-seed mean is 0.220, which is plausible but can't be independently verified. WNUT's LP correlation also differs between what the paper reports and what's in the registry, though this appears to stem from different sample sizes rather than a genuine error.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "e21c3add-633d-4663-b1eb-e2854d1b8be8",
  "uuid": "5e154194-8b30-405f-9df4-1e22cbbaabd5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JBpPZ1qkhfRoSAM3ug3t1x",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4045,
      "cache_read_input_tokens": 116905,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4045
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
