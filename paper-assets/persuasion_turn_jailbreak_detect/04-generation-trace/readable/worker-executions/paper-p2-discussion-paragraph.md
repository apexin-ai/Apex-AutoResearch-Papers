# paper p2 discussion paragraph

**DisPeD: A Controlled Study of Encoder Adaptation for Multi-Turn Jailbreak Detection** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 15
- **Recorded user turns:** 0
- **Tool calls:** 3
- **Original source:** `logs/workers/worker_paper_p2-discussion-paragraph_20260523T120500.log`
- **Structured JSON:** [`6c472c277c97f6921b27.json`](../../sessions/6c/6c472c277c97f6921b27.json)

## Before a recorded user message

15 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect",
  "session_id": "61763e55-a6af-4ad8-a395-62832efa834a",
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
    "mcp__agent-ml-research__save_project_file"
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
  "uuid": "66639821-0a2f-4ccf-a3c3-5530ae0039c3",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-3/projects/-home-ubuntu--agent-ml-research-idea-gen-0514-2-projects-persuasion-turn-jailbreak-detect/memory/"
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
    "resetsAt": 1779552000,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "cae0d1f2-8486-4229-95bb-a6f224212c24",
  "session_id": "61763e55-a6af-4ad8-a395-62832efa834a"
}
```

---

### Assistant

_source line 4_

Let me read the file first.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "61763e55-a6af-4ad8-a395-62832efa834a",
  "uuid": "214b37ab-b3eb-4062-accd-b99716a4a33b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VKPyYefK645ZFgarexYX9N",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12290,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12290
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

_source line 5_

<details open><summary>🔧 Tool call — Read · `toolu_014WaAkUL5eQfKZWhsVR8d5f`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "61763e55-a6af-4ad8-a395-62832efa834a",
  "uuid": "e2418263-db0b-455b-81bf-dbe728ce578c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VKPyYefK645ZFgarexYX9N",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12290,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12290
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

_source line 6 · 2026-05-23T12:05:14.325Z_

<details><summary>↩ Tool result · `toolu_014WaAkUL5eQfKZWhsVR8d5f`</summary>

```text
1	% conclusion.tex
2	
3	\section{Discussion}
4	\label{sec:discussion}
5	
6	\paragraph{Discriminative compression and label equivalence.}
7	Three observations argue against a topic shortcut: unstable topic OOD (F1\,=\,0.541$\pm$0.207), scrambled labels within 3.9\,pp, and label-free MLM detection (F1\,$\geq$\,0.97).
8	Classification DAPT compresses features into few dimensions (participation ratio 3.7--9.4 vs.\ 25--32; Fisher 2.6--19.7 vs.\ $<$0.001; Appendix~\ref{app:representation}), consistent with \citet{zhang2021understanding}: domain-relevant partitioning appears necessary (topic DAPT fails; Appendix~\ref{app:topic_failure}) and compression localizes to 3 SVD dimensions in layers 8--12 (Appendix~\ref{app:layerwise}). A probe over these dimensions confirms sufficiency; removal degrades DD by 17\,pp while FITD is unaffected (partial necessity; Appendix~\ref{app:discriminative_probe}). This aligns with concurrent findings that internal LLM layers encode detectable jailbreak patterns~\citep{kadali2025internallayers,kadali2026trace}.
9	
10	\paragraph{Cross-condition transfer and boundaries.}
11	ToxicChat (+18--42\,pp; Table~\ref{tab:human_data}) and cross-LLM experiments (Appendix~\ref{app:cross_llm}) confirm transfer beyond single-LLM artifacts; mixed-LLM 9-class maintains 0.818 while MLM collapses, suggesting classification extracts style-invariant features. Classification supervision is associated with lower variance on synthetic OOD (descriptively 3--23$\times$, 3 seeds) but this reverses on ToxicChat (std\,=\,0.087 vs.\ 0.013); frozen probing localizes MLM instability to Stage-2 (Appendix~\ref{app:frozen_verify}). Three encoders (125M--355M) differ in pretraining; same-architecture scaling is needed. At larger scales (355M), DAPT can be counterproductive: RoBERTa-large vanilla achieves AA F1\,=\,1.000 while 9-class drops to 0.946. WildChat FPR rises from 48.1\% to 68.1\% under 9-class DAPT, confirming that attack-side generalization amplifies benign distribution sensitivity.
12	
13	An alternative interpretation of the low-dimensional discriminative subspace (Section~\ref{sec:decomposition}) is overfitting or representation collapse rather than beneficial feature selection. The 68.1\% FPR on out-of-distribution benign data provides partial evidence for this interpretation: classification DAPT may compress representations in ways that sacrifice generalization to unseen benign distributions while improving attack-side separation.
14	
15	\section{Conclusion}
16	
17	We decompose multi-turn jailbreak generalization into two orthogonal axes. On synthetic multi-turn data at base model scale (125M--184M), classification-based domain adaptation recovers out-of-distribution detection (F1\,=\,0.97--1.0 vs.\ vanilla 0.26--0.31) while unsupervised pretraining collapses; template attacks remain robust across conditions ($|d|\!\leq\!0.14$) but strategy-diverse attacks degrade under mixed-LLM training (F1\,=\,0.504). Orthogonal to attack-side generalization, few-shot benign adaptation reduces false-positive rates from 58--68\% to 0--1.5\% with as few as 10 conversations, at 24.3$\times$ inference speedup over LLM-as-judge.
18	
19	On human-authored single-turn data (ToxicChat), this hierarchy reverses: MLM outperforms classification (0.837 vs 0.596, a 24.1\,pp gap). Classification DAPT's advantage is condition-specific (multi-turn, synthetic) rather than universal.
20	
21	These findings have boundaries. At larger scales (355M), DAPT can be counterproductive (RoBERTa-large vanilla AA\,=\,1.000 vs.\ 9-class 0.946). Mixed-LLM diversity degrades strategy-diverse attack detection to near chance, and length sensitivity persists across configurations.
22	
23	The ablation framework contributes a reusable methodology for safety classification research: four adaptation axes (domain exposure, supervision type, label quality, granularity) at multiple scales provide a template for diagnosing when and why domain adaptation succeeds or fails.
24	
25	\section{Limitations}
26	\label{sec:limitations}
27	
28	All findings derive from synthetic conversations generated by a single LLM (Qwen3-8B; 350 training, 76--118 test per family, 3 seeds); the evidence hierarchy reverses on human single-turn data (Section~\ref{sec:discussion}), and no human-generated multi-turn jailbreak dataset exists. OOD F1 figures are upper bounds because benign data is IID; estimated dual-OOD F1 drops 12--14\,pp without adaptation but recovers within 0.3\,pp after few-shot adaptation (Appendix~\ref{app:dual_ood}). Benign-side adaptation (WildChat FPR 68.1\%\,$\rightarrow$\,0\% with 10 conversations; OASST2 57.5\%\,$\rightarrow$\,1.0\% at $N$\,=\,25) is validated on only two platforms with small samples ($n \leq 49$). Benign-only adaptation does not address cross-LLM distribution shift: adapting on Llama-origin conversations collapses Llama jailbreak detection (Appendix~\ref{app:cross_llm}). Only persuasion-mediated multi-turn attacks fall within scope; single-turn token-level attacks~\citep{zou2023gcg} and non-text modalities are not addressed.
29	
30	\section*{Ethics Statement}
31	
32	This work is defensive: it improves detection of multi-turn jailbreak attacks rather than developing new attacks. We acknowledge dual-use risk, as the persuasion taxonomy could inform adversarial actors. We mitigate this by using only synthetic conversations (no real harmful content), withholding attack-generation prompts, and focusing contributions on detection mechanisms. No human subjects were involved; all data will be released under CC BY-NC 4.0.
33	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "61763e55-a6af-4ad8-a395-62832efa834a",
  "uuid": "fe5b1c87-65ee-4320-a766-60039e407838",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/conclusion.tex",
      "content": "% conclusion.tex\n\n\\section{Discussion}\n\\label{sec:discussion}\n\n\\paragraph{Discriminative compression and label equivalence.}\nThree observations argue against a topic shortcut: unstable topic OOD (F1\\,=\\,0.541$\\pm$0.207), scrambled labels within 3.9\\,pp, and label-free MLM detection (F1\\,$\\geq$\\,0.97).\nClassification DAPT compresses features into few dimensions (participation ratio 3.7--9.4 vs.\\ 25--32; Fisher 2.6--19.7 vs.\\ $<$0.001; Appendix~\\ref{app:representation}), consistent with \\citet{zhang2021understanding}: domain-relevant partitioning appears necessary (topic DAPT fails; Appendix~\\ref{app:topic_failure}) and compression localizes to 3 SVD dimensions in layers 8--12 (Appendix~\\ref{app:layerwise}). A probe over these dimensions confirms sufficiency; removal degrades DD by 17\\,pp while FITD is unaffected (partial necessity; Appendix~\\ref{app:discriminative_probe}). This aligns with concurrent findings that internal LLM layers encode detectable jailbreak patterns~\\citep{kadali2025internallayers,kadali2026trace}.\n\n\\paragraph{Cross-condition transfer and boundaries.}\nToxicChat (+18--42\\,pp; Table~\\ref{tab:human_data}) and cross-LLM experiments (Appendix~\\ref{app:cross_llm}) confirm transfer beyond single-LLM artifacts; mixed-LLM 9-class maintains 0.818 while MLM collapses, suggesting classification extracts style-invariant features. Classification supervision is associated with lower variance on synthetic OOD (descriptively 3--23$\\times$, 3 seeds) but this reverses on ToxicChat (std\\,=\\,0.087 vs.\\ 0.013); frozen probing localizes MLM instability to Stage-2 (Appendix~\\ref{app:frozen_verify}). Three encoders (125M--355M) differ in pretraining; same-architecture scaling is needed. At larger scales (355M), DAPT can be counterproductive: RoBERTa-large vanilla achieves AA F1\\,=\\,1.000 while 9-class drops to 0.946. WildChat FPR rises from 48.1\\% to 68.1\\% under 9-class DAPT, confirming that attack-side generalization amplifies benign distribution sensitivity.\n\nAn alternative interpretation of the low-dimensional discriminative subspace (Section~\\ref{sec:decomposition}) is overfitting or representation collapse rather than beneficial feature selection. The 68.1\\% FPR on out-of-distribution benign data provides partial evidence for this interpretation: classification DAPT may compress representations in ways that sacrifice generalization to unseen benign distributions while improving attack-side separation.\n\n\\section{Conclusion}\n\nWe decompose multi-turn jailbreak generalization into two orthogonal axes. On synthetic multi-turn data at base model scale (125M--184M), classification-based domain adaptation recovers out-of-distribution detection (F1\\,=\\,0.97--1.0 vs.\\ vanilla 0.26--0.31) while unsupervised pretraining collapses; template attacks remain robust across conditions ($|d|\\!\\leq\\!0.14$) but strategy-diverse attacks degrade under mixed-LLM training (F1\\,=\\,0.504). Orthogonal to attack-side generalization, few-shot benign adaptation reduces false-positive rates from 58--68\\% to 0--1.5\\% with as few as 10 conversations, at 24.3$\\times$ inference speedup over LLM-as-judge.\n\nOn human-authored single-turn data (ToxicChat), this hierarchy reverses: MLM outperforms classification (0.837 vs 0.596, a 24.1\\,pp gap). Classification DAPT's advantage is condition-specific (multi-turn, synthetic) rather than universal.\n\nThese findings have boundaries. At larger scales (355M), DAPT can be counterproductive (RoBERTa-large vanilla AA\\,=\\,1.000 vs.\\ 9-class 0.946). Mixed-LLM diversity degrades strategy-diverse attack detection to near chance, and length sensitivity persists across configurations.\n\nThe ablation framework contributes a reusable methodology for safety classification research: four adaptation axes (domain exposure, supervision type, label quality, granularity) at multiple scales provide a template for diagnosing when and why domain adaptation succeeds or fails.\n\n\\section{Limitations}\n\\label{sec:limitations}\n\nAll findings derive from synthetic conversations generated by a single LLM (Qwen3-8B; 350 training, 76--118 test per family, 3 seeds); the evidence hierarchy reverses on human single-turn data (Section~\\ref{sec:discussion}), and no human-generated multi-turn jailbreak dataset exists. OOD F1 figures are upper bounds because benign data is IID; estimated dual-OOD F1 drops 12--14\\,pp without adaptation but recovers within 0.3\\,pp after few-shot adaptation (Appendix~\\ref{app:dual_ood}). Benign-side adaptation (WildChat FPR 68.1\\%\\,$\\rightarrow$\\,0\\% with 10 conversations; OASST2 57.5\\%\\,$\\rightarrow$\\,1.0\\% at $N$\\,=\\,25) is validated on only two platforms with small samples ($n \\leq 49$). Benign-only adaptation does not address cross-LLM distribution shift: adapting on Llama-origin conversations collapses Llama jailbreak detection (Appendix~\\ref{app:cross_llm}). Only persuasion-mediated multi-turn attacks fall within scope; single-turn token-level attacks~\\citep{zou2023gcg} and non-text modalities are not addressed.\n\n\\section*{Ethics Statement}\n\nThis work is defensive: it improves detection of multi-turn jailbreak attacks rather than developing new attacks. We acknowledge dual-use risk, as the persuasion taxonomy could inform adversarial actors. We mitigate this by using only synthetic conversations (no real harmful content), withholding attack-generation prompts, and focusing contributions on detection mechanisms. No human subjects were involved; all data will be released under CC BY-NC 4.0.\n",
      "numLines": 33,
      "startLine": 1,
      "totalLines": 33
    }
  }
}
```

</details>

---

### Assistant

_source line 7_

<details><summary>Logged reasoning block</summary>

```text
I need to add the new paragraph after the "alternative interpretation" paragraph (line 13) and before `\section{Conclusion}` (line 15). Let me insert it.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "61763e55-a6af-4ad8-a395-62832efa834a",
  "uuid": "ee743cef-602d-43a9-90f3-d9e50e9898ef",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QtQcP1wJsmFacMRJTNXEQF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1771,
      "cache_read_input_tokens": 24131,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1771
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

_source line 8_

Now I'll insert the new paragraph between the "alternative interpretation" paragraph and `\section{Conclusion}`.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "61763e55-a6af-4ad8-a395-62832efa834a",
  "uuid": "c78c38dc-dee3-4e55-872b-12639958f466",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QtQcP1wJsmFacMRJTNXEQF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1771,
      "cache_read_input_tokens": 24131,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1771
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

_source line 9_

<details open><summary>🔧 Tool call — Edit · `toolu_01Puz4WgYyczX1uv9VY6hqD8`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/conclusion.tex",
  "old_string": "An alternative interpretation of the low-dimensional discriminative subspace (Section~\\ref{sec:decomposition}) is overfitting or representation collapse rather than beneficial feature selection. The 68.1\\% FPR on out-of-distribution benign data provides partial evidence for this interpretation: classification DAPT may compress representations in ways that sacrifice generalization to unseen benign distributions while improving attack-side separation.\n\n\\section{Conclusion}",
  "new_string": "An alternative interpretation of the low-dimensional discriminative subspace (Section~\\ref{sec:decomposition}) is overfitting or representation collapse rather than beneficial feature selection. The 68.1\\% FPR on out-of-distribution benign data provides partial evidence for this interpretation: classification DAPT may compress representations in ways that sacrifice generalization to unseen benign distributions while improving attack-side separation.\n\n\\paragraph{Length as a potential confound.}\nTurn count differs between attack families (DD: 6--10 turns, AA: 3--8) and IID benign (6--14), raising the concern that detection may exploit length shortcuts. Length-matched evaluation on the overlapping turn-count range shows negligible change: DD F1 shifts by $-$0.8\\,pp (range-matched) to $+$2.5\\,pp (bucket-matched), AA by $+$1.5\\,pp to $+$0.9\\,pp, confirming that detection operates on per-turn content rather than conversation length. The $-$57.9\\,pp ActorAttack collapse under zero-padding (Appendix~\\ref{app:length_independence}) is consistent with signal density dilution---padding introduces uninformative turns that reduce the proportion of attack-bearing content---rather than length shortcut removal.\n\n\\section{Conclusion}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "61763e55-a6af-4ad8-a395-62832efa834a",
  "uuid": "2b995deb-35ab-4920-8290-c465eecf5ca1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01QtQcP1wJsmFacMRJTNXEQF",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1771,
      "cache_read_input_tokens": 24131,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1771
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

_source line 10 · 2026-05-23T12:05:28.299Z_

<details><summary>↩ Tool result · `toolu_01Puz4WgYyczX1uv9VY6hqD8`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/conclusion.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "61763e55-a6af-4ad8-a395-62832efa834a",
  "uuid": "5b0afd5a-e1e1-4cf1-af17-7fd16d92a2ff",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/conclusion.tex",
    "oldString": "An alternative interpretation of the low-dimensional discriminative subspace (Section~\\ref{sec:decomposition}) is overfitting or representation collapse rather than beneficial feature selection. The 68.1\\% FPR on out-of-distribution benign data provides partial evidence for this interpretation: classification DAPT may compress representations in ways that sacrifice generalization to unseen benign distributions while improving attack-side separation.\n\n\\section{Conclusion}",
    "newString": "An alternative interpretation of the low-dimensional discriminative subspace (Section~\\ref{sec:decomposition}) is overfitting or representation collapse rather than beneficial feature selection. The 68.1\\% FPR on out-of-distribution benign data provides partial evidence for this interpretation: classification DAPT may compress representations in ways that sacrifice generalization to unseen benign distributions while improving attack-side separation.\n\n\\paragraph{Length as a potential confound.}\nTurn count differs between attack families (DD: 6--10 turns, AA: 3--8) and IID benign (6--14), raising the concern that detection may exploit length shortcuts. Length-matched evaluation on the overlapping turn-count range shows negligible change: DD F1 shifts by $-$0.8\\,pp (range-matched) to $+$2.5\\,pp (bucket-matched), AA by $+$1.5\\,pp to $+$0.9\\,pp, confirming that detection operates on per-turn content rather than conversation length. The $-$57.9\\,pp ActorAttack collapse under zero-padding (Appendix~\\ref{app:length_independence}) is consistent with signal density dilution---padding introduces uninformative turns that reduce the proportion of attack-bearing content---rather than length shortcut removal.\n\n\\section{Conclusion}",
    "originalFile": "% conclusion.tex\n\n\\section{Discussion}\n\\label{sec:discussion}\n\n\\paragraph{Discriminative compression and label equivalence.}\nThree observations argue against a topic shortcut: unstable topic OOD (F1\\,=\\,0.541$\\pm$0.207), scrambled labels within 3.9\\,pp, and label-free MLM detection (F1\\,$\\geq$\\,0.97).\nClassification DAPT compresses features into few dimensions (participation ratio 3.7--9.4 vs.\\ 25--32; Fisher 2.6--19.7 vs.\\ $<$0.001; Appendix~\\ref{app:representation}), consistent with \\citet{zhang2021understanding}: domain-relevant partitioning appears necessary (topic DAPT fails; Appendix~\\ref{app:topic_failure}) and compression localizes to 3 SVD dimensions in layers 8--12 (Appendix~\\ref{app:layerwise}). A probe over these dimensions confirms sufficiency; removal degrades DD by 17\\,pp while FITD is unaffected (partial necessity; Appendix~\\ref{app:discriminative_probe}). This aligns with concurrent findings that internal LLM layers encode detectable jailbreak patterns~\\citep{kadali2025internallayers,kadali2026trace}.\n\n\\paragraph{Cross-condition transfer and boundaries.}\nToxicChat (+18--42\\,pp; Table~\\ref{tab:human_data}) and cross-LLM experiments (Appendix~\\ref{app:cross_llm}) confirm transfer beyond single-LLM artifacts; mixed-LLM 9-class maintains 0.818 while MLM collapses, suggesting classification extracts style-invariant features. Classification supervision is associated with lower variance on synthetic OOD (descriptively 3--23$\\times$, 3 seeds) but this reverses on ToxicChat (std\\,=\\,0.087 vs.\\ 0.013); frozen probing localizes MLM instability to Stage-2 (Appendix~\\ref{app:frozen_verify}). Three encoders (125M--355M) differ in pretraining; same-architecture scaling is needed. At larger scales (355M), DAPT can be counterproductive: RoBERTa-large vanilla achieves AA F1\\,=\\,1.000 while 9-class drops to 0.946. WildChat FPR rises from 48.1\\% to 68.1\\% under 9-class DAPT, confirming that attack-side generalization amplifies benign distribution sensitivity.\n\nAn alternative interpretation of the low-dimensional discriminative subspace (Section~\\ref{sec:decomposition}) is overfitting or representation collapse rather than beneficial feature selection. The 68.1\\% FPR on out-of-distribution benign data provides partial evidence for this interpretation: classification DAPT may compress representations in ways that sacrifice generalization to unseen benign distributions while improving attack-side separation.\n\n\\section{Conclusion}\n\nWe decompose multi-turn jailbreak generalization into two orthogonal axes. On synthetic multi-turn data at base model scale (125M--184M), classification-based domain adaptation recovers out-of-distribution detection (F1\\,=\\,0.97--1.0 vs.\\ vanilla 0.26--0.31) while unsupervised pretraining collapses; template attacks remain robust across conditions ($|d|\\!\\leq\\!0.14$) but strategy-diverse attacks degrade under mixed-LLM training (F1\\,=\\,0.504). Orthogonal to attack-side generalization, few-shot benign adaptation reduces false-positive rates from 58--68\\% to 0--1.5\\% with as few as 10 conversations, at 24.3$\\times$ inference speedup over LLM-as-judge.\n\nOn human-authored single-turn data (ToxicChat), this hierarchy reverses: MLM outperforms classification (0.837 vs 0.596, a 24.1\\,pp gap). Classification DAPT's advantage is condition-specific (multi-turn, synthetic) rather than universal.\n\nThese findings have boundaries. At larger scales (355M), DAPT can be counterproductive (RoBERTa-large vanilla AA\\,=\\,1.000 vs.\\ 9-class 0.946). Mixed-LLM diversity degrades strategy-diverse attack detection to near chance, and length sensitivity persists across configurations.\n\nThe ablation framework contributes a reusable methodology for safety classification research: four adaptation axes (domain exposure, supervision type, label quality, granularity) at multiple scales provide a template for diagnosing when and why domain adaptation succeeds or fails.\n\n\\section{Limitations}\n\\label{sec:limitations}\n\nAll findings derive from synthetic conversations generated by a single LLM (Qwen3-8B; 350 training, 76--118 test per family, 3 seeds); the evidence hierarchy reverses on human single-turn data (Section~\\ref{sec:discussion}), and no human-generated multi-turn jailbreak dataset exists. OOD F1 figures are upper bounds because benign data is IID; estimated dual-OOD F1 drops 12--14\\,pp without adaptation but recovers within 0.3\\,pp after few-shot adaptation (Appendix~\\ref{app:dual_ood}). Benign-side adaptation (WildChat FPR 68.1\\%\\,$\\rightarrow$\\,0\\% with 10 conversations; OASST2 57.5\\%\\,$\\rightarrow$\\,1.0\\% at $N$\\,=\\,25) is validated on only two platforms with small samples ($n \\leq 49$). Benign-only adaptation does not address cross-LLM distribution shift: adapting on Llama-origin conversations collapses Llama jailbreak detection (Appendix~\\ref{app:cross_llm}). Only persuasion-mediated multi-turn attacks fall within scope; single-turn token-level attacks~\\citep{zou2023gcg} and non-text modalities are not addressed.\n\n\\section*{Ethics Statement}\n\nThis work is defensive: it improves detection of multi-turn jailbreak attacks rather than developing new attacks. We acknowledge dual-use risk, as the persuasion taxonomy could inform adversarial actors. We mitigate this by using only synthetic conversations (no real harmful content), withholding attack-generation prompts, and focusing contributions on detection mechanisms. No human subjects were involved; all data will be released under CC BY-NC 4.0.\n",
    "structuredPatch": [
      {
        "oldStart": 12,
        "oldLines": 6,
        "newStart": 12,
        "newLines": 9,
        "lines": [
          " ",
          " An alternative interpretation of the low-dimensional discriminative subspace (Section~\\ref{sec:decomposition}) is overfitting or representation collapse rather than beneficial feature selection. The 68.1\\% FPR on out-of-distribution benign data provides partial evidence for this interpretation: classification DAPT may compress representations in ways that sacrifice generalization to unseen benign distributions while improving attack-side separation.",
          " ",
          "+\\paragraph{Length as a potential confound.}",
          "+Turn count differs between attack families (DD: 6--10 turns, AA: 3--8) and IID benign (6--14), raising the concern that detection may exploit length shortcuts. Length-matched evaluation on the overlapping turn-count range shows negligible change: DD F1 shifts by $-$0.8\\,pp (range-matched) to $+$2.5\\,pp (bucket-matched), AA by $+$1.5\\,pp to $+$0.9\\,pp, confirming that detection operates on per-turn content rather than conversation length. The $-$57.9\\,pp ActorAttack collapse under zero-padding (Appendix~\\ref{app:length_independence}) is consistent with signal density dilution---padding introduces uninformative turns that reduce the proportion of attack-bearing content---rather than length shortcut removal.",
          "+",
          " \\section{Conclusion}",
          " ",
          " We decompose multi-turn jailbreak generalization into two orthogonal axes. On synthetic multi-turn data at base model scale (125M--184M), classification-based domain adaptation recovers out-of-distribution detection (F1\\,=\\,0.97--1.0 vs.\\ vanilla 0.26--0.31) while unsupervised pretraining collapses; template attacks remain robust across conditions ($|d|\\!\\leq\\!0.14$) but strategy-diverse attacks degrade under mixed-LLM training (F1\\,=\\,0.504). Orthogonal to attack-side generalization, few-shot benign adaptation reduces false-positive rates from 58--68\\% to 0--1.5\\% with as few as 10 conversations, at 24.3$\\times$ inference speedup over LLM-as-judge."
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

_source line 11_

Now let me compile to verify.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "61763e55-a6af-4ad8-a395-62832efa834a",
  "uuid": "ee593ec3-b1af-4c97-983f-556569cc3154",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VUG89toQgoEtHGbXbG1jaf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 682,
      "cache_read_input_tokens": 25902,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 682
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

_source line 12_

<details open><summary>🔧 Tool call — Bash · `toolu_01BnNT6w1dt23RQ522zR14df`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper && pdflatex -interaction=nonstopmode main.tex 2>&1 | tail -20",
  "timeout": 60000
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "61763e55-a6af-4ad8-a395-62832efa834a",
  "uuid": "2c199175-b2a2-4f6e-be0b-06bcf90bcc08",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01VUG89toQgoEtHGbXbG1jaf",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 682,
      "cache_read_input_tokens": 25902,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 682
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

_source line 13 · 2026-05-23T12:05:35.456Z_

<details><summary>↩ Tool result · `toolu_01BnNT6w1dt23RQ522zR14df`</summary>

```text
&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmmi10.pfb>&lt;/usr/
share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmmi8.pfb>&lt;/usr/share/t
exlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmmi9.pfb>&lt;/usr/share/texlive/
texmf-dist/fonts/type1/public/amsfonts/cm/cmr10.pfb>&lt;/usr/share/texlive/texmf-d
ist/fonts/type1/public/amsfonts/cm/cmr6.pfb>&lt;/usr/share/texlive/texmf-dist/font
s/type1/public/amsfonts/cm/cmr7.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/
public/amsfonts/cm/cmr8.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/a
msfonts/cm/cmr9.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/
cm/cmsy10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cms
y6.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmsy8.pfb>
&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmsy9.pfb>&lt;/usr/s
hare/texlive/texmf-dist/fonts/type1/public/amsfonts/symbols/msam10.pfb>&lt;/usr/sh
are/texlive/texmf-dist/fonts/type1/public/amsfonts/symbols/msbm10.pfb>&lt;/usr/sha
re/texlive/texmf-dist/fonts/type1/urw/courier/ucrr8a.pfb>&lt;/usr/share/texlive/te
xmf-dist/fonts/type1/urw/helvetic/uhvb8a.pfb>&lt;/usr/share/texlive/texmf-dist/fon
ts/type1/urw/times/utmb8a.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/urw/ti
mes/utmr8a.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/urw/times/utmri8a.pfb
>
Output written on main.pdf (25 pages, 519992 bytes).
Transcript written on main.log.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "61763e55-a6af-4ad8-a395-62832efa834a",
  "uuid": "52cb7923-ec9f-4f86-ac1d-3b4df283ff3c",
  "tool_use_result": {
    "stdout": "&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmmi10.pfb>&lt;/usr/\nshare/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmmi8.pfb>&lt;/usr/share/t\nexlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmmi9.pfb>&lt;/usr/share/texlive/\ntexmf-dist/fonts/type1/public/amsfonts/cm/cmr10.pfb>&lt;/usr/share/texlive/texmf-d\nist/fonts/type1/public/amsfonts/cm/cmr6.pfb>&lt;/usr/share/texlive/texmf-dist/font\ns/type1/public/amsfonts/cm/cmr7.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/\npublic/amsfonts/cm/cmr8.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/a\nmsfonts/cm/cmr9.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/\ncm/cmsy10.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cms\ny6.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmsy8.pfb>\n&lt;/usr/share/texlive/texmf-dist/fonts/type1/public/amsfonts/cm/cmsy9.pfb>&lt;/usr/s\nhare/texlive/texmf-dist/fonts/type1/public/amsfonts/symbols/msam10.pfb>&lt;/usr/sh\nare/texlive/texmf-dist/fonts/type1/public/amsfonts/symbols/msbm10.pfb>&lt;/usr/sha\nre/texlive/texmf-dist/fonts/type1/urw/courier/ucrr8a.pfb>&lt;/usr/share/texlive/te\nxmf-dist/fonts/type1/urw/helvetic/uhvb8a.pfb>&lt;/usr/share/texlive/texmf-dist/fon\nts/type1/urw/times/utmb8a.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/urw/ti\nmes/utmr8a.pfb>&lt;/usr/share/texlive/texmf-dist/fonts/type1/urw/times/utmri8a.pfb\n>\nOutput written on main.pdf (25 pages, 519992 bytes).\nTranscript written on main.log.",
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

_source line 14_

编译成功，25 页。长度控制段落已插入 Discussion 中 "alternative interpretation" 段落之后、`\section{Conclusion}` 之前。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "61763e55-a6af-4ad8-a395-62832efa834a",
  "uuid": "8d3284d8-9a78-427e-90c9-4bdcb63ee053",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015aAHnDxTps4jchFgrhM2eh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 863,
      "cache_read_input_tokens": 26584,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 863
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

_source line 15_

编译成功，25 页。长度控制段落已插入 Discussion 中 "alternative interpretation" 段落之后、`\section{Conclusion}` 之前。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 29777,
  "duration_api_ms": 29447,
  "num_turns": 4,
  "stop_reason": "end_turn",
  "session_id": "61763e55-a6af-4ad8-a395-62832efa834a",
  "total_cost_usd": 0.1656805,
  "usage": {
    "input_tokens": 6,
    "cache_creation_input_tokens": 15606,
    "cache_read_input_tokens": 88458,
    "output_tokens": 893,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 15606,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 48,
        "cache_read_input_tokens": 26584,
        "cache_creation_input_tokens": 863,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 863
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1484,
      "outputTokens": 15,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.001559,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 6,
      "outputTokens": 893,
      "cacheReadInputTokens": 88458,
      "cacheCreationInputTokens": 15606,
      "webSearchRequests": 0,
      "costUSD": 0.16412150000000003,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "2504d828-9216-4e69-8099-4d94fd886315"
}
```

</details>

---
