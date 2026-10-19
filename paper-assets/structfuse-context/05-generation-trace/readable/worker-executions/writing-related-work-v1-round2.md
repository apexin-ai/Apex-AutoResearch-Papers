# writing related work v1 round2

**StructFuse: Structure-Grounded Hard Negative Mining for Contrastive Code Context Retrieval** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 51
- **Recorded user turns:** 0
- **Tool calls:** 17
- **Original source:** `logs/workers/worker_writing_related-work-v1-round2_20260515T101954.log`
- **Structured JSON:** [`ee14d5044d1b88e61a74.json`](../../sessions/ee/ee14d5044d1b88e61a74.json)

## Before a recorded user message

51 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context",
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
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
  "uuid": "f5195048-0c53-468d-b25a-ddd897a57cab",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-4/projects/-home-ubuntu--agent-ml-research-idea-gen-0509-5-projects-structfuse-context/memory/"
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
    "resetsAt": 1778854800,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "014486e4-2e57-4880-9f90-c72d84879133",
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f"
}
```

---

### Assistant

_source line 4_

I'll start by reading the files I need to modify and reference.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "5bffaf6a-eedc-40cd-ab6f-3f444b2ed223",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vy5BB78V9qiwN9yEF6hPyz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12056,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12056
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

<details open><summary>🔧 Tool call — Read · `toolu_01NcvCtxMSbUQFgoCkrjEVj5`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "c9f3bd5c-c8a7-4640-abc4-2c1ffafb9f9c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vy5BB78V9qiwN9yEF6hPyz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12056,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12056
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

_source line 6 · 2026-05-15T10:20:08.419Z_

<details><summary>↩ Tool result · `toolu_01NcvCtxMSbUQFgoCkrjEVj5`</summary>

```text
1	# 2. Related Work
2	
3	## 2.1 Dense Retrieval for Code
4	
5	Code retrieval has evolved from sparse lexical methods such as BM25 \cite{robertson2009bm25} to dense neural approaches. Early pretrained code models---CodeBERT \cite{feng2020codebert}, UniXcoder \cite{guo2022unixcoder}, and InferCode \cite{bui2021infercode}---learn general-purpose code representations through masked language modeling and related pretraining objectives, enabling semantic matching beyond surface-level token overlap. More recent large-scale code models, including StarCoder2 \cite{lozhkov2024starcoder2} and Qwen2.5-Coder \cite{hui2024qwen25coder}, provide powerful encoder backbones trained on trillions of code tokens. In the retrieval domain, CodeSage \cite{zhang2024codesage} and SCodeR \cite{li2022scoder} introduce contrastive fine-tuning strategies that adapt pretrained representations for code search. The growing importance of repository-level retrieval---driven by benchmarks like SWE-bench \cite{jimenez2024swebench}---has motivated specialized systems: SweRank \cite{reddy2025swerank} formulates issue localization as code ranking, while SWE-Fixer \cite{xie2025swefixer} combines BM25 with neural reranking in a coarse-to-fine pipeline. StructFuse builds on this foundation by improving the contrastive fine-tuning stage: rather than modifying the retrieval architecture, we enhance the training signal through structure-grounded negative selection.
6	
7	## 2.2 Contrastive Learning for Code
8	
9	Contrastive learning has become a dominant paradigm for code representation learning. ContraCode \cite{jain2021contracode} generates functionally equivalent program variants through compiler transformations, training models to be invariant to syntactic variation. CodeRetriever \cite{li2022coderetriever} combines unimodal code-code and bimodal code-text contrastive objectives, achieving strong results across eleven code search benchmarks. SynCoBERT \cite{wang2021syncobert} introduces syntax-guided multi-modal contrastive pretraining that aligns code, natural language, and AST modalities through identifier prediction and edge prediction objectives. ContraBERT \cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. GraphCodeBERT \cite{guo2021graphcodebert} incorporates data-flow edges into pretraining, demonstrating that structural information improves code understanding tasks. These methods enrich the positive pair construction space or the pretraining signal. While GraphCodeBERT uses structural edges as a pretraining objective, StructFuse addresses a complementary dimension: rather than improving how positive pairs are constructed, we improve which negatives the model trains against by grounding selection in inter-procedural data-flow structure.
10	
11	## 2.3 Hard Negative Mining
12	
13	The quality of negative examples critically affects contrastive learning \cite{chen2020simclr}. In dense text retrieval, DPR \cite{karpukhin2020dpr} established the practice of using BM25 top-ranked non-relevant passages as hard negatives. ANCE \cite{xiong2021ance} dynamically mines negatives from an approximate nearest neighbor index updated during training, while RocketQA \cite{qu2021rocketqa} introduces cross-batch denoised negatives with knowledge distillation. STAR \cite{zhan2021star} further refines this paradigm by using the retriever's own top-ranked passages as training negatives. Curriculum-based approaches---CL-DRD \cite{zeng2022cldrd} and CAPSTONE \cite{he2023capstone}---schedule negative difficulty progressively during training.
14	
15	In the code domain, CoCoHaNeRe \cite{fan2025cocohanere} proposes gradient-based hard negative mining for code search and reports that BM25-selected negatives can be detrimental to contrastive training. More broadly, CoCoHaNeRe evaluates several non-gradient strategies---including both BM25 and embedding-based retrieval---and finds limitations in each, motivating their differentiable approach. StructFuse takes a different approach: we use static embedding-distance mining as a strong baseline and introduce data-flow structure as an orthogonal signal for negative selection, requiring no gradient computation or dynamic index updates.
16	
17	## 2.4 Code Structure in Machine Learning
18	
19	Program dependence graphs \cite{ferrante1987pdg} and code property graphs \cite{yamaguchi2014cpg} have long served program analysis; tools like CodeQL \cite{avgustinov2016ql} make inter-procedural analysis accessible at scale. In machine learning, code2vec \cite{alon2019code2vec} pioneered learning from AST paths, while ProGraML \cite{cummins2021programl} demonstrated that whole-program graph representations capturing control-flow, data-flow, and call relations are learnable and effective for compiler optimization tasks. CrossCodeEval \cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements.
20	
21	Recent inference-time graph methods bring structural reasoning to LLM-based software engineering. CodexGraph \cite{liu2025codexgraph} and RepoGraph \cite{ouyang2025repograph} build navigable code graph databases for LLM agents; LocAgent \cite{chen2025locagent} and RANGER \cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder \cite{liu2024graphcoder} and ARISE \cite{seddik2026arise} incorporate data-flow edges---control/data dependence and definition-use chains, respectively---but their data-flow analysis remains intra-procedural in scope. Critically, these methods primarily leverage structural graphs at inference time, incurring per-query latency proportional to graph complexity. StructFuse takes a fundamentally different approach: we leverage inter-procedural data-flow graphs at \emph{training time} to mine structure-grounded negatives, producing an encoder that internalizes cross-function data-flow semantics with zero inference overhead. The two paradigms are complementary---a StructFuse-trained encoder can serve as an efficient first-stage retriever for inference-time graph systems that perform targeted reranking.
22	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "76d1bf13-85fe-4aad-9fbb-b491fd6f702c",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md",
      "content": "# 2. Related Work\n\n## 2.1 Dense Retrieval for Code\n\nCode retrieval has evolved from sparse lexical methods such as BM25 \\cite{robertson2009bm25} to dense neural approaches. Early pretrained code models---CodeBERT \\cite{feng2020codebert}, UniXcoder \\cite{guo2022unixcoder}, and InferCode \\cite{bui2021infercode}---learn general-purpose code representations through masked language modeling and related pretraining objectives, enabling semantic matching beyond surface-level token overlap. More recent large-scale code models, including StarCoder2 \\cite{lozhkov2024starcoder2} and Qwen2.5-Coder \\cite{hui2024qwen25coder}, provide powerful encoder backbones trained on trillions of code tokens. In the retrieval domain, CodeSage \\cite{zhang2024codesage} and SCodeR \\cite{li2022scoder} introduce contrastive fine-tuning strategies that adapt pretrained representations for code search. The growing importance of repository-level retrieval---driven by benchmarks like SWE-bench \\cite{jimenez2024swebench}---has motivated specialized systems: SweRank \\cite{reddy2025swerank} formulates issue localization as code ranking, while SWE-Fixer \\cite{xie2025swefixer} combines BM25 with neural reranking in a coarse-to-fine pipeline. StructFuse builds on this foundation by improving the contrastive fine-tuning stage: rather than modifying the retrieval architecture, we enhance the training signal through structure-grounded negative selection.\n\n## 2.2 Contrastive Learning for Code\n\nContrastive learning has become a dominant paradigm for code representation learning. ContraCode \\cite{jain2021contracode} generates functionally equivalent program variants through compiler transformations, training models to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal code-code and bimodal code-text contrastive objectives, achieving strong results across eleven code search benchmarks. SynCoBERT \\cite{wang2021syncobert} introduces syntax-guided multi-modal contrastive pretraining that aligns code, natural language, and AST modalities through identifier prediction and edge prediction objectives. ContraBERT \\cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. GraphCodeBERT \\cite{guo2021graphcodebert} incorporates data-flow edges into pretraining, demonstrating that structural information improves code understanding tasks. These methods enrich the positive pair construction space or the pretraining signal. While GraphCodeBERT uses structural edges as a pretraining objective, StructFuse addresses a complementary dimension: rather than improving how positive pairs are constructed, we improve which negatives the model trains against by grounding selection in inter-procedural data-flow structure.\n\n## 2.3 Hard Negative Mining\n\nThe quality of negative examples critically affects contrastive learning \\cite{chen2020simclr}. In dense text retrieval, DPR \\cite{karpukhin2020dpr} established the practice of using BM25 top-ranked non-relevant passages as hard negatives. ANCE \\cite{xiong2021ance} dynamically mines negatives from an approximate nearest neighbor index updated during training, while RocketQA \\cite{qu2021rocketqa} introduces cross-batch denoised negatives with knowledge distillation. STAR \\cite{zhan2021star} further refines this paradigm by using the retriever's own top-ranked passages as training negatives. Curriculum-based approaches---CL-DRD \\cite{zeng2022cldrd} and CAPSTONE \\cite{he2023capstone}---schedule negative difficulty progressively during training.\n\nIn the code domain, CoCoHaNeRe \\cite{fan2025cocohanere} proposes gradient-based hard negative mining for code search and reports that BM25-selected negatives can be detrimental to contrastive training. More broadly, CoCoHaNeRe evaluates several non-gradient strategies---including both BM25 and embedding-based retrieval---and finds limitations in each, motivating their differentiable approach. StructFuse takes a different approach: we use static embedding-distance mining as a strong baseline and introduce data-flow structure as an orthogonal signal for negative selection, requiring no gradient computation or dynamic index updates.\n\n## 2.4 Code Structure in Machine Learning\n\nProgram dependence graphs \\cite{ferrante1987pdg} and code property graphs \\cite{yamaguchi2014cpg} have long served program analysis; tools like CodeQL \\cite{avgustinov2016ql} make inter-procedural analysis accessible at scale. In machine learning, code2vec \\cite{alon2019code2vec} pioneered learning from AST paths, while ProGraML \\cite{cummins2021programl} demonstrated that whole-program graph representations capturing control-flow, data-flow, and call relations are learnable and effective for compiler optimization tasks. CrossCodeEval \\cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements.\n\nRecent inference-time graph methods bring structural reasoning to LLM-based software engineering. CodexGraph \\cite{liu2025codexgraph} and RepoGraph \\cite{ouyang2025repograph} build navigable code graph databases for LLM agents; LocAgent \\cite{chen2025locagent} and RANGER \\cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder \\cite{liu2024graphcoder} and ARISE \\cite{seddik2026arise} incorporate data-flow edges---control/data dependence and definition-use chains, respectively---but their data-flow analysis remains intra-procedural in scope. Critically, these methods primarily leverage structural graphs at inference time, incurring per-query latency proportional to graph complexity. StructFuse takes a fundamentally different approach: we leverage inter-procedural data-flow graphs at \\emph{training time} to mine structure-grounded negatives, producing an encoder that internalizes cross-function data-flow semantics with zero inference overhead. The two paradigms are complementary---a StructFuse-trained encoder can serve as an efficient first-stage retriever for inference-time graph systems that perform targeted reranking.\n",
      "numLines": 22,
      "startLine": 1,
      "totalLines": 22
    }
  }
}
```

</details>

---

### Tool call

_source line 7_

<details open><summary>🔧 Tool call — Read · `toolu_017kR3Tq8SM37Ad3KMZvvaxx`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "38e1b5c4-fe57-4a60-bf83-f39bafac4b11",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vy5BB78V9qiwN9yEF6hPyz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12056,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12056
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

_source line 8 · 2026-05-15T10:20:08.906Z_

<details><summary>↩ Tool result · `toolu_017kR3Tq8SM37Ad3KMZvvaxx`</summary>

```text
1	% =============================================================================
2	% Section 1: Introduction
3	% =============================================================================
4	
5	@inproceedings{jimenez2024swebench,
6	  title={{SWE-bench}: Can Language Models Resolve Real-World {GitHub} Issues?},
7	  author={Jimenez, Carlos E. and Yang, John and Wettig, Alexander and Yao, Shunyu and Pei, Kexin and Press, Ofir and Narasimhan, Karthik},
8	  booktitle={Proceedings of the Twelfth International Conference on Learning Representations (ICLR)},
9	  year={2024}
10	}
11	
12	% =============================================================================
13	% Section 2.1: Code Retrieval Methods
14	% =============================================================================
15	
16	@article{robertson2009bm25,
17	  title={The Probabilistic Relevance Framework: {BM25} and Beyond},
18	  author={Robertson, Stephen and Zaragoza, Hugo},
19	  journal={Foundations and Trends in Information Retrieval},
20	  volume={3},
21	  number={4},
22	  pages={333--389},
23	  year={2009},
24	  publisher={Now Publishers}
25	}
26	
27	@inproceedings{karpukhin2020dpr,
28	  title={Dense Passage Retrieval for Open-Domain Question Answering},
29	  author={Karpukhin, Vladimir and O{\u{g}}uz, Barlas and Min, Sewon and Lewis, Patrick and Wu, Ledell and Edunov, Sergey and Chen, Danqi and Yih, Wen-tau},
30	  booktitle={Proceedings of the 2020 Conference on Empirical Methods in Natural Language Processing (EMNLP)},
31	  pages={6769--6781},
32	  year={2020}
33	}
34	
35	@article{reddy2025swerank,
36	  title={{SweRank}: Software Issue Localization with Code Ranking},
37	  author={Gangi Reddy, Revanth and Suresh, Tarun and Doo, JaeHyeok and Liu, Ye and Nguyen, Xuan Phi and Zhou, Yingbo and Yavuz, Semih and Xiong, Caiming and Ji, Heng and Joty, Shafiq},
38	  journal={arXiv preprint arXiv:2505.07849},
39	  year={2025}
40	}
41	
42	@inproceedings{xie2025swefixer,
43	  title={{SWE-Fixer}: Training Open-Source {LLM}s for Effective and Efficient {GitHub} Issue Resolution},
44	  author={Xie, Chengxing and Li, Bowen and Gao, Chang and Du, He and Lam, Wai and Zou, Difan and Chen, Kai},
45	  booktitle={Findings of the Association for Computational Linguistics: ACL 2025},
46	  pages={1123--1139},
47	  year={2025}
48	}
49	
50	@inproceedings{chen2025locagent,
51	  title={{LocAgent}: Graph-Guided {LLM} Agents for Code Localization},
52	  author={Chen, Zhaoling and Tang, Robert and Deng, Gangda and Wu, Fang and Wu, Jialong and Jiang, Zhiwei and Prasanna, Viktor and Cohan, Arman and Wang, Xingyao},
53	  booktitle={Proceedings of the 63rd Annual Meeting of the Association for Computational Linguistics (ACL)},
54	  pages={8697--8727},
55	  year={2025}
56	}
57	
58	@article{shah2025ranger,
59	  title={{RANGER}: Repository-Level Agent for Graph-Enhanced Retrieval},
60	  author={Shah, Pratik and Ghosh, Rajat and Singhal, Aryan and Dutta, Debojyoti},
61	  journal={arXiv preprint arXiv:2509.25257},
62	  year={2025}
63	}
64	
65	@inproceedings{liu2025codexgraph,
66	  title={{CodexGraph}: Bridging Large Language Models and Code Repositories via Code Graph Databases},
67	  author={Liu, Xiangyan and Lan, Bo and Hu, Zhiyuan and Liu, Yang and Zhang, Zhicheng and Wang, Fei and Shieh, Michael Qizhe and Zhou, Wenmeng},
68	  booktitle={Proceedings of the 2025 Conference of the North American Chapter of the Association for Computational Linguistics (NAACL)},
69	  pages={142--160},
70	  year={2025}
71	}
72	
73	@inproceedings{ouyang2025repograph,
74	  title={{RepoGraph}: Enhancing {AI} Software Engineering with Repository-level Code Graph},
75	  author={Ouyang, Siru and Yu, Wenhao and Ma, Kaixin and Xiao, Zilin and Zhang, Zhihan and Jia, Mengzhao and Han, Jiawei and Zhang, Hongming and Yu, Dong},
76	  booktitle={Proceedings of the Thirteenth International Conference on Learning Representations (ICLR)},
77	  year={2025}
78	}
79	
80	@inproceedings{liu2024graphcoder,
81	  title={{GraphCoder}: Enhancing Repository-Level Code Completion via Code Context Graph-based Retrieval and Language Model},
82	  author={Liu, Wei and Hu, Ailun and Li, Yixuan and Li, Yichen and Liu, Haoyu and Yang, Leyi},
83	  booktitle={Proceedings of the 39th IEEE/ACM International Conference on Automated Software Engineering (ASE)},
84	  year={2024}
85	}
86	
87	@article{seddik2026arise,
88	  title={{ARISE}: A Repository-level Graph Representation and Toolset for Agentic Fault Localization and Program Repair},
89	  author={Seddik, Shahd and Fard, Fatemeh},
90	  journal={arXiv preprint arXiv:2605.03117},
91	  year={2026}
92	}
93	
94	% =============================================================================
95	% Section 2.2: Pre-trained Code Representations and Contrastive Learning
96	% =============================================================================
97	
98	@inproceedings{feng2020codebert,
99	  title={{CodeBERT}: A Pre-Trained Model for Programming and Natural Languages},
100	  author={Feng, Zhangyin and Guo, Daya and Tang, Duyu and Duan, Nan and Feng, Xiaocheng and Gong, Ming and Shou, Linjun and Qin, Bing and Liu, Ting and Jiang, Daxin and Zhou, Ming},
101	  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2020},
102	  pages={1536--1547},
103	  year={2020}
104	}
105	
106	@inproceedings{guo2021graphcodebert,
107	  title={{GraphCodeBERT}: Pre-training Code Representations with Data Flow},
108	  author={Guo, Daya and Ren, Shuo and Lu, Shuai and Feng, Zhangyin and Tang, Duyu and Liu, Shujie and Zhou, Long and Duan, Nan and Svyatkovskiy, Alexey and Fu, Shengyu and Tufano, Michele and Deng, Shuai Kim and Clement, Colin and Drain, Dawn and Sundaresan, Neel and Yin, Jian and Jiang, Daxin and Zhou, Ming},
109	  booktitle={Proceedings of the Ninth International Conference on Learning Representations (ICLR)},
110	  year={2021}
111	}
112	
113	@inproceedings{guo2022unixcoder,
114	  title={{UniXcoder}: Unified Cross-Modal Pre-training for Code Representation},
115	  author={Guo, Daya and Lu, Shuai and Duan, Nan and Wang, Yanlin and Zhou, Ming and Yin, Jian},
116	  booktitle={Proceedings of the 60th Annual Meeting of the Association for Computational Linguistics (ACL)},
117	  pages={7212--7225},
118	  year={2022}
119	}
120	
121	@inproceedings{alon2019code2vec,
122	  title={code2vec: Learning Distributed Representations of Code},
123	  author={Alon, Uri and Zilberstein, Meital and Levy, Omer and Yahav, Eran},
124	  booktitle={Proceedings of the ACM on Programming Languages (POPL)},
125	  volume={3},
126	  pages={1--29},
127	  year={2019}
128	}
129	
130	@inproceedings{zhang2024codesage,
131	  title={Code Representation Learning At Scale},
132	  author={Zhang, Dejiao and Ahmad, Wasi Uddin and Tan, Ming and Ding, Hantian and Nallapati, Ramesh and Roth, Dan and Ma, Xiaofei and Xiang, Bing},
133	  booktitle={Proceedings of the Twelfth International Conference on Learning Representations (ICLR)},
134	  year={2024}
135	}
136	
137	@inproceedings{reimers2019sentencebert,
138	  title={Sentence-{BERT}: Sentence Embeddings using Siamese {BERT}-Networks},
139	  author={Reimers, Nils and Gurevych, Iryna},
140	  booktitle={Proceedings of the 2019 Conference on Empirical Methods in Natural Language Processing (EMNLP)},
141	  pages={3982--3992},
142	  year={2019}
143	}
144	
145	@inproceedings{jain2021contracode,
146	  title={Contrastive Code Representation Learning},
147	  author={Jain, Paras and Jain, Ajil and Zhang, Tianjun and Abbeel, Pieter and Gonzalez, Joseph and Stoica, Ion},
148	  booktitle={Proceedings of the 2021 Conference on Empirical Methods in Natural Language Processing (EMNLP)},
149	  pages={5954--5971},
150	  year={2021}
151	}
152	
153	@inproceedings{li2022coderetriever,
154	  title={{CodeRetriever}: A Large Scale Contrastive Pre-Training Method for Code Search},
155	  author={Li, Xiaonan and Gong, Yeyun and Shen, Yelong and Qiu, Xipeng and Zhang, Hang and Yao, Bolun and Qi, Weizhen and Jiang, Daxin and Chen, Weizhu and Duan, Nan},
156	  booktitle={Proceedings of the 2022 Conference on Empirical Methods in Natural Language Processing (EMNLP)},
157	  pages={2898--2910},
158	  year={2022}
159	}
160	
161	@inproceedings{li2022scoder,
162	  title={Soft-Labeled Contrastive Pre-training for Function-level Code Representation},
163	  author={Li, Xiaonan and Guo, Daya and Gong, Yeyun and Lin, Yun and Shen, Yelong and Qiu, Xipeng and Jiang, Daxin and Chen, Weizhu and Duan, Nan},
164	  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2022},
165	  year={2022}
166	}
167	
168	@inproceedings{ding2022programcontrasts,
169	  title={Towards Learning (Dis)-Similarity of Source Code from Program Contrasts},
170	  author={Ding, Yangruibo and Buratti, Luca and Pujar, Saurabh and Morari, Alessandro and Ray, Baishakhi and Parthasarathy, Saikat},
171	  booktitle={Proceedings of the 60th Annual Meeting of the Association for Computational Linguistics (ACL)},
172	  pages={6300--6312},
173	  year={2022}
174	}
175	
176	@inproceedings{bui2021infercode,
177	  title={{InferCode}: Self-Supervised Learning of Code Representations by Predicting Subtrees},
178	  author={Bui, Nghi D. Q. and Yu, Yijun and Jiang, Lingxiao},
179	  booktitle={Proceedings of the 43rd IEEE/ACM International Conference on Software Engineering (ICSE)},
180	  pages={1186--1197},
181	  year={2021}
182	}
183	
184	@article{lozhkov2024starcoder2,
185	  title={{StarCoder} 2 and {The Stack} v2: The Next Generation},
186	  author={Lozhkov, Anton and Li, Raymond and Ben Allal, Loubna and Cassano, Federico and Lamy-Poirier, Joel and Tazi, Nouamane and Tang, Ao and Pykhtar, Dmytro and Liu, Jiawei and Wei, Yuxiang and others},
187	  journal={arXiv preprint arXiv:2402.19173},
188	  year={2024}
189	}
190	
191	@article{hui2024qwen25coder,
192	  title={{Qwen2.5-Coder} Technical Report},
193	  author={Hui, Binyuan and Yang, Jian and Cui, Zeyu and Yang, Jiaxi and Liu, Dayiheng and Zhang, Lei and Liu, Tianyu and Zhang, Jiajun and Yu, Bowen and Lu, Keming and Dang, Kai and Fan, Yang and Zhang, Yichang and Yang, An and Men, Rui and Huang, Fei and Zheng, Bo and others},
194	  journal={arXiv preprint arXiv:2409.12186},
195	  year={2024}
196	}
197	
198	% =============================================================================
199	% Section 2.3: Hard Negative Mining
200	% =============================================================================
201	
202	@inproceedings{chen2020simclr,
203	  title={A Simple Framework for Contrastive Learning of Visual Representations},
204	  author={Chen, Ting and Kornblith, Simon and Norouzi, Mohammad and Hinton, Geoffrey},
205	  booktitle={Proceedings of the 37th International Conference on Machine Learning (ICML)},
206	  pages={1597--1607},
207	  year={2020}
208	}
209	
210	@inproceedings{xiong2021ance,
211	  title={Approximate Nearest Neighbor Negative Contrastive Learning for Dense Text Retrieval},
212	  author={Xiong, Lee and Xiong, Chenyan and Li, Ye and Tang, Kwok-Fung and Liu, Jialin and Bennett, Paul and Ahmed, Junaid and Overwijk, Arnold},
213	  booktitle={Proceedings of the Ninth International Conference on Learning Representations (ICLR)},
214	  year={2021}
215	}
216	
217	@inproceedings{zhan2021star,
218	  title={Optimizing Dense Retrieval Model Training with Hard Negatives},
219	  author={Zhan, Jingtao and Mao, Jiaxin and Liu, Yiqun and Guo, Jiafeng and Zhang, Min and Ma, Shaoping},
220	  booktitle={Proceedings of the 44th International ACM SIGIR Conference on Research and Development in Information Retrieval},
221	  pages={1503--1512},
222	  year={2021}
223	}
224	
225	@inproceedings{qu2021rocketqa,
226	  title={{RocketQA}: An Optimized Training Approach to Dense Passage Retrieval for Open-Domain Question Answering},
227	  author={Qu, Yingqi and Ding, Yuchen and Liu, Jing and Liu, Kai and Ren, Ruiyang and Zhao, Wayne Xin and Dong, Daxiang and Wu, Hua and Wang, Haifeng},
228	  booktitle={Proceedings of the 2021 Conference of the North American Chapter of the Association for Computational Linguistics (NAACL-HLT)},
229	  pages={5835--5847},
230	  year={2021}
231	}
232	
233	@inproceedings{zeng2022cldrd,
234	  title={Curriculum Learning for Dense Retrieval Distillation},
235	  author={Zeng, Hansi and Zamani, Hamed and Vinay, Vishwa},
236	  booktitle={Proceedings of the 45th International ACM SIGIR Conference on Research and Development in Information Retrieval},
237	  pages={1979--1983},
238	  year={2022}
239	}
240	
241	@article{fan2025cocohanere,
242	  title={Effective Hard Negative Mining for Contrastive Learning-Based Code Search},
243	  author={Fan, Ye and Li, Chuanyi and Ge, Jidong and Huang, LiGuo and Luo, Bin},
244	  journal={ACM Transactions on Software Engineering and Methodology},
245	  volume={34},
246	  number={3},
247	  year={2025},
248	  publisher={ACM}
249	}
250	
251	% =============================================================================
252	% Section 2.4: Code Structure Analysis
253	% =============================================================================
254	
255	@article{ferrante1987pdg,
256	  title={The Program Dependence Graph and Its Use in Optimization},
257	  author={Ferrante, Jeanne and Ottenstein, Karl J. and Warren, Joe D.},
258	  journal={ACM Transactions on Programming Languages and Systems},
259	  volume={9},
260	  number={3},
261	  pages={319--349},
262	  year={1987},
263	  publisher={ACM}
264	}
265	
266	@inproceedings{yamaguchi2014cpg,
267	  title={Modeling and Discovering Vulnerabilities with Code Property Graphs},
268	  author={Yamaguchi, Fabian and Golde, Nico and Arp, Daniel and Rieck, Konrad},
269	  booktitle={Proceedings of the 2014 IEEE Symposium on Security and Privacy (S\&P)},
270	  pages={590--604},
271	  year={2014},
272	  publisher={IEEE}
273	}
274	
275	@inproceedings{avgustinov2016ql,
276	  title={{QL}: Object-oriented Queries on Relational Data},
277	  author={Avgustinov, Pavel and de Moor, Oege and Jones, Michael Peyton and Sch{\"a}fer, Max},
278	  booktitle={30th European Conference on Object-Oriented Programming (ECOOP)},
279	  series={LIPIcs},
280	  volume={56},
281	  pages={2:1--2:25},
282	  year={2016}
283	}
284	
285	% =============================================================================
286	% Section 3: Method
287	% =============================================================================
288	
289	@inproceedings{hu2022lora,
290	  title={{LoRA}: Low-Rank Adaptation of Large Language Models},
291	  author={Hu, Edward J. and Shen, Yelong and Wallis, Phillip and Allen-Zhu, Zeyuan and Li, Yuanzhi and Wang, Shean and Wang, Lu and Chen, Weizhu},
292	  booktitle={Proceedings of the Tenth International Conference on Learning Representations (ICLR)},
293	  year={2022}
294	}
295	
296	@article{oord2018representation,
297	  title={Representation Learning with Contrastive Predictive Coding},
298	  author={van den Oord, A{\"a}ron and Li, Yazhe and Vinyals, Oriol},
299	  journal={arXiv preprint arXiv:1807.03748},
300	  year={2018}
301	}
302	
303	% =============================================================================
304	% Supplement: New citations added 2026-05-15
305	% =============================================================================
306	
307	@article{wang2021syncobert,
308	  title={{SynCoBERT}: Syntax-Guided Multi-Modal Contrastive Pre-Training for Code Representation},
309	  author={Wang, Xin and Wang, Yasheng and Mi, Fei and Zhou, Pingyi and Wan, Yao and Liu, Xiao and Li, Li and Wu, Hao and Liu, Jin and Jiang, Xin},
310	  journal={arXiv preprint arXiv:2108.04556},
311	  year={2021}
312	}
313	
314	@inproceedings{liu2023contrabert,
315	  title={{ContraBERT}: Enhancing Code Pre-trained Models via Contrastive Learning},
316	  author={Liu, Shangqing and Wu, Bozhi and Xie, Xiaofei and Meng, Guozhu and Liu, Yang},
317	  booktitle={Proceedings of the 45th IEEE/ACM International Conference on Software Engineering (ICSE)},
318	  pages={2476--2487},
319	  year={2023}
320	}
321	
322	@inproceedings{he2023capstone,
323	  title={{CAPSTONE}: Curriculum Sampling for Dense Retrieval with Document Expansion},
324	  author={He, Xingwei and Gong, Yeyun and Jin, A-Long and Zhang, Hang and Dong, Anlei and Jiao, Jian and Yiu, Siu Ming and Duan, Nan},
325	  booktitle={Proceedings of the 2023 Conference on Empirical Methods in Natural Language Processing (EMNLP)},
326	  pages={10531--10541},
327	  year={2023}
328	}
329	
330	@inproceedings{ding2023crosscodeeval,
331	  title={{CrossCodeEval}: A Diverse and Multilingual Benchmark for Cross-File Code Completion},
332	  author={Ding, Yangruibo and Wang, Zijian and Ahmad, Wasi Uddin and Ding, Hantian and Tan, Ming and Jain, Nihal and Ramanathan, Murali Krishna and Nallapati, Ramesh and Bhatia, Parminder and Roth, Dan and Xiang, Bing},
333	  booktitle={Advances in Neural Information Processing Systems 36 (NeurIPS)},
334	  year={2023}
335	}
336	
337	@inproceedings{cummins2021programl,
338	  title={{ProGraML}: A Graph-based Program Representation for Data Flow Analysis and Compiler Optimizations},
339	  author={Cummins, Chris and Fisches, Zacharias V. and Ben-Nun, Tal and Hoefler, Torsten and O'Boyle, Michael F. P. and Leather, Hugh},
340	  booktitle={Proceedings of the 38th International Conference on Machine Learning (ICML)},
341	  pages={2244--2253},
342	  year={2021},
343	  publisher={PMLR}
344	}
345	
346	@inproceedings{huang2021cosqa,
347	  title={{CoSQA}: 20,000+ Web Queries for Code Search and Question Answering},
348	  author={Huang, Junjie and Tang, Duyu and Shou, Linjun and Gong, Ming and Xu, Ke and Jiang, Daxin and Zhou, Ming and Duan, Nan},
349	  booktitle={Proceedings of the 59th Annual Meeting of the Association for Computational Linguistics (ACL)},
350	  pages={5690--5700},
351	  year={2021}
352	}
353	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "68f0e0b9-1ebf-4527-bcde-648e4078cdf3",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/references.bib",
      "content": "% =============================================================================\n% Section 1: Introduction\n% =============================================================================\n\n@inproceedings{jimenez2024swebench,\n  title={{SWE-bench}: Can Language Models Resolve Real-World {GitHub} Issues?},\n  author={Jimenez, Carlos E. and Yang, John and Wettig, Alexander and Yao, Shunyu and Pei, Kexin and Press, Ofir and Narasimhan, Karthik},\n  booktitle={Proceedings of the Twelfth International Conference on Learning Representations (ICLR)},\n  year={2024}\n}\n\n% =============================================================================\n% Section 2.1: Code Retrieval Methods\n% =============================================================================\n\n@article{robertson2009bm25,\n  title={The Probabilistic Relevance Framework: {BM25} and Beyond},\n  author={Robertson, Stephen and Zaragoza, Hugo},\n  journal={Foundations and Trends in Information Retrieval},\n  volume={3},\n  number={4},\n  pages={333--389},\n  year={2009},\n  publisher={Now Publishers}\n}\n\n@inproceedings{karpukhin2020dpr,\n  title={Dense Passage Retrieval for Open-Domain Question Answering},\n  author={Karpukhin, Vladimir and O{\\u{g}}uz, Barlas and Min, Sewon and Lewis, Patrick and Wu, Ledell and Edunov, Sergey and Chen, Danqi and Yih, Wen-tau},\n  booktitle={Proceedings of the 2020 Conference on Empirical Methods in Natural Language Processing (EMNLP)},\n  pages={6769--6781},\n  year={2020}\n}\n\n@article{reddy2025swerank,\n  title={{SweRank}: Software Issue Localization with Code Ranking},\n  author={Gangi Reddy, Revanth and Suresh, Tarun and Doo, JaeHyeok and Liu, Ye and Nguyen, Xuan Phi and Zhou, Yingbo and Yavuz, Semih and Xiong, Caiming and Ji, Heng and Joty, Shafiq},\n  journal={arXiv preprint arXiv:2505.07849},\n  year={2025}\n}\n\n@inproceedings{xie2025swefixer,\n  title={{SWE-Fixer}: Training Open-Source {LLM}s for Effective and Efficient {GitHub} Issue Resolution},\n  author={Xie, Chengxing and Li, Bowen and Gao, Chang and Du, He and Lam, Wai and Zou, Difan and Chen, Kai},\n  booktitle={Findings of the Association for Computational Linguistics: ACL 2025},\n  pages={1123--1139},\n  year={2025}\n}\n\n@inproceedings{chen2025locagent,\n  title={{LocAgent}: Graph-Guided {LLM} Agents for Code Localization},\n  author={Chen, Zhaoling and Tang, Robert and Deng, Gangda and Wu, Fang and Wu, Jialong and Jiang, Zhiwei and Prasanna, Viktor and Cohan, Arman and Wang, Xingyao},\n  booktitle={Proceedings of the 63rd Annual Meeting of the Association for Computational Linguistics (ACL)},\n  pages={8697--8727},\n  year={2025}\n}\n\n@article{shah2025ranger,\n  title={{RANGER}: Repository-Level Agent for Graph-Enhanced Retrieval},\n  author={Shah, Pratik and Ghosh, Rajat and Singhal, Aryan and Dutta, Debojyoti},\n  journal={arXiv preprint arXiv:2509.25257},\n  year={2025}\n}\n\n@inproceedings{liu2025codexgraph,\n  title={{CodexGraph}: Bridging Large Language Models and Code Repositories via Code Graph Databases},\n  author={Liu, Xiangyan and Lan, Bo and Hu, Zhiyuan and Liu, Yang and Zhang, Zhicheng and Wang, Fei and Shieh, Michael Qizhe and Zhou, Wenmeng},\n  booktitle={Proceedings of the 2025 Conference of the North American Chapter of the Association for Computational Linguistics (NAACL)},\n  pages={142--160},\n  year={2025}\n}\n\n@inproceedings{ouyang2025repograph,\n  title={{RepoGraph}: Enhancing {AI} Software Engineering with Repository-level Code Graph},\n  author={Ouyang, Siru and Yu, Wenhao and Ma, Kaixin and Xiao, Zilin and Zhang, Zhihan and Jia, Mengzhao and Han, Jiawei and Zhang, Hongming and Yu, Dong},\n  booktitle={Proceedings of the Thirteenth International Conference on Learning Representations (ICLR)},\n  year={2025}\n}\n\n@inproceedings{liu2024graphcoder,\n  title={{GraphCoder}: Enhancing Repository-Level Code Completion via Code Context Graph-based Retrieval and Language Model},\n  author={Liu, Wei and Hu, Ailun and Li, Yixuan and Li, Yichen and Liu, Haoyu and Yang, Leyi},\n  booktitle={Proceedings of the 39th IEEE/ACM International Conference on Automated Software Engineering (ASE)},\n  year={2024}\n}\n\n@article{seddik2026arise,\n  title={{ARISE}: A Repository-level Graph Representation and Toolset for Agentic Fault Localization and Program Repair},\n  author={Seddik, Shahd and Fard, Fatemeh},\n  journal={arXiv preprint arXiv:2605.03117},\n  year={2026}\n}\n\n% =============================================================================\n% Section 2.2: Pre-trained Code Representations and Contrastive Learning\n% =============================================================================\n\n@inproceedings{feng2020codebert,\n  title={{CodeBERT}: A Pre-Trained Model for Programming and Natural Languages},\n  author={Feng, Zhangyin and Guo, Daya and Tang, Duyu and Duan, Nan and Feng, Xiaocheng and Gong, Ming and Shou, Linjun and Qin, Bing and Liu, Ting and Jiang, Daxin and Zhou, Ming},\n  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2020},\n  pages={1536--1547},\n  year={2020}\n}\n\n@inproceedings{guo2021graphcodebert,\n  title={{GraphCodeBERT}: Pre-training Code Representations with Data Flow},\n  author={Guo, Daya and Ren, Shuo and Lu, Shuai and Feng, Zhangyin and Tang, Duyu and Liu, Shujie and Zhou, Long and Duan, Nan and Svyatkovskiy, Alexey and Fu, Shengyu and Tufano, Michele and Deng, Shuai Kim and Clement, Colin and Drain, Dawn and Sundaresan, Neel and Yin, Jian and Jiang, Daxin and Zhou, Ming},\n  booktitle={Proceedings of the Ninth International Conference on Learning Representations (ICLR)},\n  year={2021}\n}\n\n@inproceedings{guo2022unixcoder,\n  title={{UniXcoder}: Unified Cross-Modal Pre-training for Code Representation},\n  author={Guo, Daya and Lu, Shuai and Duan, Nan and Wang, Yanlin and Zhou, Ming and Yin, Jian},\n  booktitle={Proceedings of the 60th Annual Meeting of the Association for Computational Linguistics (ACL)},\n  pages={7212--7225},\n  year={2022}\n}\n\n@inproceedings{alon2019code2vec,\n  title={code2vec: Learning Distributed Representations of Code},\n  author={Alon, Uri and Zilberstein, Meital and Levy, Omer and Yahav, Eran},\n  booktitle={Proceedings of the ACM on Programming Languages (POPL)},\n  volume={3},\n  pages={1--29},\n  year={2019}\n}\n\n@inproceedings{zhang2024codesage,\n  title={Code Representation Learning At Scale},\n  author={Zhang, Dejiao and Ahmad, Wasi Uddin and Tan, Ming and Ding, Hantian and Nallapati, Ramesh and Roth, Dan and Ma, Xiaofei and Xiang, Bing},\n  booktitle={Proceedings of the Twelfth International Conference on Learning Representations (ICLR)},\n  year={2024}\n}\n\n@inproceedings{reimers2019sentencebert,\n  title={Sentence-{BERT}: Sentence Embeddings using Siamese {BERT}-Networks},\n  author={Reimers, Nils and Gurevych, Iryna},\n  booktitle={Proceedings of the 2019 Conference on Empirical Methods in Natural Language Processing (EMNLP)},\n  pages={3982--3992},\n  year={2019}\n}\n\n@inproceedings{jain2021contracode,\n  title={Contrastive Code Representation Learning},\n  author={Jain, Paras and Jain, Ajil and Zhang, Tianjun and Abbeel, Pieter and Gonzalez, Joseph and Stoica, Ion},\n  booktitle={Proceedings of the 2021 Conference on Empirical Methods in Natural Language Processing (EMNLP)},\n  pages={5954--5971},\n  year={2021}\n}\n\n@inproceedings{li2022coderetriever,\n  title={{CodeRetriever}: A Large Scale Contrastive Pre-Training Method for Code Search},\n  author={Li, Xiaonan and Gong, Yeyun and Shen, Yelong and Qiu, Xipeng and Zhang, Hang and Yao, Bolun and Qi, Weizhen and Jiang, Daxin and Chen, Weizhu and Duan, Nan},\n  booktitle={Proceedings of the 2022 Conference on Empirical Methods in Natural Language Processing (EMNLP)},\n  pages={2898--2910},\n  year={2022}\n}\n\n@inproceedings{li2022scoder,\n  title={Soft-Labeled Contrastive Pre-training for Function-level Code Representation},\n  author={Li, Xiaonan and Guo, Daya and Gong, Yeyun and Lin, Yun and Shen, Yelong and Qiu, Xipeng and Jiang, Daxin and Chen, Weizhu and Duan, Nan},\n  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2022},\n  year={2022}\n}\n\n@inproceedings{ding2022programcontrasts,\n  title={Towards Learning (Dis)-Similarity of Source Code from Program Contrasts},\n  author={Ding, Yangruibo and Buratti, Luca and Pujar, Saurabh and Morari, Alessandro and Ray, Baishakhi and Parthasarathy, Saikat},\n  booktitle={Proceedings of the 60th Annual Meeting of the Association for Computational Linguistics (ACL)},\n  pages={6300--6312},\n  year={2022}\n}\n\n@inproceedings{bui2021infercode,\n  title={{InferCode}: Self-Supervised Learning of Code Representations by Predicting Subtrees},\n  author={Bui, Nghi D. Q. and Yu, Yijun and Jiang, Lingxiao},\n  booktitle={Proceedings of the 43rd IEEE/ACM International Conference on Software Engineering (ICSE)},\n  pages={1186--1197},\n  year={2021}\n}\n\n@article{lozhkov2024starcoder2,\n  title={{StarCoder} 2 and {The Stack} v2: The Next Generation},\n  author={Lozhkov, Anton and Li, Raymond and Ben Allal, Loubna and Cassano, Federico and Lamy-Poirier, Joel and Tazi, Nouamane and Tang, Ao and Pykhtar, Dmytro and Liu, Jiawei and Wei, Yuxiang and others},\n  journal={arXiv preprint arXiv:2402.19173},\n  year={2024}\n}\n\n@article{hui2024qwen25coder,\n  title={{Qwen2.5-Coder} Technical Report},\n  author={Hui, Binyuan and Yang, Jian and Cui, Zeyu and Yang, Jiaxi and Liu, Dayiheng and Zhang, Lei and Liu, Tianyu and Zhang, Jiajun and Yu, Bowen and Lu, Keming and Dang, Kai and Fan, Yang and Zhang, Yichang and Yang, An and Men, Rui and Huang, Fei and Zheng, Bo and others},\n  journal={arXiv preprint arXiv:2409.12186},\n  year={2024}\n}\n\n% =============================================================================\n% Section 2.3: Hard Negative Mining\n% =============================================================================\n\n@inproceedings{chen2020simclr,\n  title={A Simple Framework for Contrastive Learning of Visual Representations},\n  author={Chen, Ting and Kornblith, Simon and Norouzi, Mohammad and Hinton, Geoffrey},\n  booktitle={Proceedings of the 37th International Conference on Machine Learning (ICML)},\n  pages={1597--1607},\n  year={2020}\n}\n\n@inproceedings{xiong2021ance,\n  title={Approximate Nearest Neighbor Negative Contrastive Learning for Dense Text Retrieval},\n  author={Xiong, Lee and Xiong, Chenyan and Li, Ye and Tang, Kwok-Fung and Liu, Jialin and Bennett, Paul and Ahmed, Junaid and Overwijk, Arnold},\n  booktitle={Proceedings of the Ninth International Conference on Learning Representations (ICLR)},\n  year={2021}\n}\n\n@inproceedings{zhan2021star,\n  title={Optimizing Dense Retrieval Model Training with Hard Negatives},\n  author={Zhan, Jingtao and Mao, Jiaxin and Liu, Yiqun and Guo, Jiafeng and Zhang, Min and Ma, Shaoping},\n  booktitle={Proceedings of the 44th International ACM SIGIR Conference on Research and Development in Information Retrieval},\n  pages={1503--1512},\n  year={2021}\n}\n\n@inproceedings{qu2021rocketqa,\n  title={{RocketQA}: An Optimized Training Approach to Dense Passage Retrieval for Open-Domain Question Answering},\n  author={Qu, Yingqi and Ding, Yuchen and Liu, Jing and Liu, Kai and Ren, Ruiyang and Zhao, Wayne Xin and Dong, Daxiang and Wu, Hua and Wang, Haifeng},\n  booktitle={Proceedings of the 2021 Conference of the North American Chapter of the Association for Computational Linguistics (NAACL-HLT)},\n  pages={5835--5847},\n  year={2021}\n}\n\n@inproceedings{zeng2022cldrd,\n  title={Curriculum Learning for Dense Retrieval Distillation},\n  author={Zeng, Hansi and Zamani, Hamed and Vinay, Vishwa},\n  booktitle={Proceedings of the 45th International ACM SIGIR Conference on Research and Development in Information Retrieval},\n  pages={1979--1983},\n  year={2022}\n}\n\n@article{fan2025cocohanere,\n  title={Effective Hard Negative Mining for Contrastive Learning-Based Code Search},\n  author={Fan, Ye and Li, Chuanyi and Ge, Jidong and Huang, LiGuo and Luo, Bin},\n  journal={ACM Transactions on Software Engineering and Methodology},\n  volume={34},\n  number={3},\n  year={2025},\n  publisher={ACM}\n}\n\n% =============================================================================\n% Section 2.4: Code Structure Analysis\n% =============================================================================\n\n@article{ferrante1987pdg,\n  title={The Program Dependence Graph and Its Use in Optimization},\n  author={Ferrante, Jeanne and Ottenstein, Karl J. and Warren, Joe D.},\n  journal={ACM Transactions on Programming Languages and Systems},\n  volume={9},\n  number={3},\n  pages={319--349},\n  year={1987},\n  publisher={ACM}\n}\n\n@inproceedings{yamaguchi2014cpg,\n  title={Modeling and Discovering Vulnerabilities with Code Property Graphs},\n  author={Yamaguchi, Fabian and Golde, Nico and Arp, Daniel and Rieck, Konrad},\n  booktitle={Proceedings of the 2014 IEEE Symposium on Security and Privacy (S\\&P)},\n  pages={590--604},\n  year={2014},\n  publisher={IEEE}\n}\n\n@inproceedings{avgustinov2016ql,\n  title={{QL}: Object-oriented Queries on Relational Data},\n  author={Avgustinov, Pavel and de Moor, Oege and Jones, Michael Peyton and Sch{\\\"a}fer, Max},\n  booktitle={30th European Conference on Object-Oriented Programming (ECOOP)},\n  series={LIPIcs},\n  volume={56},\n  pages={2:1--2:25},\n  year={2016}\n}\n\n% =============================================================================\n% Section 3: Method\n% =============================================================================\n\n@inproceedings{hu2022lora,\n  title={{LoRA}: Low-Rank Adaptation of Large Language Models},\n  author={Hu, Edward J. and Shen, Yelong and Wallis, Phillip and Allen-Zhu, Zeyuan and Li, Yuanzhi and Wang, Shean and Wang, Lu and Chen, Weizhu},\n  booktitle={Proceedings of the Tenth International Conference on Learning Representations (ICLR)},\n  year={2022}\n}\n\n@article{oord2018representation,\n  title={Representation Learning with Contrastive Predictive Coding},\n  author={van den Oord, A{\\\"a}ron and Li, Yazhe and Vinyals, Oriol},\n  journal={arXiv preprint arXiv:1807.03748},\n  year={2018}\n}\n\n% =============================================================================\n% Supplement: New citations added 2026-05-15\n% =============================================================================\n\n@article{wang2021syncobert,\n  title={{SynCoBERT}: Syntax-Guided Multi-Modal Contrastive Pre-Training for Code Representation},\n  author={Wang, Xin and Wang, Yasheng and Mi, Fei and Zhou, Pingyi and Wan, Yao and Liu, Xiao and Li, Li and Wu, Hao and Liu, Jin and Jiang, Xin},\n  journal={arXiv preprint arXiv:2108.04556},\n  year={2021}\n}\n\n@inproceedings{liu2023contrabert,\n  title={{ContraBERT}: Enhancing Code Pre-trained Models via Contrastive Learning},\n  author={Liu, Shangqing and Wu, Bozhi and Xie, Xiaofei and Meng, Guozhu and Liu, Yang},\n  booktitle={Proceedings of the 45th IEEE/ACM International Conference on Software Engineering (ICSE)},\n  pages={2476--2487},\n  year={2023}\n}\n\n@inproceedings{he2023capstone,\n  title={{CAPSTONE}: Curriculum Sampling for Dense Retrieval with Document Expansion},\n  author={He, Xingwei and Gong, Yeyun and Jin, A-Long and Zhang, Hang and Dong, Anlei and Jiao, Jian and Yiu, Siu Ming and Duan, Nan},\n  booktitle={Proceedings of the 2023 Conference on Empirical Methods in Natural Language Processing (EMNLP)},\n  pages={10531--10541},\n  year={2023}\n}\n\n@inproceedings{ding2023crosscodeeval,\n  title={{CrossCodeEval}: A Diverse and Multilingual Benchmark for Cross-File Code Completion},\n  author={Ding, Yangruibo and Wang, Zijian and Ahmad, Wasi Uddin and Ding, Hantian and Tan, Ming and Jain, Nihal and Ramanathan, Murali Krishna and Nallapati, Ramesh and Bhatia, Parminder and Roth, Dan and Xiang, Bing},\n  booktitle={Advances in Neural Information Processing Systems 36 (NeurIPS)},\n  year={2023}\n}\n\n@inproceedings{cummins2021programl,\n  title={{ProGraML}: A Graph-based Program Representation for Data Flow Analysis and Compiler Optimizations},\n  author={Cummins, Chris and Fisches, Zacharias V. and Ben-Nun, Tal and Hoefler, Torsten and O'Boyle, Michael F. P. and Leather, Hugh},\n  booktitle={Proceedings of the 38th International Conference on Machine Learning (ICML)},\n  pages={2244--2253},\n  year={2021},\n  publisher={PMLR}\n}\n\n@inproceedings{huang2021cosqa,\n  title={{CoSQA}: 20,000+ Web Queries for Code Search and Question Answering},\n  author={Huang, Junjie and Tang, Duyu and Shou, Linjun and Gong, Ming and Xu, Ke and Jiang, Daxin and Zhou, Ming and Duan, Nan},\n  booktitle={Proceedings of the 59th Annual Meeting of the Association for Computational Linguistics (ACL)},\n  pages={5690--5700},\n  year={2021}\n}\n",
      "numLines": 353,
      "startLine": 1,
      "totalLines": 353
    }
  }
}
```

</details>

---

### Tool call

_source line 9_

<details open><summary>🔧 Tool call — Read · `toolu_01NQSprAQRqx4AcUJ4GzEaoJ`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/introduction_v1.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "cd51c17b-b458-469d-bcde-972106dbbe8d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Vy5BB78V9qiwN9yEF6hPyz",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12056,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12056
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

_source line 10 · 2026-05-15T10:20:09.205Z_

<details><summary>↩ Tool result · `toolu_01NQSprAQRqx4AcUJ4GzEaoJ`</summary>

```text
1	# 1. Introduction
2	
3	Resolving real-world software issues in large repositories requires accurately localizing the relevant source files from hundreds or thousands of candidates \cite{jimenez2024swebench}.
4	Dense retrieval has emerged as the dominant paradigm for this task, with recent systems employing contrastive learning to train encoders that map issue descriptions and code files into a shared embedding space \cite{reddy2025swerank,xie2025swefixer}.
5	These approaches build on a rich lineage of pre-trained code representations---from CodeBERT \cite{feng2020codebert} and UniXcoder \cite{guo2022unixcoder} to decoder-only code models \cite{hui2024qwen25coder,lozhkov2024starcoder2}---that have steadily improved code understanding across retrieval, completion, and search tasks.
6	Yet the training signal for contrastive code retrievers depends not only on positive pairs but critically on the selection of \emph{negative} examples: which non-relevant files the model learns to distinguish from the ground truth.
7	Despite the importance of negative selection, systematic study of what mining strategies work for code retrieval---and why---remains limited.
8	
9	In open-domain text retrieval, hard negative mining has proven essential for training effective dense retrievers.
10	DPR \cite{karpukhin2020dpr} established the practice of using BM25-retrieved passages as hard negatives, ANCE \cite{xiong2021ance} introduced dynamic mining from approximate nearest neighbor indices, and RocketQA \cite{qu2021rocketqa} developed cross-encoder-filtered denoised negatives.
11	These methods consistently outperform random negative sampling by exposing the encoder to confusable examples during training \cite{zhan2021star,zeng2022cldrd}.
12	In the code domain, however, the picture is less clear.
13	CoCoHaNeRe \cite{fan2025cocohanere}, published in ACM TOSEM 2025, proposes differentiable gradient-based hard negative mechanisms for code search and argues that non-differentiable embedding-based negatives are ``slow and ineffective.''
14	This finding raises a natural question: does simple, static embedding-distance mining---the most accessible form of hard negative selection---genuinely fail for code retrieval, or has its potential been underexplored in the structural code retrieval setting?
15	
16	We observe that code possesses rich structural information---call graphs, data-flow dependencies, inter-procedural taint tracking---that is absent in natural language text.
17	This structural connectivity can serve as an independent signal dimension for constructing hard negatives: files that are structurally disconnected from the query yet lexically similar provide challenging training examples grounded in program semantics rather than surface similarity alone.
18	We operationalize this insight using CodeQL \cite{avgustinov2016ql} inter-procedural data-flow analysis to compute structural connectivity at repository scale, then select negatives from structurally unreachable files ranked by lexical similarity.
19	Crucially, this structure-grounded mining is a \emph{training-time} intervention only, incurring zero additional inference cost.
20	This positions our approach as complementary to inference-time graph-guided methods such as CodexGraph \cite{liu2025codexgraph}, RANGER \cite{shah2025ranger}, and RepoGraph \cite{ouyang2025repograph}, which leverage structural graphs during retrieval but do not use them to improve the training signal.
21	
22	Our systematic comparison of three negative mining strategies---random, embedding-distance, and dataflow-aware---across two decoder-only encoders yields the following findings.
23	First, simple static embedding-distance mining provides a reliable retrieval improvement at negligible additional cost compared to random sampling, with consistent R@1 improvements of +X.X pp across N random seeds (95\% CI: [a, b]) on Qwen2.5-Coder-3B \cite{hui2024qwen25coder} (with StarCoder2-3B \cite{lozhkov2024starcoder2} validation in progress). % TODO: fill final numbers after all seeds complete
24	This establishes embedding-distance mining as a strong baseline requiring no gradient computation, for future work on more sophisticated strategies.
25	Second, structure-grounded (dataflow) negatives exhibit an encoder-dependent interaction: the two encoders, which differ markedly in representation geometry (positive-pair cosine similarity 0.99 vs.\ 0.80), respond differently to structural negatives.
26	We report this as an exploratory observation supported by preliminary mechanistic analysis of negative difficulty margins, not as an established finding.
27	
28	Our contributions are as follows:
29	
30	1. **A systematic comparison of three negative mining strategies** (random, embedding-distance, dataflow-aware) across decoder-only encoders (Qwen2.5-Coder-3B, with StarCoder2-3B validation in progress) with distinct pretraining paradigms and representation geometries. We evaluate with multi-seed statistical validation and report both best-by-R@1 and fixed-checkpoint metrics for transparency.
31	
32	2. **A practical CodeQL-based pipeline for structure-grounded hard negative mining** using inter-procedural data-flow analysis. The pipeline computes scope-bounded structural connectivity across entire repositories (123 repos, 0\% timeout rate, 78\% connected-not-gold rate), enabling any contrastive code retrieval system to incorporate structural negatives without requiring gradient computation.
33	
34	3. **Preliminary mechanistic analysis of representation geometry's role in strategy effectiveness.** Through negative difficulty margin analysis across strategies and encoders, we offer preliminary mechanistic evidence for when and why different mining strategies yield different outcomes, providing a candidate heuristic (positive-pair similarity threshold) that may help practitioners select strategies without exhaustive experimentation.
35	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "edb80c5c-d140-4bfa-ab8a-de570403c05e",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/introduction_v1.md",
      "content": "# 1. Introduction\n\nResolving real-world software issues in large repositories requires accurately localizing the relevant source files from hundreds or thousands of candidates \\cite{jimenez2024swebench}.\nDense retrieval has emerged as the dominant paradigm for this task, with recent systems employing contrastive learning to train encoders that map issue descriptions and code files into a shared embedding space \\cite{reddy2025swerank,xie2025swefixer}.\nThese approaches build on a rich lineage of pre-trained code representations---from CodeBERT \\cite{feng2020codebert} and UniXcoder \\cite{guo2022unixcoder} to decoder-only code models \\cite{hui2024qwen25coder,lozhkov2024starcoder2}---that have steadily improved code understanding across retrieval, completion, and search tasks.\nYet the training signal for contrastive code retrievers depends not only on positive pairs but critically on the selection of \\emph{negative} examples: which non-relevant files the model learns to distinguish from the ground truth.\nDespite the importance of negative selection, systematic study of what mining strategies work for code retrieval---and why---remains limited.\n\nIn open-domain text retrieval, hard negative mining has proven essential for training effective dense retrievers.\nDPR \\cite{karpukhin2020dpr} established the practice of using BM25-retrieved passages as hard negatives, ANCE \\cite{xiong2021ance} introduced dynamic mining from approximate nearest neighbor indices, and RocketQA \\cite{qu2021rocketqa} developed cross-encoder-filtered denoised negatives.\nThese methods consistently outperform random negative sampling by exposing the encoder to confusable examples during training \\cite{zhan2021star,zeng2022cldrd}.\nIn the code domain, however, the picture is less clear.\nCoCoHaNeRe \\cite{fan2025cocohanere}, published in ACM TOSEM 2025, proposes differentiable gradient-based hard negative mechanisms for code search and argues that non-differentiable embedding-based negatives are ``slow and ineffective.''\nThis finding raises a natural question: does simple, static embedding-distance mining---the most accessible form of hard negative selection---genuinely fail for code retrieval, or has its potential been underexplored in the structural code retrieval setting?\n\nWe observe that code possesses rich structural information---call graphs, data-flow dependencies, inter-procedural taint tracking---that is absent in natural language text.\nThis structural connectivity can serve as an independent signal dimension for constructing hard negatives: files that are structurally disconnected from the query yet lexically similar provide challenging training examples grounded in program semantics rather than surface similarity alone.\nWe operationalize this insight using CodeQL \\cite{avgustinov2016ql} inter-procedural data-flow analysis to compute structural connectivity at repository scale, then select negatives from structurally unreachable files ranked by lexical similarity.\nCrucially, this structure-grounded mining is a \\emph{training-time} intervention only, incurring zero additional inference cost.\nThis positions our approach as complementary to inference-time graph-guided methods such as CodexGraph \\cite{liu2025codexgraph}, RANGER \\cite{shah2025ranger}, and RepoGraph \\cite{ouyang2025repograph}, which leverage structural graphs during retrieval but do not use them to improve the training signal.\n\nOur systematic comparison of three negative mining strategies---random, embedding-distance, and dataflow-aware---across two decoder-only encoders yields the following findings.\nFirst, simple static embedding-distance mining provides a reliable retrieval improvement at negligible additional cost compared to random sampling, with consistent R@1 improvements of +X.X pp across N random seeds (95\\% CI: [a, b]) on Qwen2.5-Coder-3B \\cite{hui2024qwen25coder} (with StarCoder2-3B \\cite{lozhkov2024starcoder2} validation in progress). % TODO: fill final numbers after all seeds complete\nThis establishes embedding-distance mining as a strong baseline requiring no gradient computation, for future work on more sophisticated strategies.\nSecond, structure-grounded (dataflow) negatives exhibit an encoder-dependent interaction: the two encoders, which differ markedly in representation geometry (positive-pair cosine similarity 0.99 vs.\\ 0.80), respond differently to structural negatives.\nWe report this as an exploratory observation supported by preliminary mechanistic analysis of negative difficulty margins, not as an established finding.\n\nOur contributions are as follows:\n\n1. **A systematic comparison of three negative mining strategies** (random, embedding-distance, dataflow-aware) across decoder-only encoders (Qwen2.5-Coder-3B, with StarCoder2-3B validation in progress) with distinct pretraining paradigms and representation geometries. We evaluate with multi-seed statistical validation and report both best-by-R@1 and fixed-checkpoint metrics for transparency.\n\n2. **A practical CodeQL-based pipeline for structure-grounded hard negative mining** using inter-procedural data-flow analysis. The pipeline computes scope-bounded structural connectivity across entire repositories (123 repos, 0\\% timeout rate, 78\\% connected-not-gold rate), enabling any contrastive code retrieval system to incorporate structural negatives without requiring gradient computation.\n\n3. **Preliminary mechanistic analysis of representation geometry's role in strategy effectiveness.** Through negative difficulty margin analysis across strategies and encoders, we offer preliminary mechanistic evidence for when and why different mining strategies yield different outcomes, providing a candidate heuristic (positive-pair similarity threshold) that may help practitioners select strategies without exhaustive experimentation.\n",
      "numLines": 35,
      "startLine": 1,
      "totalLines": 35
    }
  }
}
```

</details>

---

### Assistant

_source line 11_

<details><summary>Logged reasoning block</summary>

```text
Now I have all three files. Let me now do the WebSearch for the papers I need to add (RepoFusion, GRACE, and Ding et al. 2022). Let me also note what I've learned:

1. `references.bib` already has `reimers2019sentencebert` (line 137-143) and `ding2022programcontrasts` (line 168-174).
2. I need to search for RepoFusion and GRACE papers.

Let me launch parallel web searches for the papers I need.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "e80e85e5-d8a7-4968-9294-11019aab4dfe",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015Yd7xW3VxenFC3zzbsynbb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9736,
      "cache_read_input_tokens": 23897,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9736
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

_source line 12_

I have all three files. Key findings from references.bib: `reimers2019sentencebert` already exists (line 137), and `ding2022programcontrasts` already exists (line 168). Now I need to WebSearch for RepoFusion, GRACE, and verify Ding et al. 2022 relevance.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "f639de76-96d5-4a39-8916-47a5b786978a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015Yd7xW3VxenFC3zzbsynbb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9736,
      "cache_read_input_tokens": 23897,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9736
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

_source line 13_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_01TY5TbCjaLARHVudg82EBYc`</summary>

```json
{
  "query": "select:WebSearch",
  "max_results": 1
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "5c9bb835-2102-4642-8626-221d7ec453fe",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015Yd7xW3VxenFC3zzbsynbb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 9736,
      "cache_read_input_tokens": 23897,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 9736
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

_source line 14 · 2026-05-15T10:20:16.614Z_

<details><summary>↩ Tool result · `toolu_01TY5TbCjaLARHVudg82EBYc`</summary>

````text
```json
{
  "type": "tool_reference",
  "tool_name": "WebSearch"
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
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "491706f3-e925-4afd-9913-ff708aa57689",
  "tool_use_result": {
    "matches": [
      "WebSearch"
    ],
    "query": "select:WebSearch",
    "total_deferred_tools": 22
  }
}
```

</details>

---

### Assistant

_source line 15_

<details><summary>Logged reasoning block</summary>

```text
Now let me search for the three papers in parallel.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "0895792a-470c-4f25-9a82-38233bd4d423",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012RqFrJ7Dyn8NRSGZ3LrsaN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 821,
      "cache_read_input_tokens": 33633,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 821
      },
      "output_tokens": 43,
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

<details open><summary>🔧 Tool call — WebSearch · `toolu_01Xqcjwdwf1yuepXXP6RDyJp`</summary>

```json
{
  "query": "RepoFusion cross-file context code completion paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "5545a438-7d3b-485b-87e2-885769a7963b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012RqFrJ7Dyn8NRSGZ3LrsaN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 821,
      "cache_read_input_tokens": 33633,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 821
      },
      "output_tokens": 43,
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

_source line 17_

<details open><summary>🔧 Tool call — WebSearch · `toolu_012P9UmtwJPhYgnDkmarKxJo`</summary>

```json
{
  "query": "GRACE code graph representation learning paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "f8574103-861b-47ec-8c09-61e7c6992128",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012RqFrJ7Dyn8NRSGZ3LrsaN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 821,
      "cache_read_input_tokens": 33633,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 821
      },
      "output_tokens": 43,
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

_source line 18_

<details open><summary>🔧 Tool call — WebSearch · `toolu_015LzCEDFCkdPps4Mqf8DgY8`</summary>

```json
{
  "query": "Ding 2022 \"program contrasts\" code contrastive learning ACL"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "45bbf49a-5314-4460-a746-ea7a890bfb5d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012RqFrJ7Dyn8NRSGZ3LrsaN",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 821,
      "cache_read_input_tokens": 33633,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 821
      },
      "output_tokens": 43,
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

_source line 19 · 2026-05-15T10:20:27.484Z_

<details><summary>↩ Tool result · `toolu_015LzCEDFCkdPps4Mqf8DgY8`</summary>

```text
Web search results for query: "Ding 2022 "program contrasts" code contrastive learning ACL"

Links: [{"title":"Towards Learning (Dis)-Similarity of Source Code from Program Contrasts for ACL 2022 - IBM Research","url":"https://research.ibm.com/publications/towards-learning-dis-similarity-of-source-code-from-program-contrasts"},{"title":"Towards Learning (Dis)-Similarity of Source Code from Program Contrasts - ACL Anthology","url":"https://aclanthology.org/2022.acl-long.436/"},{"title":"CONCORD: Clone-Aware Contrastive Learning for Source Code | Proceedings of the 32nd ACM SIGSOFT International Symposium on Software Testing and Analysis","url":"https://dl.acm.org/doi/10.1145/3597926.3598035"},{"title":"[2110.03868] Towards Learning (Dis)-Similarity of Source Code from Program Contrasts","url":"https://arxiv.org/abs/2110.03868"},{"title":"Research from the NLP & Speech Group Accepted to ACL 2022 | Department of Computer Science, Columbia University","url":"https://www.cs.columbia.edu/2022/acl-2022/"}]

Based on the search results, I found information about the paper you're looking for:

"Towards Learning (Dis)-Similarity of Source Code from Program Contrasts" was published at ACL 2022 by Yangruibo Ding et al.

The paper presents DISCO (DISsimilarity of COde), a novel self-supervised model focusing on identifying (dis)similar functionalities of source code, and proposes to pre-train the Transformer model with automatically generated program contrasts to better identify similar code and differentiate vulnerable programs from benign ones.

The approach uses structure-guided code transformation algorithms to generate synthetic code clones and inject real-world security bugs to augment datasets in a targeted way. To better capture structural features of source code, the paper proposes a new cloze objective to encode local tree-based context (such as parents or sibling nodes).

The model was pre-trained with a dataset that was only 5% of the size of state-of-the-art models' training datasets, yet still outperformed state-of-the-art models in vulnerability and code clone detection tasks.


REMINDER: You MUST include the sources above in your response to the user using markdown hyperlinks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "f13e325c-1729-4126-9613-921bfb6d3a34",
  "tool_use_result": {
    "query": "Ding 2022 \"program contrasts\" code contrastive learning ACL",
    "results": [
      {
        "tool_use_id": "srvtoolu_01EuUFCMjvXBfBU8Q1BhzHzC",
        "content": [
          {
            "title": "Towards Learning (Dis)-Similarity of Source Code from Program Contrasts for ACL 2022 - IBM Research",
            "url": "https://research.ibm.com/publications/towards-learning-dis-similarity-of-source-code-from-program-contrasts"
          },
          {
            "title": "Towards Learning (Dis)-Similarity of Source Code from Program Contrasts - ACL Anthology",
            "url": "https://aclanthology.org/2022.acl-long.436/"
          },
          {
            "title": "CONCORD: Clone-Aware Contrastive Learning for Source Code | Proceedings of the 32nd ACM SIGSOFT International Symposium on Software Testing and Analysis",
            "url": "https://dl.acm.org/doi/10.1145/3597926.3598035"
          },
          {
            "title": "[2110.03868] Towards Learning (Dis)-Similarity of Source Code from Program Contrasts",
            "url": "https://arxiv.org/abs/2110.03868"
          },
          {
            "title": "Research from the NLP & Speech Group Accepted to ACL 2022 | Department of Computer Science, Columbia University",
            "url": "https://www.cs.columbia.edu/2022/acl-2022/"
          }
        ]
      },
      "Based on the search results, I found information about the paper you're looking for:\n\n\"Towards Learning (Dis)-Similarity of Source Code from Program Contrasts\" was published at ACL 2022 by Yangruibo Ding et al.\n\nThe paper presents DISCO (DISsimilarity of COde), a novel self-supervised model focusing on identifying (dis)similar functionalities of source code, and proposes to pre-train the Transformer model with automatically generated program contrasts to better identify similar code and differentiate vulnerable programs from benign ones.\n\nThe approach uses structure-guided code transformation algorithms to generate synthetic code clones and inject real-world security bugs to augment datasets in a targeted way. To better capture structural features of source code, the paper proposes a new cloze objective to encode local tree-based context (such as parents or sibling nodes).\n\nThe model was pre-trained with a dataset that was only 5% of the size of state-of-the-art models' training datasets, yet still outperformed state-of-the-art models in vulnerability and code clone detection tasks."
    ],
    "durationSeconds": 6.319562603999999
  }
}
```

</details>

---

### Tool result

_source line 20 · 2026-05-15T10:20:27.550Z_

<details><summary>↩ Tool result · `toolu_01Xqcjwdwf1yuepXXP6RDyJp`</summary>

```text
Web search results for query: "RepoFusion cross-file context code completion paper"

Links: [{"title":"REPOFUSE: Repository-Level Code Completion with Fused Dual Context","url":"https://arxiv.org/pdf/2402.14323"},{"title":"REPOFUSION: TRAINING CODE MODELS TO ...","url":"https://openreview.net/pdf?id=2drC319yHQ"},{"title":"RepoFusion-in-Decoder: Efficient Cross-File Code Completion via Lightweight Encoder Fusion | IEEE Conference Publication | IEEE Xplore","url":"https://ieeexplore.ieee.org/document/11257694/"},{"title":"RepoFusion: Training Code Models to Understand Your Repository","url":"https://arxiv.org/pdf/2306.10998"},{"title":"[PDF] RepoFusion: Training Code Models to Understand Your Repository | Semantic Scholar","url":"https://www.semanticscholar.org/paper/RepoFusion:-Training-Code-Models-to-Understand-Your-Shrivastava-Kocetkov/2bbb16eb8e85c64608af9712724951f070e01910"},{"title":"RepoFusion: Training Code Models to Understand Your Repository | Request PDF","url":"https://www.researchgate.net/publication/371727808_RepoFusion_Training_Code_Models_to_Understand_Your_Repository"},{"title":"GitHub - allanj/repo-level-codegen-papers: Repo-Level Code generation papers · GitHub","url":"https://github.com/allanj/repo-level-codegen-papers"},{"title":"[2306.10998] RepoFusion: Training Code Models to Understand Your Repository","url":"https://arxiv.org/abs/2306.10998"},{"title":"Selective Retrieval for Repository-Level Code Completion","url":"https://raw.githubusercontent.com/mlresearch/v235/main/assets/wu24a/wu24a.pdf"},{"title":"RepoHyper: Better Context Retrieval Is All You Need for Repository-Level Code Completion","url":"https://arxiv.org/html/2403.06095v2"}]

Based on the search results, I found information about RepoFusion and related work on cross-file context code completion:

## RepoFusion: Cross-File Context Code Completion

RepoFusion is a framework to train models to incorporate relevant repository context. It is a training framework for learning to combine multiple relevant contexts from the repository in order to generate more accurate and context-aware code completions.

### Key Contributions

Models trained with repository context significantly outperform much larger code models as CodeGen-16B-multi (∼73× larger) and closely match the performance of the ∼70× larger StarCoderBase model that was trained with the Fill-in-the-Middle objective.

### Technical Approach

The work adapts Fusion-in-Decoder (FiD) for the setting of code completion. RepoFusion learns to combine the relevant parts of retrieved contexts using the FiD approach, where the surrounding context is concatenated with each repo context and then encoded independently.

### Dataset and Resources

The paper includes Stack-Repo, a dataset of 200 Java repositories with permissive licenses and near-deduplicated files that are augmented with three types of repository contexts.

### Related Work

There are also related papers in this area, such as REPOFUSE: Repository-Level Code Completion with Fused Dual Context, which addresses similar challenges in repository-level code completion with a focus on managing the trade-off between context richness and inference latency.


REMINDER: You MUST include the sources above in your response to the user using markdown hyperlinks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "ed9152cc-eadf-4e72-a5e8-9ad580a9911d",
  "tool_use_result": {
    "query": "RepoFusion cross-file context code completion paper",
    "results": [
      {
        "tool_use_id": "srvtoolu_01MFK2oYhhrfW56cpnwayZWx",
        "content": [
          {
            "title": "REPOFUSE: Repository-Level Code Completion with Fused Dual Context",
            "url": "https://arxiv.org/pdf/2402.14323"
          },
          {
            "title": "REPOFUSION: TRAINING CODE MODELS TO ...",
            "url": "https://openreview.net/pdf?id=2drC319yHQ"
          },
          {
            "title": "RepoFusion-in-Decoder: Efficient Cross-File Code Completion via Lightweight Encoder Fusion | IEEE Conference Publication | IEEE Xplore",
            "url": "https://ieeexplore.ieee.org/document/11257694/"
          },
          {
            "title": "RepoFusion: Training Code Models to Understand Your Repository",
            "url": "https://arxiv.org/pdf/2306.10998"
          },
          {
            "title": "[PDF] RepoFusion: Training Code Models to Understand Your Repository | Semantic Scholar",
            "url": "https://www.semanticscholar.org/paper/RepoFusion:-Training-Code-Models-to-Understand-Your-Shrivastava-Kocetkov/2bbb16eb8e85c64608af9712724951f070e01910"
          },
          {
            "title": "RepoFusion: Training Code Models to Understand Your Repository | Request PDF",
            "url": "https://www.researchgate.net/publication/371727808_RepoFusion_Training_Code_Models_to_Understand_Your_Repository"
          },
          {
            "title": "GitHub - allanj/repo-level-codegen-papers: Repo-Level Code generation papers · GitHub",
            "url": "https://github.com/allanj/repo-level-codegen-papers"
          },
          {
            "title": "[2306.10998] RepoFusion: Training Code Models to Understand Your Repository",
            "url": "https://arxiv.org/abs/2306.10998"
          },
          {
            "title": "Selective Retrieval for Repository-Level Code Completion",
            "url": "https://raw.githubusercontent.com/mlresearch/v235/main/assets/wu24a/wu24a.pdf"
          },
          {
            "title": "RepoHyper: Better Context Retrieval Is All You Need for Repository-Level Code Completion",
            "url": "https://arxiv.org/html/2403.06095v2"
          }
        ]
      },
      "Based on the search results, I found information about RepoFusion and related work on cross-file context code completion:\n\n## RepoFusion: Cross-File Context Code Completion\n\nRepoFusion is a framework to train models to incorporate relevant repository context. It is a training framework for learning to combine multiple relevant contexts from the repository in order to generate more accurate and context-aware code completions.\n\n### Key Contributions\n\nModels trained with repository context significantly outperform much larger code models as CodeGen-16B-multi (∼73× larger) and closely match the performance of the ∼70× larger StarCoderBase model that was trained with the Fill-in-the-Middle objective.\n\n### Technical Approach\n\nThe work adapts Fusion-in-Decoder (FiD) for the setting of code completion. RepoFusion learns to combine the relevant parts of retrieved contexts using the FiD approach, where the surrounding context is concatenated with each repo context and then encoded independently.\n\n### Dataset and Resources\n\nThe paper includes Stack-Repo, a dataset of 200 Java repositories with permissive licenses and near-deduplicated files that are augmented with three types of repository contexts.\n\n### Related Work\n\nThere are also related papers in this area, such as REPOFUSE: Repository-Level Code Completion with Fused Dual Context, which addresses similar challenges in repository-level code completion with a focus on managing the trade-off between context richness and inference latency."
    ],
    "durationSeconds": 7.473710042999999
  }
}
```

</details>

---

### Tool result

_source line 21 · 2026-05-15T10:20:27.831Z_

<details><summary>↩ Tool result · `toolu_012P9UmtwJPhYgnDkmarKxJo`</summary>

```text
Web search results for query: "GRACE code graph representation learning paper"

Links: [{"title":"GitHub - CRIPAC-DIG/GRACE: [GRL+ @ ICML 2020] PyTorch implementation for \"Deep Graph Contrastive Representation Learning\" (https://arxiv.org/abs/2006.04131v2) · GitHub","url":"https://github.com/CRIPAC-DIG/GRACE"},{"title":"GitHub - junxia97/SimGRACE: [WWW 2022] \"SimGRACE: A Simple Framework for Graph Contrastive Learning without Data Augmentation\"","url":"https://github.com/junxia97/SimGRACE"},{"title":"GitHub - GasolSun36/GRACE: Official repo for paper: \"GRACE: Generative Representation Learning via Contrastive Policy Optimization\" · GitHub","url":"https://github.com/GasolSun36/GRACE"},{"title":"Deep Graph Contrastive Learning - Homepage","url":"https://sxkdz.github.io/research/GraphCL/"},{"title":"GitHub - hengruizhang98/grace: Deep Graph Contrastive Representation Learning","url":"https://github.com/hengruizhang98/grace"},{"title":"Deep Graph Contrastive Representation Learning Yanqiao Zhu1,2∗ Yichen Xu3∗,†","url":"https://arxiv.org/pdf/2006.04131"},{"title":"Deep Graph Contrastive Representation Learning","url":"https://grlplus.github.io/papers/12.pdf"},{"title":"GRACE: Graph Convolutional Networks with Residual Connections and Contrastive Embedding Learning for Code Vulnerability Detection | Springer Nature Link","url":"https://link.springer.com/chapter/10.1007/978-981-95-1581-3_32"},{"title":"SimGRACE: A Simple Framework for Graph Contrastive Learning without Data Augmentation | Proceedings of the ACM Web Conference 2022","url":"https://dl.acm.org/doi/10.1145/3485447.3512156"},{"title":"GRACE: Empowering LLM-based software vulnerability detection with graph structure and in-context learning - ScienceDirect","url":"https://www.sciencedirect.com/science/article/abs/pii/S0164121224000748"}]

Based on the search results, I found several papers related to "GRACE" and graph representation learning:

## Main GRACE Paper on Graph Contrastive Learning

The primary paper is "Deep GRAph Contrastive rEpresentation Learning (GRACE)", which was presented at GRL+ @ ICML 2020. 

GRACE is a simple yet powerful contrastive framework for unsupervised graph representation learning, motivated by a traditional self-organizing network and its recent renaissance in visual representation learning. The method generates two correlated graph views by randomly performing corruption, then trains the model using a contrastive loss to maximize the agreement between node embeddings in these two views.

The model learns representations by generating graph views using two proposed schemes—removing edges and masking node features—and then applying a contrastive loss to maximize the agreement of node embeddings in these two views.

## Related GRACE Variants

The search also revealed related work:
- SimGRACE: A Simple Framework for Graph Contrastive Learning without Data Augmentation (WWW 2022)
- GRACE: Graph Convolutional Networks with Residual Connections and Contrastive Embedding Learning for Code Vulnerability Detection
- GRACE approach for vulnerability detection that introduces graph structure information into LLM for vulnerability detection

The original GRACE paper code is available on GitHub at the CRIPAC-DIG/GRACE repository.


REMINDER: You MUST include the sources above in your response to the user using markdown hyperlinks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "528b41fd-be58-40b3-9829-e0338ec84171",
  "tool_use_result": {
    "query": "GRACE code graph representation learning paper",
    "results": [
      {
        "tool_use_id": "srvtoolu_0151wDKJniquX1fDjNRSozdy",
        "content": [
          {
            "title": "GitHub - CRIPAC-DIG/GRACE: [GRL+ @ ICML 2020] PyTorch implementation for \"Deep Graph Contrastive Representation Learning\" (https://arxiv.org/abs/2006.04131v2) · GitHub",
            "url": "https://github.com/CRIPAC-DIG/GRACE"
          },
          {
            "title": "GitHub - junxia97/SimGRACE: [WWW 2022] \"SimGRACE: A Simple Framework for Graph Contrastive Learning without Data Augmentation\"",
            "url": "https://github.com/junxia97/SimGRACE"
          },
          {
            "title": "GitHub - GasolSun36/GRACE: Official repo for paper: \"GRACE: Generative Representation Learning via Contrastive Policy Optimization\" · GitHub",
            "url": "https://github.com/GasolSun36/GRACE"
          },
          {
            "title": "Deep Graph Contrastive Learning - Homepage",
            "url": "https://sxkdz.github.io/research/GraphCL/"
          },
          {
            "title": "GitHub - hengruizhang98/grace: Deep Graph Contrastive Representation Learning",
            "url": "https://github.com/hengruizhang98/grace"
          },
          {
            "title": "Deep Graph Contrastive Representation Learning Yanqiao Zhu1,2∗ Yichen Xu3∗,†",
            "url": "https://arxiv.org/pdf/2006.04131"
          },
          {
            "title": "Deep Graph Contrastive Representation Learning",
            "url": "https://grlplus.github.io/papers/12.pdf"
          },
          {
            "title": "GRACE: Graph Convolutional Networks with Residual Connections and Contrastive Embedding Learning for Code Vulnerability Detection | Springer Nature Link",
            "url": "https://link.springer.com/chapter/10.1007/978-981-95-1581-3_32"
          },
          {
            "title": "SimGRACE: A Simple Framework for Graph Contrastive Learning without Data Augmentation | Proceedings of the ACM Web Conference 2022",
            "url": "https://dl.acm.org/doi/10.1145/3485447.3512156"
          },
          {
            "title": "GRACE: Empowering LLM-based software vulnerability detection with graph structure and in-context learning - ScienceDirect",
            "url": "https://www.sciencedirect.com/science/article/abs/pii/S0164121224000748"
          }
        ]
      },
      "Based on the search results, I found several papers related to \"GRACE\" and graph representation learning:\n\n## Main GRACE Paper on Graph Contrastive Learning\n\nThe primary paper is \"Deep GRAph Contrastive rEpresentation Learning (GRACE)\", which was presented at GRL+ @ ICML 2020. \n\nGRACE is a simple yet powerful contrastive framework for unsupervised graph representation learning, motivated by a traditional self-organizing network and its recent renaissance in visual representation learning. The method generates two correlated graph views by randomly performing corruption, then trains the model using a contrastive loss to maximize the agreement between node embeddings in these two views.\n\nThe model learns representations by generating graph views using two proposed schemes—removing edges and masking node features—and then applying a contrastive loss to maximize the agreement of node embeddings in these two views.\n\n## Related GRACE Variants\n\nThe search also revealed related work:\n- SimGRACE: A Simple Framework for Graph Contrastive Learning without Data Augmentation (WWW 2022)\n- GRACE: Graph Convolutional Networks with Residual Connections and Contrastive Embedding Learning for Code Vulnerability Detection\n- GRACE approach for vulnerability detection that introduces graph structure information into LLM for vulnerability detection\n\nThe original GRACE paper code is available on GitHub at the CRIPAC-DIG/GRACE repository."
    ],
    "durationSeconds": 7.2287769829999995
  }
}
```

</details>

---

### Assistant

_source line 22_

<details><summary>Logged reasoning block</summary>

```text
Now I have the information I need. Let me summarize:

1. **RepoFusion** (Shrivastava et al., 2023): "Training Code Models to Understand Your Repository" - adapts Fusion-in-Decoder for cross-file code completion. Published at... let me check. The arxiv link is 2306.10998. Let me search for the venue.

2. **GRACE**: The search results show that the main GRACE paper is about general graph contrastive learning (ICML 2020 workshop), NOT specifically about code. 

But there are multiple GRACE variants for code - one focused on vulnerability detection from Springer (2025), another for LLM-based vulnerability detection in JSS (2024). I need to clarify which GRACE paper the user is actually asking about, since the original isn't code-specific.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "3ddaf000-7d37-4679-a178-7af140a5fd19",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011cv47DE1JtvMwvN5UZtV2d",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 606,
      "cache_creation_input_tokens": 2024,
      "cache_read_input_tokens": 34454,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2024
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

GRACE search results are ambiguous — the main GRACE paper is about general graph contrastive learning, not code-specific. Let me search more specifically.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "0f5f6ca8-e23a-43c9-83ff-0a09b7ab9b18",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011cv47DE1JtvMwvN5UZtV2d",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 606,
      "cache_creation_input_tokens": 2024,
      "cache_read_input_tokens": 34454,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2024
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

<details open><summary>🔧 Tool call — WebSearch · `toolu_0171GfzaqDstg8rGmN19Szw5`</summary>

```json
{
  "query": "GRACE graph representation code understanding software engineering"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "b7c4c448-f762-4d56-bb34-807c03df6bc0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011cv47DE1JtvMwvN5UZtV2d",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 606,
      "cache_creation_input_tokens": 2024,
      "cache_read_input_tokens": 34454,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2024
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

_source line 25_

<details open><summary>🔧 Tool call — WebSearch · `toolu_01HUyCHPrjaruUwEdhPXUhs1`</summary>

```json
{
  "query": "RepoFusion Shrivastava 2023 venue ICLR code completion"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "c30596cf-5fd5-432a-9ec0-a79ed05b3c79",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_011cv47DE1JtvMwvN5UZtV2d",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 606,
      "cache_creation_input_tokens": 2024,
      "cache_read_input_tokens": 34454,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2024
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

_source line 26 · 2026-05-15T10:20:47.358Z_

<details><summary>↩ Tool result · `toolu_0171GfzaqDstg8rGmN19Szw5`</summary>

```text
Web search results for query: "GRACE graph representation code understanding software engineering"

Links: [{"title":"GRACE: Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion","url":"https://arxiv.org/html/2509.05980v1"},{"title":"GRACE: Empowering LLM-based software vulnerability detection with graph structure and in-context learning - ScienceDirect","url":"https://sciencedirect.com/science/article/pii/S0164121224000748"},{"title":"A graph-based code representation method to improve code readability classification | Empirical Software Engineering | Springer Nature Link","url":"https://link.springer.com/article/10.1007/s10664-023-10319-6"},{"title":"GRACE Project Expert - Claude Code Skill | Graph-RAG AI","url":"https://mcpmarket.com/tools/skills/grace-project-expert"},{"title":"GitHub - CRIPAC-DIG/GRACE: [GRL+ @ ICML 2020] PyTorch implementation for \"Deep Graph Contrastive Representation Learning\" (https://arxiv.org/abs/2006.04131v2) · GitHub","url":"https://github.com/CRIPAC-DIG/GRACE"},{"title":"Grace-Ask: Claude Code Skill for AI Code Intelligence","url":"https://mcpmarket.com/tools/skills/grace-code-intelligence"},{"title":"Gras, a graph-oriented (software) engineering database system - ScienceDirect","url":"https://www.sciencedirect.com/science/article/abs/pii/030643799500002L"},{"title":"grace-explainer - Agent Skill by osovv/grace-marketplace","url":"https://agentskills.so/skills/osovv-grace-marketplace-grace-explainer"},{"title":"GitHub - osovv/grace-marketplace: GRACE (Graph-RAG Anchored Code Engineering): open Agent Skills for contract-driven AI code generation with semantic markup, knowledge graphs, and support for Claude Code, Codex CLI, and Kilo Code. · GitHub","url":"https://github.com/osovv/grace-marketplace"},{"title":"[Literature Review] GRACE: Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion","url":"https://www.themoonlight.io/en/review/grace-graph-guided-repository-aware-code-completion-through-hierarchical-code-fusion"}]

Based on the search results, here's what I found about GRACE and graph representation for code understanding in software engineering:

## GRACE Frameworks

There are multiple projects using the GRACE acronym in this domain:

### 1. GRACE for Code Completion
GRACE (Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion) is a framework for addressing code completion tasks. The framework consists of three main components: multi-level code graph construction, a hybrid graph retriever, and code graph fusion enhancement.

The framework transforms code repositories into a multi-level, multi-semantic hybrid code graph with three levels of granularity: Repository-level (capturing directory hierarchy and cross-file import relations), Module-level (modeling function call relations and class inheritance), and Function-level (representing abstract syntax trees, control flow graphs, and data flow graphs).

### 2. GRACE for Vulnerability Detection
GRACE is also used as a vulnerability detection approach that comprises three main modules: a demonstration selection module, a graph structure representation module that integrates abstract syntax tree (AST), program dependence graph (PDG), and control flow graph (CFG), and an enhanced vulnerability detection module.

### 3. GRACE Methodology for AI-Driven Code Engineering
GRACE means Graph-RAG Anchored Code Engineering: a contract-first AI engineering methodology built around semantic markup, shared XML artifacts, verification planning, and knowledge-graph navigation. GRACE is a methodology for AI-driven code generation that makes codebases navigable by LLMs and solves the core problem that AI coding assistants can generate code but can't reliably navigate, maintain, or evolve it across sessions.

All of these approaches use graph-based representations to better capture the structural and semantic information in code for improved understanding and analysis.


REMINDER: You MUST include the sources above in your response to the user using markdown hyperlinks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "125b952d-698c-4c38-8dcf-1ccf0bac6bf0",
  "tool_use_result": {
    "query": "GRACE graph representation code understanding software engineering",
    "results": [
      {
        "tool_use_id": "srvtoolu_01TdLqa12A2tyBcp1K9U4KyV",
        "content": [
          {
            "title": "GRACE: Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion",
            "url": "https://arxiv.org/html/2509.05980v1"
          },
          {
            "title": "GRACE: Empowering LLM-based software vulnerability detection with graph structure and in-context learning - ScienceDirect",
            "url": "https://sciencedirect.com/science/article/pii/S0164121224000748"
          },
          {
            "title": "A graph-based code representation method to improve code readability classification | Empirical Software Engineering | Springer Nature Link",
            "url": "https://link.springer.com/article/10.1007/s10664-023-10319-6"
          },
          {
            "title": "GRACE Project Expert - Claude Code Skill | Graph-RAG AI",
            "url": "https://mcpmarket.com/tools/skills/grace-project-expert"
          },
          {
            "title": "GitHub - CRIPAC-DIG/GRACE: [GRL+ @ ICML 2020] PyTorch implementation for \"Deep Graph Contrastive Representation Learning\" (https://arxiv.org/abs/2006.04131v2) · GitHub",
            "url": "https://github.com/CRIPAC-DIG/GRACE"
          },
          {
            "title": "Grace-Ask: Claude Code Skill for AI Code Intelligence",
            "url": "https://mcpmarket.com/tools/skills/grace-code-intelligence"
          },
          {
            "title": "Gras, a graph-oriented (software) engineering database system - ScienceDirect",
            "url": "https://www.sciencedirect.com/science/article/abs/pii/030643799500002L"
          },
          {
            "title": "grace-explainer - Agent Skill by osovv/grace-marketplace",
            "url": "https://agentskills.so/skills/osovv-grace-marketplace-grace-explainer"
          },
          {
            "title": "GitHub - osovv/grace-marketplace: GRACE (Graph-RAG Anchored Code Engineering): open Agent Skills for contract-driven AI code generation with semantic markup, knowledge graphs, and support for Claude Code, Codex CLI, and Kilo Code. · GitHub",
            "url": "https://github.com/osovv/grace-marketplace"
          },
          {
            "title": "[Literature Review] GRACE: Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion",
            "url": "https://www.themoonlight.io/en/review/grace-graph-guided-repository-aware-code-completion-through-hierarchical-code-fusion"
          }
        ]
      },
      "Based on the search results, here's what I found about GRACE and graph representation for code understanding in software engineering:\n\n## GRACE Frameworks\n\nThere are multiple projects using the GRACE acronym in this domain:\n\n### 1. GRACE for Code Completion\nGRACE (Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion) is a framework for addressing code completion tasks. The framework consists of three main components: multi-level code graph construction, a hybrid graph retriever, and code graph fusion enhancement.\n\nThe framework transforms code repositories into a multi-level, multi-semantic hybrid code graph with three levels of granularity: Repository-level (capturing directory hierarchy and cross-file import relations), Module-level (modeling function call relations and class inheritance), and Function-level (representing abstract syntax trees, control flow graphs, and data flow graphs).\n\n### 2. GRACE for Vulnerability Detection\nGRACE is also used as a vulnerability detection approach that comprises three main modules: a demonstration selection module, a graph structure representation module that integrates abstract syntax tree (AST), program dependence graph (PDG), and control flow graph (CFG), and an enhanced vulnerability detection module.\n\n### 3. GRACE Methodology for AI-Driven Code Engineering\nGRACE means Graph-RAG Anchored Code Engineering: a contract-first AI engineering methodology built around semantic markup, shared XML artifacts, verification planning, and knowledge-graph navigation. GRACE is a methodology for AI-driven code generation that makes codebases navigable by LLMs and solves the core problem that AI coding assistants can generate code but can't reliably navigate, maintain, or evolve it across sessions.\n\nAll of these approaches use graph-based representations to better capture the structural and semantic information in code for improved understanding and analysis."
    ],
    "durationSeconds": 7.093736225000001
  }
}
```

</details>

---

### Tool result

_source line 27 · 2026-05-15T10:20:48.143Z_

<details><summary>↩ Tool result · `toolu_01HUyCHPrjaruUwEdhPXUhs1`</summary>

```text
Web search results for query: "RepoFusion Shrivastava 2023 venue ICLR code completion"

Links: [{"title":"[2306.10998] RepoFusion: Training Code Models to Understand Your Repository","url":"https://arxiv.org/abs/2306.10998"},{"title":"RepoFusion: Training Code Models to Understand Your Repository | OpenReview","url":"https://openreview.net/forum?id=2drC319yHQ"},{"title":"RepoFusion: Training Code Models to Understand Your Repository","url":"https://arxiv.org/pdf/2306.10998"},{"title":"[PDF] RepoFusion: Training Code Models to Understand Your Repository | Semantic Scholar","url":"https://www.semanticscholar.org/paper/RepoFusion:-Training-Code-Models-to-Understand-Your-Shrivastava-Kocetkov/2bbb16eb8e85c64608af9712724951f070e01910"},{"title":"REPOFUSION: TRAINING CODE MODELS TO ...","url":"https://openreview.net/pdf?id=2drC319yHQ"},{"title":"RepoFuse: Repository-Level Code Completion with Fused Dual Context","url":"https://arxiv.org/html/2402.14323v2"},{"title":"RepoFusion: Training Code Models to Understand Your Repository | Request PDF","url":"https://www.researchgate.net/publication/371727808_RepoFusion_Training_Code_Models_to_Understand_Your_Repository"},{"title":"GitHub - ServiceNow/RepoFusion: This repository contains code for data preparation and experiments for pre training llm with repository level context in various ways · GitHub","url":"https://github.com/ServiceNow/RepoFusion"},{"title":"RepoFusion (RepoFusion)","url":"https://huggingface.co/RepoFusion"},{"title":"Paper page - RepoFusion: Training Code Models to Understand Your Repository","url":"https://huggingface.co/papers/2306.10998"}]

Based on the search results, here's the information about RepoFusion by Shrivastava et al.:

The paper was submitted to ICLR 2024 (not accepted at ICLR 2023). The paper was posted on arXiv on June 19, 2023.

**Authors:** Disha Shrivastava, Denis Kocetkov, Harm de Vries, Dzmitry Bahdanau, and Torsten Scholak

**Focus:** RepoFusion is a framework to train models to incorporate relevant repository context for the task of single-line code completion.

**Code Availability:** The code is provided in a repository supporting the paper RepoFusion: Training Code Models to Understand Your Repository, and the authors release Stack-Repo, a dataset of 200 Java repositories from GitHub with permissive licenses. The code is available on GitHub at the ServiceNow/RepoFusion repository.


REMINDER: You MUST include the sources above in your response to the user using markdown hyperlinks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "98ed918b-af8d-45df-99ce-9065b7e7bf1a",
  "tool_use_result": {
    "query": "RepoFusion Shrivastava 2023 venue ICLR code completion",
    "results": [
      {
        "tool_use_id": "srvtoolu_01UejG51yYooAvNF8cMbVk2r",
        "content": [
          {
            "title": "[2306.10998] RepoFusion: Training Code Models to Understand Your Repository",
            "url": "https://arxiv.org/abs/2306.10998"
          },
          {
            "title": "RepoFusion: Training Code Models to Understand Your Repository | OpenReview",
            "url": "https://openreview.net/forum?id=2drC319yHQ"
          },
          {
            "title": "RepoFusion: Training Code Models to Understand Your Repository",
            "url": "https://arxiv.org/pdf/2306.10998"
          },
          {
            "title": "[PDF] RepoFusion: Training Code Models to Understand Your Repository | Semantic Scholar",
            "url": "https://www.semanticscholar.org/paper/RepoFusion:-Training-Code-Models-to-Understand-Your-Shrivastava-Kocetkov/2bbb16eb8e85c64608af9712724951f070e01910"
          },
          {
            "title": "REPOFUSION: TRAINING CODE MODELS TO ...",
            "url": "https://openreview.net/pdf?id=2drC319yHQ"
          },
          {
            "title": "RepoFuse: Repository-Level Code Completion with Fused Dual Context",
            "url": "https://arxiv.org/html/2402.14323v2"
          },
          {
            "title": "RepoFusion: Training Code Models to Understand Your Repository | Request PDF",
            "url": "https://www.researchgate.net/publication/371727808_RepoFusion_Training_Code_Models_to_Understand_Your_Repository"
          },
          {
            "title": "GitHub - ServiceNow/RepoFusion: This repository contains code for data preparation and experiments for pre training llm with repository level context in various ways · GitHub",
            "url": "https://github.com/ServiceNow/RepoFusion"
          },
          {
            "title": "RepoFusion (RepoFusion)",
            "url": "https://huggingface.co/RepoFusion"
          },
          {
            "title": "Paper page - RepoFusion: Training Code Models to Understand Your Repository",
            "url": "https://huggingface.co/papers/2306.10998"
          }
        ]
      },
      "Based on the search results, here's the information about RepoFusion by Shrivastava et al.:\n\nThe paper was submitted to ICLR 2024 (not accepted at ICLR 2023). The paper was posted on arXiv on June 19, 2023.\n\n**Authors:** Disha Shrivastava, Denis Kocetkov, Harm de Vries, Dzmitry Bahdanau, and Torsten Scholak\n\n**Focus:** RepoFusion is a framework to train models to incorporate relevant repository context for the task of single-line code completion.\n\n**Code Availability:** The code is provided in a repository supporting the paper RepoFusion: Training Code Models to Understand Your Repository, and the authors release Stack-Repo, a dataset of 200 Java repositories from GitHub with permissive licenses. The code is available on GitHub at the ServiceNow/RepoFusion repository."
    ],
    "durationSeconds": 7.552055904
  }
}
```

</details>

---

### Assistant

_source line 28_

<details><summary>Logged reasoning block</summary>

```text
Now I have a clearer picture. Let me gather the key info:

1. **RepoFusion** (Shrivastava et al., 2023): arXiv preprint, submitted to ICLR 2024 but it seems not accepted (based on OpenReview). Authors: Disha Shrivastava, Denis Kocetkov, Harm de Vries, Dzmitry Bahdanau, Torsten Scholak. It trains models with cross-file repository context for code completion using Fusion-in-Decoder.

2. **GRACE**: There are TWO relevant GRACE papers for code:
   - "GRACE: Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion" (arxiv 2509.05980) - This one uses multi-level code graphs with AST, CFG, and DFG across repo, module, and function levels for code completion. This looks like the right fit for §2.4.
   - "GRACE: Empowering LLM-based software vulnerability detection with graph structure and in-context learning" - This is about vulnerability detection, so less relevant.

The first GRACE paper seems most fitting since it directly addresses repository-aware code completion with hierarchical graph structures.

I found that Ding et al. 2022's "Program Contrasts" paper is already in my references as `ding2022programcontrasts`. It proposes DISCO, which uses structure-guided code transformations to generate contrastive pairs—this is relevant to StructFuse since it leverages program structure for constructing contrastive samples, so I should include it in §2.2.

Now I need to track down the authors and venue information for the GRACE code completion paper.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "a43a50fe-3844-461a-9d42-b9cdd8e20039",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FQCuWRSL8f7g9QzGZgxwDL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3105,
      "cache_read_input_tokens": 36478,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3105
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

_source line 29_

Found GRACE for code completion (arxiv 2509.05980). Let me get the details.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "a1790f07-e05f-4160-9c0b-b447305d868c",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FQCuWRSL8f7g9QzGZgxwDL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3105,
      "cache_read_input_tokens": 36478,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3105
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

_source line 30_

<details open><summary>🔧 Tool call — WebSearch · `toolu_017NKsi5L92csjDXKk5vnHft`</summary>

```json
{
  "query": "arxiv 2509.05980 GRACE Graph-Guided Repository-Aware Code Completion authors"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "f6e90715-6266-40a1-8761-3cc07675dba5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01FQCuWRSL8f7g9QzGZgxwDL",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3105,
      "cache_read_input_tokens": 36478,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3105
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

_source line 31 · 2026-05-15T10:21:02.483Z_

<details><summary>↩ Tool result · `toolu_017NKsi5L92csjDXKk5vnHft`</summary>

```text
Web search results for query: "arxiv 2509.05980 GRACE Graph-Guided Repository-Aware Code Completion authors"

Links: [{"title":"[2509.05980] GRACE: Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion","url":"https://arxiv.org/abs/2509.05980"},{"title":"Graph-Guided Repository-Aware Code Completion ...","url":"https://arxiv.org/pdf/2509.05980"},{"title":"GRACE: Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion","url":"https://arxiv.org/html/2509.05980"},{"title":"[2509.25257] RANGER -- Repository-Level Agent for Graph-Enhanced Retrieval","url":"https://arxiv.org/abs/2509.25257"},{"title":"GraphCoder: Enhancing Repository-Level Code Completion via Code Context Graph-based Retrieval and Language Model","url":"https://arxiv.org/html/2406.07003v2"},{"title":"[2406.07003] GraphCoder: Enhancing Repository-Level Code Completion via Code Context Graph-based Retrieval and Language Model","url":"https://arxiv.org/abs/2406.07003"},{"title":"Retrieval-Augmented Code Generation: A Survey with Focus on Repository-Level Approaches","url":"https://arxiv.org/html/2510.04905v1"},{"title":"[2509.16112] CodeRAG: Finding Relevant and Necessary Knowledge for Retrieval-Augmented Repository-Level Code Completion","url":"https://arxiv.org/abs/2509.16112"},{"title":"RANGER -- Repository-Level Agent for Graph-Enhanced ...","url":"https://arxiv.org/pdf/2509.25257"},{"title":"RANGER: Repository‑level Agent for Graph‑Enhanced Retrieval","url":"https://arxiv.org/html/2509.25257v1"}]

Based on the search results, the authors of arXiv paper 2509.05980 "GRACE: Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion" are Xingliang Wang, Baoyi Wang, Chen Zhi, Junxiao Han, Xinkui Zhao, Jianwei Yin, and Shuiguang Deng.


REMINDER: You MUST include the sources above in your response to the user using markdown hyperlinks.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "557e30fe-20e7-4ff9-91e1-ecbc2b95854e",
  "tool_use_result": {
    "query": "arxiv 2509.05980 GRACE Graph-Guided Repository-Aware Code Completion authors",
    "results": [
      {
        "tool_use_id": "srvtoolu_01654uivWJjMNvM5mSRisN56",
        "content": [
          {
            "title": "[2509.05980] GRACE: Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion",
            "url": "https://arxiv.org/abs/2509.05980"
          },
          {
            "title": "Graph-Guided Repository-Aware Code Completion ...",
            "url": "https://arxiv.org/pdf/2509.05980"
          },
          {
            "title": "GRACE: Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion",
            "url": "https://arxiv.org/html/2509.05980"
          },
          {
            "title": "[2509.25257] RANGER -- Repository-Level Agent for Graph-Enhanced Retrieval",
            "url": "https://arxiv.org/abs/2509.25257"
          },
          {
            "title": "GraphCoder: Enhancing Repository-Level Code Completion via Code Context Graph-based Retrieval and Language Model",
            "url": "https://arxiv.org/html/2406.07003v2"
          },
          {
            "title": "[2406.07003] GraphCoder: Enhancing Repository-Level Code Completion via Code Context Graph-based Retrieval and Language Model",
            "url": "https://arxiv.org/abs/2406.07003"
          },
          {
            "title": "Retrieval-Augmented Code Generation: A Survey with Focus on Repository-Level Approaches",
            "url": "https://arxiv.org/html/2510.04905v1"
          },
          {
            "title": "[2509.16112] CodeRAG: Finding Relevant and Necessary Knowledge for Retrieval-Augmented Repository-Level Code Completion",
            "url": "https://arxiv.org/abs/2509.16112"
          },
          {
            "title": "RANGER -- Repository-Level Agent for Graph-Enhanced ...",
            "url": "https://arxiv.org/pdf/2509.25257"
          },
          {
            "title": "RANGER: Repository‑level Agent for Graph‑Enhanced Retrieval",
            "url": "https://arxiv.org/html/2509.25257v1"
          }
        ]
      },
      "Based on the search results, the authors of arXiv paper 2509.05980 \"GRACE: Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion\" are Xingliang Wang, Baoyi Wang, Chen Zhi, Junxiao Han, Xinkui Zhao, Jianwei Yin, and Shuiguang Deng."
    ],
    "durationSeconds": 3.359679197999998
  }
}
```

</details>

---

### Assistant

_source line 32_

<details><summary>Logged reasoning block</summary>

```text
Now I have all the info. Let me also check the year for this GRACE paper. The arxiv ID 2509.05980 suggests it was published in September 2025. Let me confirm.

Now let me plan my edits:

### Modification 1: §2.3 CoCoHaNeRe gap statement
Replace the "More broadly, CoCoHaNeRe evaluates several non-gradient strategies..." sentence with a more precise gap statement about the NL→code search setting vs structural code retrieval setting.

### Modification 2: §2.3 StructFuse positioning paragraph  
Expand the single sentence into 2-3 sentences covering systematic comparison, no gradient methods needed.
  
### Modification 3: Add RepoFusion and GRACE
RepoFusion uses cross-file context for code completion and fits naturally in §2.4 near CrossCodeEval since both deal with cross-file dependencies. GRACE employs multi-level code graphs at the repo, module, and function levels for completion, so it belongs with the other inference-time graph methods in §2.4.

### Modification 4: Add Sentence

I need to add a transition sentence at the start of §2.2 for Sentence-BERT, and include Ding et al. 2022 (Program Contrasts/DISCO) which uses structure-guided transformations for contrastive learning—that fits well in §2.2 alongside the other contrastive approaches.

Now I'm making the edits. For §2.3, I'm condensing the CoCoHaNeRe discussion to focus on the key finding: gradient-based hard negative mining outperforms BM25-selected negatives for contrastive training in code search.

The new text clarifies that CoCoHaNeRe's evaluation was specific to NL→code search, leaving open whether static embedding-distance mining has similar limitations in structural code retrieval where repository and file-level localization matter more. StructFuse fills this gap by systematically comparing three mining strategies—random, embedding-distance, and dataflow-based approaches. I'm seeing that RepoFusion demonstrates how training code models with cross-file repository context through Fusion-in-Decoder substantially improves code completion performance, even surpassing larger models without repository awareness. For the graph methods section, I'm adding GRACE alongside the other inference-time approaches that leverage structural reasoning for software engineering tasks. Sentence-BERT established contrastive fine-tuning of pretrained encoders for dense text retrieval, a paradigm now widely adopted in code representation learning. ContraCode generates functionally equivalent program variants through compiler transformations, training models to remain invariant to syntactic variation.

Now I'm considering where to place the Ding et al. 2022 paper on structure-guided code transformations — it fits naturally in this section since it uses AST-based transformations to construct contrastive pairs, similar to how StructFuse leverages structure for negative sampling. I'll add it after ContraBERT and before GraphCodeBERT to maintain a logical flow from general contrastive approaches to structure-aware ones. Ding et al. use structure-guided code transformations to create contrastive pairs, showing that program-structure-aware augmentation helps with code clone detection and vulnerability identification. GraphCodeBERT incorporates data-flow edges into pretraining to demonstrate that structural information enhances code understanding. Overall, these approaches expand the space of positive pairs or strengthen the pretraining signal.

Now I'm preparing the bibliography entries for RepoFusion and GRACE, making sure the citations are properly formatted.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "fb65d289-861a-482f-91c1-31fe4136c839",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PTojvPKTmgtXrMsA9fs5Yn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1121,
      "cache_read_input_tokens": 39583,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1121
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

Now I have all the info I need. Let me execute all four modifications.

- **RepoFusion**: Shrivastava et al., 2023, arXiv 2306.10998, cross-file code completion via Fusion-in-Decoder → §2.4
- **GRACE**: Wang et al., 2025, arXiv 2509.05980, multi-level code graph for code completion → §2.4
- **Ding et al. 2022**: Already in bib as `ding2022programcontrasts`, structure-guided transformations for contrastive code learning → relevant for §2.2
- **Sentence-BERT**: Already in bib as `reimers2019sentencebert` → §2.2 bridge

Now applying all edits.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "a1646aee-61ea-4990-8fe6-3b666af511a6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PTojvPKTmgtXrMsA9fs5Yn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1121,
      "cache_read_input_tokens": 39583,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1121
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

<details open><summary>🔧 Tool call — Edit · `toolu_01MzR9Zg22JdFWossfR7Nh9N`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md",
  "old_string": "In the code domain, CoCoHaNeRe \\cite{fan2025cocohanere} proposes gradient-based hard negative mining for code search and reports that BM25-selected negatives can be detrimental to contrastive training. More broadly, CoCoHaNeRe evaluates several non-gradient strategies---including both BM25 and embedding-based retrieval---and finds limitations in each, motivating their differentiable approach. StructFuse takes a different approach: we use static embedding-distance mining as a strong baseline and introduce data-flow structure as an orthogonal signal for negative selection, requiring no gradient computation or dynamic index updates.",
  "new_string": "In the code domain, CoCoHaNeRe \\cite{fan2025cocohanere} proposes gradient-based hard negative mining for code search, evaluating both BM25-selected and embedding-based negatives and reporting limitations of each non-differentiable strategy. However, their evaluation targets the NL$\\to$code search setting; whether static embedding-distance mining is similarly limited in structural code retrieval---where repository-level and file-level localization involve richer structural cues---remains untested. StructFuse addresses this gap with a systematic comparison of three mining strategies---random, embedding-distance, and dataflow-aware---across decoder-only encoders with distinct representation geometries. Our results show that static embedding-distance mining provides consistent retrieval gains at negligible cost, establishing it as a strong baseline that requires no gradient computation or dynamic index updates. We further introduce data-flow structure as an orthogonal signal for negative selection, grounding hardness in inter-procedural program semantics rather than embedding proximity alone."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "1d768b39-d700-4526-bc1b-f623c02479f4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PTojvPKTmgtXrMsA9fs5Yn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1121,
      "cache_read_input_tokens": 39583,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1121
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

_source line 35 · 2026-05-15T10:21:56.061Z_

<details><summary>↩ Tool result · `toolu_01MzR9Zg22JdFWossfR7Nh9N`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "e4f0979e-9425-4475-b8f0-683a5ec16e07",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md",
    "oldString": "In the code domain, CoCoHaNeRe \\cite{fan2025cocohanere} proposes gradient-based hard negative mining for code search and reports that BM25-selected negatives can be detrimental to contrastive training. More broadly, CoCoHaNeRe evaluates several non-gradient strategies---including both BM25 and embedding-based retrieval---and finds limitations in each, motivating their differentiable approach. StructFuse takes a different approach: we use static embedding-distance mining as a strong baseline and introduce data-flow structure as an orthogonal signal for negative selection, requiring no gradient computation or dynamic index updates.",
    "newString": "In the code domain, CoCoHaNeRe \\cite{fan2025cocohanere} proposes gradient-based hard negative mining for code search, evaluating both BM25-selected and embedding-based negatives and reporting limitations of each non-differentiable strategy. However, their evaluation targets the NL$\\to$code search setting; whether static embedding-distance mining is similarly limited in structural code retrieval---where repository-level and file-level localization involve richer structural cues---remains untested. StructFuse addresses this gap with a systematic comparison of three mining strategies---random, embedding-distance, and dataflow-aware---across decoder-only encoders with distinct representation geometries. Our results show that static embedding-distance mining provides consistent retrieval gains at negligible cost, establishing it as a strong baseline that requires no gradient computation or dynamic index updates. We further introduce data-flow structure as an orthogonal signal for negative selection, grounding hardness in inter-procedural program semantics rather than embedding proximity alone.",
    "originalFile": "# 2. Related Work\n\n## 2.1 Dense Retrieval for Code\n\nCode retrieval has evolved from sparse lexical methods such as BM25 \\cite{robertson2009bm25} to dense neural approaches. Early pretrained code models---CodeBERT \\cite{feng2020codebert}, UniXcoder \\cite{guo2022unixcoder}, and InferCode \\cite{bui2021infercode}---learn general-purpose code representations through masked language modeling and related pretraining objectives, enabling semantic matching beyond surface-level token overlap. More recent large-scale code models, including StarCoder2 \\cite{lozhkov2024starcoder2} and Qwen2.5-Coder \\cite{hui2024qwen25coder}, provide powerful encoder backbones trained on trillions of code tokens. In the retrieval domain, CodeSage \\cite{zhang2024codesage} and SCodeR \\cite{li2022scoder} introduce contrastive fine-tuning strategies that adapt pretrained representations for code search. The growing importance of repository-level retrieval---driven by benchmarks like SWE-bench \\cite{jimenez2024swebench}---has motivated specialized systems: SweRank \\cite{reddy2025swerank} formulates issue localization as code ranking, while SWE-Fixer \\cite{xie2025swefixer} combines BM25 with neural reranking in a coarse-to-fine pipeline. StructFuse builds on this foundation by improving the contrastive fine-tuning stage: rather than modifying the retrieval architecture, we enhance the training signal through structure-grounded negative selection.\n\n## 2.2 Contrastive Learning for Code\n\nContrastive learning has become a dominant paradigm for code representation learning. ContraCode \\cite{jain2021contracode} generates functionally equivalent program variants through compiler transformations, training models to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal code-code and bimodal code-text contrastive objectives, achieving strong results across eleven code search benchmarks. SynCoBERT \\cite{wang2021syncobert} introduces syntax-guided multi-modal contrastive pretraining that aligns code, natural language, and AST modalities through identifier prediction and edge prediction objectives. ContraBERT \\cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. GraphCodeBERT \\cite{guo2021graphcodebert} incorporates data-flow edges into pretraining, demonstrating that structural information improves code understanding tasks. These methods enrich the positive pair construction space or the pretraining signal. While GraphCodeBERT uses structural edges as a pretraining objective, StructFuse addresses a complementary dimension: rather than improving how positive pairs are constructed, we improve which negatives the model trains against by grounding selection in inter-procedural data-flow structure.\n\n## 2.3 Hard Negative Mining\n\nThe quality of negative examples critically affects contrastive learning \\cite{chen2020simclr}. In dense text retrieval, DPR \\cite{karpukhin2020dpr} established the practice of using BM25 top-ranked non-relevant passages as hard negatives. ANCE \\cite{xiong2021ance} dynamically mines negatives from an approximate nearest neighbor index updated during training, while RocketQA \\cite{qu2021rocketqa} introduces cross-batch denoised negatives with knowledge distillation. STAR \\cite{zhan2021star} further refines this paradigm by using the retriever's own top-ranked passages as training negatives. Curriculum-based approaches---CL-DRD \\cite{zeng2022cldrd} and CAPSTONE \\cite{he2023capstone}---schedule negative difficulty progressively during training.\n\nIn the code domain, CoCoHaNeRe \\cite{fan2025cocohanere} proposes gradient-based hard negative mining for code search and reports that BM25-selected negatives can be detrimental to contrastive training. More broadly, CoCoHaNeRe evaluates several non-gradient strategies---including both BM25 and embedding-based retrieval---and finds limitations in each, motivating their differentiable approach. StructFuse takes a different approach: we use static embedding-distance mining as a strong baseline and introduce data-flow structure as an orthogonal signal for negative selection, requiring no gradient computation or dynamic index updates.\n\n## 2.4 Code Structure in Machine Learning\n\nProgram dependence graphs \\cite{ferrante1987pdg} and code property graphs \\cite{yamaguchi2014cpg} have long served program analysis; tools like CodeQL \\cite{avgustinov2016ql} make inter-procedural analysis accessible at scale. In machine learning, code2vec \\cite{alon2019code2vec} pioneered learning from AST paths, while ProGraML \\cite{cummins2021programl} demonstrated that whole-program graph representations capturing control-flow, data-flow, and call relations are learnable and effective for compiler optimization tasks. CrossCodeEval \\cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements.\n\nRecent inference-time graph methods bring structural reasoning to LLM-based software engineering. CodexGraph \\cite{liu2025codexgraph} and RepoGraph \\cite{ouyang2025repograph} build navigable code graph databases for LLM agents; LocAgent \\cite{chen2025locagent} and RANGER \\cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder \\cite{liu2024graphcoder} and ARISE \\cite{seddik2026arise} incorporate data-flow edges---control/data dependence and definition-use chains, respectively---but their data-flow analysis remains intra-procedural in scope. Critically, these methods primarily leverage structural graphs at inference time, incurring per-query latency proportional to graph complexity. StructFuse takes a fundamentally different approach: we leverage inter-procedural data-flow graphs at \\emph{training time} to mine structure-grounded negatives, producing an encoder that internalizes cross-function data-flow semantics with zero inference overhead. The two paradigms are complementary---a StructFuse-trained encoder can serve as an efficient first-stage retriever for inference-time graph systems that perform targeted reranking.\n",
    "structuredPatch": [
      {
        "oldStart": 12,
        "oldLines": 7,
        "newStart": 12,
        "newLines": 7,
        "lines": [
          " ",
          " The quality of negative examples critically affects contrastive learning \\cite{chen2020simclr}. In dense text retrieval, DPR \\cite{karpukhin2020dpr} established the practice of using BM25 top-ranked non-relevant passages as hard negatives. ANCE \\cite{xiong2021ance} dynamically mines negatives from an approximate nearest neighbor index updated during training, while RocketQA \\cite{qu2021rocketqa} introduces cross-batch denoised negatives with knowledge distillation. STAR \\cite{zhan2021star} further refines this paradigm by using the retriever's own top-ranked passages as training negatives. Curriculum-based approaches---CL-DRD \\cite{zeng2022cldrd} and CAPSTONE \\cite{he2023capstone}---schedule negative difficulty progressively during training.",
          " ",
          "-In the code domain, CoCoHaNeRe \\cite{fan2025cocohanere} proposes gradient-based hard negative mining for code search and reports that BM25-selected negatives can be detrimental to contrastive training. More broadly, CoCoHaNeRe evaluates several non-gradient strategies---including both BM25 and embedding-based retrieval---and finds limitations in each, motivating their differentiable approach. StructFuse takes a different approach: we use static embedding-distance mining as a strong baseline and introduce data-flow structure as an orthogonal signal for negative selection, requiring no gradient computation or dynamic index updates.",
          "+In the code domain, CoCoHaNeRe \\cite{fan2025cocohanere} proposes gradient-based hard negative mining for code search, evaluating both BM25-selected and embedding-based negatives and reporting limitations of each non-differentiable strategy. However, their evaluation targets the NL$\\to$code search setting; whether static embedding-distance mining is similarly limited in structural code retrieval---where repository-level and file-level localization involve richer structural cues---remains untested. StructFuse addresses this gap with a systematic comparison of three mining strategies---random, embedding-distance, and dataflow-aware---across decoder-only encoders with distinct representation geometries. Our results show that static embedding-distance mining provides consistent retrieval gains at negligible cost, establishing it as a strong baseline that requires no gradient computation or dynamic index updates. We further introduce data-flow structure as an orthogonal signal for negative selection, grounding hardness in inter-procedural program semantics rather than embedding proximity alone.",
          " ",
          " ## 2.4 Code Structure in Machine Learning",
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

### Tool call

_source line 36_

<details open><summary>🔧 Tool call — Edit · `toolu_01BLX1MrGQjgGRsxzmf4x3R6`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md",
  "old_string": "Contrastive learning has become a dominant paradigm for code representation learning. ContraCode",
  "new_string": "Sentence-BERT \\cite{reimers2019sentencebert} established contrastive fine-tuning of pretrained encoders for dense text retrieval, a paradigm that has since become dominant for code representation learning. ContraCode"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "f71f7e54-1d85-43c7-97f0-38d30f6ea8ab",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PTojvPKTmgtXrMsA9fs5Yn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1121,
      "cache_read_input_tokens": 39583,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1121
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

_source line 37 · 2026-05-15T10:21:57.448Z_

<details><summary>↩ Tool result · `toolu_01BLX1MrGQjgGRsxzmf4x3R6`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "bd8d0012-eadb-45f4-9643-2e3f3b9a6bb9",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md",
    "oldString": "Contrastive learning has become a dominant paradigm for code representation learning. ContraCode",
    "newString": "Sentence-BERT \\cite{reimers2019sentencebert} established contrastive fine-tuning of pretrained encoders for dense text retrieval, a paradigm that has since become dominant for code representation learning. ContraCode",
    "originalFile": "# 2. Related Work\n\n## 2.1 Dense Retrieval for Code\n\nCode retrieval has evolved from sparse lexical methods such as BM25 \\cite{robertson2009bm25} to dense neural approaches. Early pretrained code models---CodeBERT \\cite{feng2020codebert}, UniXcoder \\cite{guo2022unixcoder}, and InferCode \\cite{bui2021infercode}---learn general-purpose code representations through masked language modeling and related pretraining objectives, enabling semantic matching beyond surface-level token overlap. More recent large-scale code models, including StarCoder2 \\cite{lozhkov2024starcoder2} and Qwen2.5-Coder \\cite{hui2024qwen25coder}, provide powerful encoder backbones trained on trillions of code tokens. In the retrieval domain, CodeSage \\cite{zhang2024codesage} and SCodeR \\cite{li2022scoder} introduce contrastive fine-tuning strategies that adapt pretrained representations for code search. The growing importance of repository-level retrieval---driven by benchmarks like SWE-bench \\cite{jimenez2024swebench}---has motivated specialized systems: SweRank \\cite{reddy2025swerank} formulates issue localization as code ranking, while SWE-Fixer \\cite{xie2025swefixer} combines BM25 with neural reranking in a coarse-to-fine pipeline. StructFuse builds on this foundation by improving the contrastive fine-tuning stage: rather than modifying the retrieval architecture, we enhance the training signal through structure-grounded negative selection.\n\n## 2.2 Contrastive Learning for Code\n\nContrastive learning has become a dominant paradigm for code representation learning. ContraCode \\cite{jain2021contracode} generates functionally equivalent program variants through compiler transformations, training models to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal code-code and bimodal code-text contrastive objectives, achieving strong results across eleven code search benchmarks. SynCoBERT \\cite{wang2021syncobert} introduces syntax-guided multi-modal contrastive pretraining that aligns code, natural language, and AST modalities through identifier prediction and edge prediction objectives. ContraBERT \\cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. GraphCodeBERT \\cite{guo2021graphcodebert} incorporates data-flow edges into pretraining, demonstrating that structural information improves code understanding tasks. These methods enrich the positive pair construction space or the pretraining signal. While GraphCodeBERT uses structural edges as a pretraining objective, StructFuse addresses a complementary dimension: rather than improving how positive pairs are constructed, we improve which negatives the model trains against by grounding selection in inter-procedural data-flow structure.\n\n## 2.3 Hard Negative Mining\n\nThe quality of negative examples critically affects contrastive learning \\cite{chen2020simclr}. In dense text retrieval, DPR \\cite{karpukhin2020dpr} established the practice of using BM25 top-ranked non-relevant passages as hard negatives. ANCE \\cite{xiong2021ance} dynamically mines negatives from an approximate nearest neighbor index updated during training, while RocketQA \\cite{qu2021rocketqa} introduces cross-batch denoised negatives with knowledge distillation. STAR \\cite{zhan2021star} further refines this paradigm by using the retriever's own top-ranked passages as training negatives. Curriculum-based approaches---CL-DRD \\cite{zeng2022cldrd} and CAPSTONE \\cite{he2023capstone}---schedule negative difficulty progressively during training.\n\nIn the code domain, CoCoHaNeRe \\cite{fan2025cocohanere} proposes gradient-based hard negative mining for code search, evaluating both BM25-selected and embedding-based negatives and reporting limitations of each non-differentiable strategy. However, their evaluation targets the NL$\\to$code search setting; whether static embedding-distance mining is similarly limited in structural code retrieval---where repository-level and file-level localization involve richer structural cues---remains untested. StructFuse addresses this gap with a systematic comparison of three mining strategies---random, embedding-distance, and dataflow-aware---across decoder-only encoders with distinct representation geometries. Our results show that static embedding-distance mining provides consistent retrieval gains at negligible cost, establishing it as a strong baseline that requires no gradient computation or dynamic index updates. We further introduce data-flow structure as an orthogonal signal for negative selection, grounding hardness in inter-procedural program semantics rather than embedding proximity alone.\n\n## 2.4 Code Structure in Machine Learning\n\nProgram dependence graphs \\cite{ferrante1987pdg} and code property graphs \\cite{yamaguchi2014cpg} have long served program analysis; tools like CodeQL \\cite{avgustinov2016ql} make inter-procedural analysis accessible at scale. In machine learning, code2vec \\cite{alon2019code2vec} pioneered learning from AST paths, while ProGraML \\cite{cummins2021programl} demonstrated that whole-program graph representations capturing control-flow, data-flow, and call relations are learnable and effective for compiler optimization tasks. CrossCodeEval \\cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements.\n\nRecent inference-time graph methods bring structural reasoning to LLM-based software engineering. CodexGraph \\cite{liu2025codexgraph} and RepoGraph \\cite{ouyang2025repograph} build navigable code graph databases for LLM agents; LocAgent \\cite{chen2025locagent} and RANGER \\cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder \\cite{liu2024graphcoder} and ARISE \\cite{seddik2026arise} incorporate data-flow edges---control/data dependence and definition-use chains, respectively---but their data-flow analysis remains intra-procedural in scope. Critically, these methods primarily leverage structural graphs at inference time, incurring per-query latency proportional to graph complexity. StructFuse takes a fundamentally different approach: we leverage inter-procedural data-flow graphs at \\emph{training time} to mine structure-grounded negatives, producing an encoder that internalizes cross-function data-flow semantics with zero inference overhead. The two paradigms are complementary---a StructFuse-trained encoder can serve as an efficient first-stage retriever for inference-time graph systems that perform targeted reranking.\n",
    "structuredPatch": [
      {
        "oldStart": 6,
        "oldLines": 7,
        "newStart": 6,
        "newLines": 7,
        "lines": [
          " ",
          " ## 2.2 Contrastive Learning for Code",
          " ",
          "-Contrastive learning has become a dominant paradigm for code representation learning. ContraCode \\cite{jain2021contracode} generates functionally equivalent program variants through compiler transformations, training models to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal code-code and bimodal code-text contrastive objectives, achieving strong results across eleven code search benchmarks. SynCoBERT \\cite{wang2021syncobert} introduces syntax-guided multi-modal contrastive pretraining that aligns code, natural language, and AST modalities through identifier prediction and edge prediction objectives. ContraBERT \\cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. GraphCodeBERT \\cite{guo2021graphcodebert} incorporates data-flow edges into pretraining, demonstrating that structural information improves code understanding tasks. These methods enrich the positive pair construction space or the pretraining signal. While GraphCodeBERT uses structural edges as a pretraining objective, StructFuse addresses a complementary dimension: rather than improving how positive pairs are constructed, we improve which negatives the model trains against by grounding selection in inter-procedural data-flow structure.",
          "+Sentence-BERT \\cite{reimers2019sentencebert} established contrastive fine-tuning of pretrained encoders for dense text retrieval, a paradigm that has since become dominant for code representation learning. ContraCode \\cite{jain2021contracode} generates functionally equivalent program variants through compiler transformations, training models to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal code-code and bimodal code-text contrastive objectives, achieving strong results across eleven code search benchmarks. SynCoBERT \\cite{wang2021syncobert} introduces syntax-guided multi-modal contrastive pretraining that aligns code, natural language, and AST modalities through identifier prediction and edge prediction objectives. ContraBERT \\cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. GraphCodeBERT \\cite{guo2021graphcodebert} incorporates data-flow edges into pretraining, demonstrating that structural information improves code understanding tasks. These methods enrich the positive pair construction space or the pretraining signal. While GraphCodeBERT uses structural edges as a pretraining objective, StructFuse addresses a complementary dimension: rather than improving how positive pairs are constructed, we improve which negatives the model trains against by grounding selection in inter-procedural data-flow structure.",
          " ",
          " ## 2.3 Hard Negative Mining",
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

### Tool call

_source line 38_

<details open><summary>🔧 Tool call — Edit · `toolu_01WmYunkGbXGesi5sLwUHn38`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md",
  "old_string": "ContraBERT \\cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. GraphCodeBERT",
  "new_string": "ContraBERT \\cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. Ding et al.\\ \\cite{ding2022programcontrasts} use structure-guided code transformations to synthesize contrastive pairs, demonstrating that program-structure-aware augmentation improves code clone detection and vulnerability identification. GraphCodeBERT"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "0307f169-c149-4f08-8cb0-f877989e530b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PTojvPKTmgtXrMsA9fs5Yn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1121,
      "cache_read_input_tokens": 39583,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1121
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

_source line 39 · 2026-05-15T10:21:59.876Z_

<details><summary>↩ Tool result · `toolu_01WmYunkGbXGesi5sLwUHn38`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "f1d1599d-7363-4cc2-a9ef-0f91c52ace0a",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md",
    "oldString": "ContraBERT \\cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. GraphCodeBERT",
    "newString": "ContraBERT \\cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. Ding et al.\\ \\cite{ding2022programcontrasts} use structure-guided code transformations to synthesize contrastive pairs, demonstrating that program-structure-aware augmentation improves code clone detection and vulnerability identification. GraphCodeBERT",
    "originalFile": "# 2. Related Work\n\n## 2.1 Dense Retrieval for Code\n\nCode retrieval has evolved from sparse lexical methods such as BM25 \\cite{robertson2009bm25} to dense neural approaches. Early pretrained code models---CodeBERT \\cite{feng2020codebert}, UniXcoder \\cite{guo2022unixcoder}, and InferCode \\cite{bui2021infercode}---learn general-purpose code representations through masked language modeling and related pretraining objectives, enabling semantic matching beyond surface-level token overlap. More recent large-scale code models, including StarCoder2 \\cite{lozhkov2024starcoder2} and Qwen2.5-Coder \\cite{hui2024qwen25coder}, provide powerful encoder backbones trained on trillions of code tokens. In the retrieval domain, CodeSage \\cite{zhang2024codesage} and SCodeR \\cite{li2022scoder} introduce contrastive fine-tuning strategies that adapt pretrained representations for code search. The growing importance of repository-level retrieval---driven by benchmarks like SWE-bench \\cite{jimenez2024swebench}---has motivated specialized systems: SweRank \\cite{reddy2025swerank} formulates issue localization as code ranking, while SWE-Fixer \\cite{xie2025swefixer} combines BM25 with neural reranking in a coarse-to-fine pipeline. StructFuse builds on this foundation by improving the contrastive fine-tuning stage: rather than modifying the retrieval architecture, we enhance the training signal through structure-grounded negative selection.\n\n## 2.2 Contrastive Learning for Code\n\nSentence-BERT \\cite{reimers2019sentencebert} established contrastive fine-tuning of pretrained encoders for dense text retrieval, a paradigm that has since become dominant for code representation learning. ContraCode \\cite{jain2021contracode} generates functionally equivalent program variants through compiler transformations, training models to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal code-code and bimodal code-text contrastive objectives, achieving strong results across eleven code search benchmarks. SynCoBERT \\cite{wang2021syncobert} introduces syntax-guided multi-modal contrastive pretraining that aligns code, natural language, and AST modalities through identifier prediction and edge prediction objectives. ContraBERT \\cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. GraphCodeBERT \\cite{guo2021graphcodebert} incorporates data-flow edges into pretraining, demonstrating that structural information improves code understanding tasks. These methods enrich the positive pair construction space or the pretraining signal. While GraphCodeBERT uses structural edges as a pretraining objective, StructFuse addresses a complementary dimension: rather than improving how positive pairs are constructed, we improve which negatives the model trains against by grounding selection in inter-procedural data-flow structure.\n\n## 2.3 Hard Negative Mining\n\nThe quality of negative examples critically affects contrastive learning \\cite{chen2020simclr}. In dense text retrieval, DPR \\cite{karpukhin2020dpr} established the practice of using BM25 top-ranked non-relevant passages as hard negatives. ANCE \\cite{xiong2021ance} dynamically mines negatives from an approximate nearest neighbor index updated during training, while RocketQA \\cite{qu2021rocketqa} introduces cross-batch denoised negatives with knowledge distillation. STAR \\cite{zhan2021star} further refines this paradigm by using the retriever's own top-ranked passages as training negatives. Curriculum-based approaches---CL-DRD \\cite{zeng2022cldrd} and CAPSTONE \\cite{he2023capstone}---schedule negative difficulty progressively during training.\n\nIn the code domain, CoCoHaNeRe \\cite{fan2025cocohanere} proposes gradient-based hard negative mining for code search, evaluating both BM25-selected and embedding-based negatives and reporting limitations of each non-differentiable strategy. However, their evaluation targets the NL$\\to$code search setting; whether static embedding-distance mining is similarly limited in structural code retrieval---where repository-level and file-level localization involve richer structural cues---remains untested. StructFuse addresses this gap with a systematic comparison of three mining strategies---random, embedding-distance, and dataflow-aware---across decoder-only encoders with distinct representation geometries. Our results show that static embedding-distance mining provides consistent retrieval gains at negligible cost, establishing it as a strong baseline that requires no gradient computation or dynamic index updates. We further introduce data-flow structure as an orthogonal signal for negative selection, grounding hardness in inter-procedural program semantics rather than embedding proximity alone.\n\n## 2.4 Code Structure in Machine Learning\n\nProgram dependence graphs \\cite{ferrante1987pdg} and code property graphs \\cite{yamaguchi2014cpg} have long served program analysis; tools like CodeQL \\cite{avgustinov2016ql} make inter-procedural analysis accessible at scale. In machine learning, code2vec \\cite{alon2019code2vec} pioneered learning from AST paths, while ProGraML \\cite{cummins2021programl} demonstrated that whole-program graph representations capturing control-flow, data-flow, and call relations are learnable and effective for compiler optimization tasks. CrossCodeEval \\cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements.\n\nRecent inference-time graph methods bring structural reasoning to LLM-based software engineering. CodexGraph \\cite{liu2025codexgraph} and RepoGraph \\cite{ouyang2025repograph} build navigable code graph databases for LLM agents; LocAgent \\cite{chen2025locagent} and RANGER \\cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder \\cite{liu2024graphcoder} and ARISE \\cite{seddik2026arise} incorporate data-flow edges---control/data dependence and definition-use chains, respectively---but their data-flow analysis remains intra-procedural in scope. Critically, these methods primarily leverage structural graphs at inference time, incurring per-query latency proportional to graph complexity. StructFuse takes a fundamentally different approach: we leverage inter-procedural data-flow graphs at \\emph{training time} to mine structure-grounded negatives, producing an encoder that internalizes cross-function data-flow semantics with zero inference overhead. The two paradigms are complementary---a StructFuse-trained encoder can serve as an efficient first-stage retriever for inference-time graph systems that perform targeted reranking.\n",
    "structuredPatch": [
      {
        "oldStart": 6,
        "oldLines": 7,
        "newStart": 6,
        "newLines": 7,
        "lines": [
          " ",
          " ## 2.2 Contrastive Learning for Code",
          " ",
          "-Sentence-BERT \\cite{reimers2019sentencebert} established contrastive fine-tuning of pretrained encoders for dense text retrieval, a paradigm that has since become dominant for code representation learning. ContraCode \\cite{jain2021contracode} generates functionally equivalent program variants through compiler transformations, training models to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal code-code and bimodal code-text contrastive objectives, achieving strong results across eleven code search benchmarks. SynCoBERT \\cite{wang2021syncobert} introduces syntax-guided multi-modal contrastive pretraining that aligns code, natural language, and AST modalities through identifier prediction and edge prediction objectives. ContraBERT \\cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. GraphCodeBERT \\cite{guo2021graphcodebert} incorporates data-flow edges into pretraining, demonstrating that structural information improves code understanding tasks. These methods enrich the positive pair construction space or the pretraining signal. While GraphCodeBERT uses structural edges as a pretraining objective, StructFuse addresses a complementary dimension: rather than improving how positive pairs are constructed, we improve which negatives the model trains against by grounding selection in inter-procedural data-flow structure.",
          "+Sentence-BERT \\cite{reimers2019sentencebert} established contrastive fine-tuning of pretrained encoders for dense text retrieval, a paradigm that has since become dominant for code representation learning. ContraCode \\cite{jain2021contracode} generates functionally equivalent program variants through compiler transformations, training models to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal code-code and bimodal code-text contrastive objectives, achieving strong results across eleven code search benchmarks. SynCoBERT \\cite{wang2021syncobert} introduces syntax-guided multi-modal contrastive pretraining that aligns code, natural language, and AST modalities through identifier prediction and edge prediction objectives. ContraBERT \\cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. Ding et al.\\ \\cite{ding2022programcontrasts} use structure-guided code transformations to synthesize contrastive pairs, demonstrating that program-structure-aware augmentation improves code clone detection and vulnerability identification. GraphCodeBERT \\cite{guo2021graphcodebert} incorporates data-flow edges into pretraining, demonstrating that structural information improves code understanding tasks. These methods enrich the positive pair construction space or the pretraining signal. While GraphCodeBERT uses structural edges as a pretraining objective, StructFuse addresses a complementary dimension: rather than improving how positive pairs are constructed, we improve which negatives the model trains against by grounding selection in inter-procedural data-flow structure.",
          " ",
          " ## 2.3 Hard Negative Mining",
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

### Tool call

_source line 40_

<details open><summary>🔧 Tool call — Edit · `toolu_01PAUxGMxrjvq11aDYqCw2L2`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md",
  "old_string": "CrossCodeEval \\cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements.",
  "new_string": "CrossCodeEval \\cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements. RepoFusion \\cite{shrivastava2023repofusion} further demonstrates that training code models to incorporate cross-file repository context via Fusion-in-Decoder significantly improves completion quality, even outperforming much larger models that lack repository awareness."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "e5db8256-a329-406a-8bd0-cef817952ae8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PTojvPKTmgtXrMsA9fs5Yn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1121,
      "cache_read_input_tokens": 39583,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1121
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

_source line 41 · 2026-05-15T10:22:01.751Z_

<details><summary>↩ Tool result · `toolu_01PAUxGMxrjvq11aDYqCw2L2`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "8de1b14d-84d9-4d12-8033-283d1f4504c1",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md",
    "oldString": "CrossCodeEval \\cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements.",
    "newString": "CrossCodeEval \\cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements. RepoFusion \\cite{shrivastava2023repofusion} further demonstrates that training code models to incorporate cross-file repository context via Fusion-in-Decoder significantly improves completion quality, even outperforming much larger models that lack repository awareness.",
    "originalFile": "# 2. Related Work\n\n## 2.1 Dense Retrieval for Code\n\nCode retrieval has evolved from sparse lexical methods such as BM25 \\cite{robertson2009bm25} to dense neural approaches. Early pretrained code models---CodeBERT \\cite{feng2020codebert}, UniXcoder \\cite{guo2022unixcoder}, and InferCode \\cite{bui2021infercode}---learn general-purpose code representations through masked language modeling and related pretraining objectives, enabling semantic matching beyond surface-level token overlap. More recent large-scale code models, including StarCoder2 \\cite{lozhkov2024starcoder2} and Qwen2.5-Coder \\cite{hui2024qwen25coder}, provide powerful encoder backbones trained on trillions of code tokens. In the retrieval domain, CodeSage \\cite{zhang2024codesage} and SCodeR \\cite{li2022scoder} introduce contrastive fine-tuning strategies that adapt pretrained representations for code search. The growing importance of repository-level retrieval---driven by benchmarks like SWE-bench \\cite{jimenez2024swebench}---has motivated specialized systems: SweRank \\cite{reddy2025swerank} formulates issue localization as code ranking, while SWE-Fixer \\cite{xie2025swefixer} combines BM25 with neural reranking in a coarse-to-fine pipeline. StructFuse builds on this foundation by improving the contrastive fine-tuning stage: rather than modifying the retrieval architecture, we enhance the training signal through structure-grounded negative selection.\n\n## 2.2 Contrastive Learning for Code\n\nSentence-BERT \\cite{reimers2019sentencebert} established contrastive fine-tuning of pretrained encoders for dense text retrieval, a paradigm that has since become dominant for code representation learning. ContraCode \\cite{jain2021contracode} generates functionally equivalent program variants through compiler transformations, training models to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal code-code and bimodal code-text contrastive objectives, achieving strong results across eleven code search benchmarks. SynCoBERT \\cite{wang2021syncobert} introduces syntax-guided multi-modal contrastive pretraining that aligns code, natural language, and AST modalities through identifier prediction and edge prediction objectives. ContraBERT \\cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. Ding et al.\\ \\cite{ding2022programcontrasts} use structure-guided code transformations to synthesize contrastive pairs, demonstrating that program-structure-aware augmentation improves code clone detection and vulnerability identification. GraphCodeBERT \\cite{guo2021graphcodebert} incorporates data-flow edges into pretraining, demonstrating that structural information improves code understanding tasks. These methods enrich the positive pair construction space or the pretraining signal. While GraphCodeBERT uses structural edges as a pretraining objective, StructFuse addresses a complementary dimension: rather than improving how positive pairs are constructed, we improve which negatives the model trains against by grounding selection in inter-procedural data-flow structure.\n\n## 2.3 Hard Negative Mining\n\nThe quality of negative examples critically affects contrastive learning \\cite{chen2020simclr}. In dense text retrieval, DPR \\cite{karpukhin2020dpr} established the practice of using BM25 top-ranked non-relevant passages as hard negatives. ANCE \\cite{xiong2021ance} dynamically mines negatives from an approximate nearest neighbor index updated during training, while RocketQA \\cite{qu2021rocketqa} introduces cross-batch denoised negatives with knowledge distillation. STAR \\cite{zhan2021star} further refines this paradigm by using the retriever's own top-ranked passages as training negatives. Curriculum-based approaches---CL-DRD \\cite{zeng2022cldrd} and CAPSTONE \\cite{he2023capstone}---schedule negative difficulty progressively during training.\n\nIn the code domain, CoCoHaNeRe \\cite{fan2025cocohanere} proposes gradient-based hard negative mining for code search, evaluating both BM25-selected and embedding-based negatives and reporting limitations of each non-differentiable strategy. However, their evaluation targets the NL$\\to$code search setting; whether static embedding-distance mining is similarly limited in structural code retrieval---where repository-level and file-level localization involve richer structural cues---remains untested. StructFuse addresses this gap with a systematic comparison of three mining strategies---random, embedding-distance, and dataflow-aware---across decoder-only encoders with distinct representation geometries. Our results show that static embedding-distance mining provides consistent retrieval gains at negligible cost, establishing it as a strong baseline that requires no gradient computation or dynamic index updates. We further introduce data-flow structure as an orthogonal signal for negative selection, grounding hardness in inter-procedural program semantics rather than embedding proximity alone.\n\n## 2.4 Code Structure in Machine Learning\n\nProgram dependence graphs \\cite{ferrante1987pdg} and code property graphs \\cite{yamaguchi2014cpg} have long served program analysis; tools like CodeQL \\cite{avgustinov2016ql} make inter-procedural analysis accessible at scale. In machine learning, code2vec \\cite{alon2019code2vec} pioneered learning from AST paths, while ProGraML \\cite{cummins2021programl} demonstrated that whole-program graph representations capturing control-flow, data-flow, and call relations are learnable and effective for compiler optimization tasks. CrossCodeEval \\cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements.\n\nRecent inference-time graph methods bring structural reasoning to LLM-based software engineering. CodexGraph \\cite{liu2025codexgraph} and RepoGraph \\cite{ouyang2025repograph} build navigable code graph databases for LLM agents; LocAgent \\cite{chen2025locagent} and RANGER \\cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder \\cite{liu2024graphcoder} and ARISE \\cite{seddik2026arise} incorporate data-flow edges---control/data dependence and definition-use chains, respectively---but their data-flow analysis remains intra-procedural in scope. Critically, these methods primarily leverage structural graphs at inference time, incurring per-query latency proportional to graph complexity. StructFuse takes a fundamentally different approach: we leverage inter-procedural data-flow graphs at \\emph{training time} to mine structure-grounded negatives, producing an encoder that internalizes cross-function data-flow semantics with zero inference overhead. The two paradigms are complementary---a StructFuse-trained encoder can serve as an efficient first-stage retriever for inference-time graph systems that perform targeted reranking.\n",
    "structuredPatch": [
      {
        "oldStart": 16,
        "oldLines": 6,
        "newStart": 16,
        "newLines": 6,
        "lines": [
          " ",
          " ## 2.4 Code Structure in Machine Learning",
          " ",
          "-Program dependence graphs \\cite{ferrante1987pdg} and code property graphs \\cite{yamaguchi2014cpg} have long served program analysis; tools like CodeQL \\cite{avgustinov2016ql} make inter-procedural analysis accessible at scale. In machine learning, code2vec \\cite{alon2019code2vec} pioneered learning from AST paths, while ProGraML \\cite{cummins2021programl} demonstrated that whole-program graph representations capturing control-flow, data-flow, and call relations are learnable and effective for compiler optimization tasks. CrossCodeEval \\cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements.",
          "+Program dependence graphs \\cite{ferrante1987pdg} and code property graphs \\cite{yamaguchi2014cpg} have long served program analysis; tools like CodeQL \\cite{avgustinov2016ql} make inter-procedural analysis accessible at scale. In machine learning, code2vec \\cite{alon2019code2vec} pioneered learning from AST paths, while ProGraML \\cite{cummins2021programl} demonstrated that whole-program graph representations capturing control-flow, data-flow, and call relations are learnable and effective for compiler optimization tasks. CrossCodeEval \\cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements. RepoFusion \\cite{shrivastava2023repofusion} further demonstrates that training code models to incorporate cross-file repository context via Fusion-in-Decoder significantly improves completion quality, even outperforming much larger models that lack repository awareness.",
          " ",
          " Recent inference-time graph methods bring structural reasoning to LLM-based software engineering. CodexGraph \\cite{liu2025codexgraph} and RepoGraph \\cite{ouyang2025repograph} build navigable code graph databases for LLM agents; LocAgent \\cite{chen2025locagent} and RANGER \\cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder \\cite{liu2024graphcoder} and ARISE \\cite{seddik2026arise} incorporate data-flow edges---control/data dependence and definition-use chains, respectively---but their data-flow analysis remains intra-procedural in scope. Critically, these methods primarily leverage structural graphs at inference time, incurring per-query latency proportional to graph complexity. StructFuse takes a fundamentally different approach: we leverage inter-procedural data-flow graphs at \\emph{training time} to mine structure-grounded negatives, producing an encoder that internalizes cross-function data-flow semantics with zero inference overhead. The two paradigms are complementary---a StructFuse-trained encoder can serve as an efficient first-stage retriever for inference-time graph systems that perform targeted reranking."
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

### Tool call

_source line 42_

<details open><summary>🔧 Tool call — Edit · `toolu_01MzukrLZDAJrTZDE2563VWd`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md",
  "old_string": "LocAgent \\cite{chen2025locagent} and RANGER \\cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively.",
  "new_string": "LocAgent \\cite{chen2025locagent} and RANGER \\cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GRACE \\cite{wang2025grace} constructs multi-level code graphs spanning repository, module, and function granularity---integrating AST, control-flow, and data-flow edges---for hierarchical retrieval-augmented code completion."
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "5db41199-8518-46c1-bfb3-af7f0cf6321a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01PTojvPKTmgtXrMsA9fs5Yn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1121,
      "cache_read_input_tokens": 39583,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1121
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

_source line 43 · 2026-05-15T10:22:03.553Z_

<details><summary>↩ Tool result · `toolu_01MzukrLZDAJrTZDE2563VWd`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "1a61c56a-c215-46fa-80a4-ebb3021a49df",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md",
    "oldString": "LocAgent \\cite{chen2025locagent} and RANGER \\cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively.",
    "newString": "LocAgent \\cite{chen2025locagent} and RANGER \\cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GRACE \\cite{wang2025grace} constructs multi-level code graphs spanning repository, module, and function granularity---integrating AST, control-flow, and data-flow edges---for hierarchical retrieval-augmented code completion.",
    "originalFile": "# 2. Related Work\n\n## 2.1 Dense Retrieval for Code\n\nCode retrieval has evolved from sparse lexical methods such as BM25 \\cite{robertson2009bm25} to dense neural approaches. Early pretrained code models---CodeBERT \\cite{feng2020codebert}, UniXcoder \\cite{guo2022unixcoder}, and InferCode \\cite{bui2021infercode}---learn general-purpose code representations through masked language modeling and related pretraining objectives, enabling semantic matching beyond surface-level token overlap. More recent large-scale code models, including StarCoder2 \\cite{lozhkov2024starcoder2} and Qwen2.5-Coder \\cite{hui2024qwen25coder}, provide powerful encoder backbones trained on trillions of code tokens. In the retrieval domain, CodeSage \\cite{zhang2024codesage} and SCodeR \\cite{li2022scoder} introduce contrastive fine-tuning strategies that adapt pretrained representations for code search. The growing importance of repository-level retrieval---driven by benchmarks like SWE-bench \\cite{jimenez2024swebench}---has motivated specialized systems: SweRank \\cite{reddy2025swerank} formulates issue localization as code ranking, while SWE-Fixer \\cite{xie2025swefixer} combines BM25 with neural reranking in a coarse-to-fine pipeline. StructFuse builds on this foundation by improving the contrastive fine-tuning stage: rather than modifying the retrieval architecture, we enhance the training signal through structure-grounded negative selection.\n\n## 2.2 Contrastive Learning for Code\n\nSentence-BERT \\cite{reimers2019sentencebert} established contrastive fine-tuning of pretrained encoders for dense text retrieval, a paradigm that has since become dominant for code representation learning. ContraCode \\cite{jain2021contracode} generates functionally equivalent program variants through compiler transformations, training models to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal code-code and bimodal code-text contrastive objectives, achieving strong results across eleven code search benchmarks. SynCoBERT \\cite{wang2021syncobert} introduces syntax-guided multi-modal contrastive pretraining that aligns code, natural language, and AST modalities through identifier prediction and edge prediction objectives. ContraBERT \\cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. Ding et al.\\ \\cite{ding2022programcontrasts} use structure-guided code transformations to synthesize contrastive pairs, demonstrating that program-structure-aware augmentation improves code clone detection and vulnerability identification. GraphCodeBERT \\cite{guo2021graphcodebert} incorporates data-flow edges into pretraining, demonstrating that structural information improves code understanding tasks. These methods enrich the positive pair construction space or the pretraining signal. While GraphCodeBERT uses structural edges as a pretraining objective, StructFuse addresses a complementary dimension: rather than improving how positive pairs are constructed, we improve which negatives the model trains against by grounding selection in inter-procedural data-flow structure.\n\n## 2.3 Hard Negative Mining\n\nThe quality of negative examples critically affects contrastive learning \\cite{chen2020simclr}. In dense text retrieval, DPR \\cite{karpukhin2020dpr} established the practice of using BM25 top-ranked non-relevant passages as hard negatives. ANCE \\cite{xiong2021ance} dynamically mines negatives from an approximate nearest neighbor index updated during training, while RocketQA \\cite{qu2021rocketqa} introduces cross-batch denoised negatives with knowledge distillation. STAR \\cite{zhan2021star} further refines this paradigm by using the retriever's own top-ranked passages as training negatives. Curriculum-based approaches---CL-DRD \\cite{zeng2022cldrd} and CAPSTONE \\cite{he2023capstone}---schedule negative difficulty progressively during training.\n\nIn the code domain, CoCoHaNeRe \\cite{fan2025cocohanere} proposes gradient-based hard negative mining for code search, evaluating both BM25-selected and embedding-based negatives and reporting limitations of each non-differentiable strategy. However, their evaluation targets the NL$\\to$code search setting; whether static embedding-distance mining is similarly limited in structural code retrieval---where repository-level and file-level localization involve richer structural cues---remains untested. StructFuse addresses this gap with a systematic comparison of three mining strategies---random, embedding-distance, and dataflow-aware---across decoder-only encoders with distinct representation geometries. Our results show that static embedding-distance mining provides consistent retrieval gains at negligible cost, establishing it as a strong baseline that requires no gradient computation or dynamic index updates. We further introduce data-flow structure as an orthogonal signal for negative selection, grounding hardness in inter-procedural program semantics rather than embedding proximity alone.\n\n## 2.4 Code Structure in Machine Learning\n\nProgram dependence graphs \\cite{ferrante1987pdg} and code property graphs \\cite{yamaguchi2014cpg} have long served program analysis; tools like CodeQL \\cite{avgustinov2016ql} make inter-procedural analysis accessible at scale. In machine learning, code2vec \\cite{alon2019code2vec} pioneered learning from AST paths, while ProGraML \\cite{cummins2021programl} demonstrated that whole-program graph representations capturing control-flow, data-flow, and call relations are learnable and effective for compiler optimization tasks. CrossCodeEval \\cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements. RepoFusion \\cite{shrivastava2023repofusion} further demonstrates that training code models to incorporate cross-file repository context via Fusion-in-Decoder significantly improves completion quality, even outperforming much larger models that lack repository awareness.\n\nRecent inference-time graph methods bring structural reasoning to LLM-based software engineering. CodexGraph \\cite{liu2025codexgraph} and RepoGraph \\cite{ouyang2025repograph} build navigable code graph databases for LLM agents; LocAgent \\cite{chen2025locagent} and RANGER \\cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder \\cite{liu2024graphcoder} and ARISE \\cite{seddik2026arise} incorporate data-flow edges---control/data dependence and definition-use chains, respectively---but their data-flow analysis remains intra-procedural in scope. Critically, these methods primarily leverage structural graphs at inference time, incurring per-query latency proportional to graph complexity. StructFuse takes a fundamentally different approach: we leverage inter-procedural data-flow graphs at \\emph{training time} to mine structure-grounded negatives, producing an encoder that internalizes cross-function data-flow semantics with zero inference overhead. The two paradigms are complementary---a StructFuse-trained encoder can serve as an efficient first-stage retriever for inference-time graph systems that perform targeted reranking.\n",
    "structuredPatch": [
      {
        "oldStart": 18,
        "oldLines": 4,
        "newStart": 18,
        "newLines": 4,
        "lines": [
          " ",
          " Program dependence graphs \\cite{ferrante1987pdg} and code property graphs \\cite{yamaguchi2014cpg} have long served program analysis; tools like CodeQL \\cite{avgustinov2016ql} make inter-procedural analysis accessible at scale. In machine learning, code2vec \\cite{alon2019code2vec} pioneered learning from AST paths, while ProGraML \\cite{cummins2021programl} demonstrated that whole-program graph representations capturing control-flow, data-flow, and call relations are learnable and effective for compiler optimization tasks. CrossCodeEval \\cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements. RepoFusion \\cite{shrivastava2023repofusion} further demonstrates that training code models to incorporate cross-file repository context via Fusion-in-Decoder significantly improves completion quality, even outperforming much larger models that lack repository awareness.",
          " ",
          "-Recent inference-time graph methods bring structural reasoning to LLM-based software engineering. CodexGraph \\cite{liu2025codexgraph} and RepoGraph \\cite{ouyang2025repograph} build navigable code graph databases for LLM agents; LocAgent \\cite{chen2025locagent} and RANGER \\cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GraphCoder \\cite{liu2024graphcoder} and ARISE \\cite{seddik2026arise} incorporate data-flow edges---control/data dependence and definition-use chains, respectively---but their data-flow analysis remains intra-procedural in scope. Critically, these methods primarily leverage structural graphs at inference time, incurring per-query latency proportional to graph complexity. StructFuse takes a fundamentally different approach: we leverage inter-procedural data-flow graphs at \\emph{training time} to mine structure-grounded negatives, producing an encoder that internalizes cross-function data-flow semantics with zero inference overhead. The two paradigms are complementary---a StructFuse-trained encoder can serve as an efficient first-stage retriever for inference-time graph systems that perform targeted reranking.",
          "+Recent inference-time graph methods bring structural reasoning to LLM-based software engineering. CodexGraph \\cite{liu2025codexgraph} and RepoGraph \\cite{ouyang2025repograph} build navigable code graph databases for LLM agents; LocAgent \\cite{chen2025locagent} and RANGER \\cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GRACE \\cite{wang2025grace} constructs multi-level code graphs spanning repository, module, and function granularity---integrating AST, control-flow, and data-flow edges---for hierarchical retrieval-augmented code completion. GraphCoder \\cite{liu2024graphcoder} and ARISE \\cite{seddik2026arise} incorporate data-flow edges---control/data dependence and definition-use chains, respectively---but their data-flow analysis remains intra-procedural in scope. Critically, these methods primarily leverage structural graphs at inference time, incurring per-query latency proportional to graph complexity. StructFuse takes a fundamentally different approach: we leverage inter-procedural data-flow graphs at \\emph{training time} to mine structure-grounded negatives, producing an encoder that internalizes cross-function data-flow semantics with zero inference overhead. The two paradigms are complementary---a StructFuse-trained encoder can serve as an efficient first-stage retriever for inference-time graph systems that perform targeted reranking."
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

_source line 44_

Now adding the two new bib entries to references.bib.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "486148f8-e629-4f16-8386-91a9f3bc7dc5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NLDLzRAix1UwaxEZ16uB9H",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4596,
      "cache_read_input_tokens": 40704,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4596
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

_source line 45_

<details open><summary>🔧 Tool call — Edit · `toolu_01KqTabMvbDM5T5Bpasjziju`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/references.bib",
  "old_string": "% =============================================================================\n% Section 2.4: Code Structure Analysis\n% =============================================================================",
  "new_string": "@article{shrivastava2023repofusion,\n  title={{RepoFusion}: Training Code Models to Understand Your Repository},\n  author={Shrivastava, Disha and Kocetkov, Denis and de Vries, Harm and Bahdanau, Dzmitry and Scholak, Torsten},\n  journal={arXiv preprint arXiv:2306.10998},\n  year={2023}\n}\n\n@article{wang2025grace,\n  title={{GRACE}: Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion},\n  author={Wang, Xingliang and Wang, Baoyi and Zhi, Chen and Han, Junxiao and Zhao, Xinkui and Yin, Jianwei and Deng, Shuiguang},\n  journal={arXiv preprint arXiv:2509.05980},\n  year={2025}\n}\n\n% =============================================================================\n% Section 2.4: Code Structure Analysis\n% ============================================================================="
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "a99712a2-3985-4743-9c67-6a66c77acbef",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01NLDLzRAix1UwaxEZ16uB9H",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 4596,
      "cache_read_input_tokens": 40704,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 4596
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

_source line 46 · 2026-05-15T10:22:09.492Z_

<details><summary>↩ Tool result · `toolu_01KqTabMvbDM5T5Bpasjziju`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/references.bib has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "7088a3a8-f815-4d96-b12a-65473871b709",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/references.bib",
    "oldString": "% =============================================================================\n% Section 2.4: Code Structure Analysis\n% =============================================================================",
    "newString": "@article{shrivastava2023repofusion,\n  title={{RepoFusion}: Training Code Models to Understand Your Repository},\n  author={Shrivastava, Disha and Kocetkov, Denis and de Vries, Harm and Bahdanau, Dzmitry and Scholak, Torsten},\n  journal={arXiv preprint arXiv:2306.10998},\n  year={2023}\n}\n\n@article{wang2025grace,\n  title={{GRACE}: Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion},\n  author={Wang, Xingliang and Wang, Baoyi and Zhi, Chen and Han, Junxiao and Zhao, Xinkui and Yin, Jianwei and Deng, Shuiguang},\n  journal={arXiv preprint arXiv:2509.05980},\n  year={2025}\n}\n\n% =============================================================================\n% Section 2.4: Code Structure Analysis\n% =============================================================================",
    "originalFile": "% =============================================================================\n% Section 1: Introduction\n% =============================================================================\n\n@inproceedings{jimenez2024swebench,\n  title={{SWE-bench}: Can Language Models Resolve Real-World {GitHub} Issues?},\n  author={Jimenez, Carlos E. and Yang, John and Wettig, Alexander and Yao, Shunyu and Pei, Kexin and Press, Ofir and Narasimhan, Karthik},\n  booktitle={Proceedings of the Twelfth International Conference on Learning Representations (ICLR)},\n  year={2024}\n}\n\n% =============================================================================\n% Section 2.1: Code Retrieval Methods\n% =============================================================================\n\n@article{robertson2009bm25,\n  title={The Probabilistic Relevance Framework: {BM25} and Beyond},\n  author={Robertson, Stephen and Zaragoza, Hugo},\n  journal={Foundations and Trends in Information Retrieval},\n  volume={3},\n  number={4},\n  pages={333--389},\n  year={2009},\n  publisher={Now Publishers}\n}\n\n@inproceedings{karpukhin2020dpr,\n  title={Dense Passage Retrieval for Open-Domain Question Answering},\n  author={Karpukhin, Vladimir and O{\\u{g}}uz, Barlas and Min, Sewon and Lewis, Patrick and Wu, Ledell and Edunov, Sergey and Chen, Danqi and Yih, Wen-tau},\n  booktitle={Proceedings of the 2020 Conference on Empirical Methods in Natural Language Processing (EMNLP)},\n  pages={6769--6781},\n  year={2020}\n}\n\n@article{reddy2025swerank,\n  title={{SweRank}: Software Issue Localization with Code Ranking},\n  author={Gangi Reddy, Revanth and Suresh, Tarun and Doo, JaeHyeok and Liu, Ye and Nguyen, Xuan Phi and Zhou, Yingbo and Yavuz, Semih and Xiong, Caiming and Ji, Heng and Joty, Shafiq},\n  journal={arXiv preprint arXiv:2505.07849},\n  year={2025}\n}\n\n@inproceedings{xie2025swefixer,\n  title={{SWE-Fixer}: Training Open-Source {LLM}s for Effective and Efficient {GitHub} Issue Resolution},\n  author={Xie, Chengxing and Li, Bowen and Gao, Chang and Du, He and Lam, Wai and Zou, Difan and Chen, Kai},\n  booktitle={Findings of the Association for Computational Linguistics: ACL 2025},\n  pages={1123--1139},\n  year={2025}\n}\n\n@inproceedings{chen2025locagent,\n  title={{LocAgent}: Graph-Guided {LLM} Agents for Code Localization},\n  author={Chen, Zhaoling and Tang, Robert and Deng, Gangda and Wu, Fang and Wu, Jialong and Jiang, Zhiwei and Prasanna, Viktor and Cohan, Arman and Wang, Xingyao},\n  booktitle={Proceedings of the 63rd Annual Meeting of the Association for Computational Linguistics (ACL)},\n  pages={8697--8727},\n  year={2025}\n}\n\n@article{shah2025ranger,\n  title={{RANGER}: Repository-Level Agent for Graph-Enhanced Retrieval},\n  author={Shah, Pratik and Ghosh, Rajat and Singhal, Aryan and Dutta, Debojyoti},\n  journal={arXiv preprint arXiv:2509.25257},\n  year={2025}\n}\n\n@inproceedings{liu2025codexgraph,\n  title={{CodexGraph}: Bridging Large Language Models and Code Repositories via Code Graph Databases},\n  author={Liu, Xiangyan and Lan, Bo and Hu, Zhiyuan and Liu, Yang and Zhang, Zhicheng and Wang, Fei and Shieh, Michael Qizhe and Zhou, Wenmeng},\n  booktitle={Proceedings of the 2025 Conference of the North American Chapter of the Association for Computational Linguistics (NAACL)},\n  pages={142--160},\n  year={2025}\n}\n\n@inproceedings{ouyang2025repograph,\n  title={{RepoGraph}: Enhancing {AI} Software Engineering with Repository-level Code Graph},\n  author={Ouyang, Siru and Yu, Wenhao and Ma, Kaixin and Xiao, Zilin and Zhang, Zhihan and Jia, Mengzhao and Han, Jiawei and Zhang, Hongming and Yu, Dong},\n  booktitle={Proceedings of the Thirteenth International Conference on Learning Representations (ICLR)},\n  year={2025}\n}\n\n@inproceedings{liu2024graphcoder,\n  title={{GraphCoder}: Enhancing Repository-Level Code Completion via Code Context Graph-based Retrieval and Language Model},\n  author={Liu, Wei and Hu, Ailun and Li, Yixuan and Li, Yichen and Liu, Haoyu and Yang, Leyi},\n  booktitle={Proceedings of the 39th IEEE/ACM International Conference on Automated Software Engineering (ASE)},\n  year={2024}\n}\n\n@article{seddik2026arise,\n  title={{ARISE}: A Repository-level Graph Representation and Toolset for Agentic Fault Localization and Program Repair},\n  author={Seddik, Shahd and Fard, Fatemeh},\n  journal={arXiv preprint arXiv:2605.03117},\n  year={2026}\n}\n\n% =============================================================================\n% Section 2.2: Pre-trained Code Representations and Contrastive Learning\n% =============================================================================\n\n@inproceedings{feng2020codebert,\n  title={{CodeBERT}: A Pre-Trained Model for Programming and Natural Languages},\n  author={Feng, Zhangyin and Guo, Daya and Tang, Duyu and Duan, Nan and Feng, Xiaocheng and Gong, Ming and Shou, Linjun and Qin, Bing and Liu, Ting and Jiang, Daxin and Zhou, Ming},\n  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2020},\n  pages={1536--1547},\n  year={2020}\n}\n\n@inproceedings{guo2021graphcodebert,\n  title={{GraphCodeBERT}: Pre-training Code Representations with Data Flow},\n  author={Guo, Daya and Ren, Shuo and Lu, Shuai and Feng, Zhangyin and Tang, Duyu and Liu, Shujie and Zhou, Long and Duan, Nan and Svyatkovskiy, Alexey and Fu, Shengyu and Tufano, Michele and Deng, Shuai Kim and Clement, Colin and Drain, Dawn and Sundaresan, Neel and Yin, Jian and Jiang, Daxin and Zhou, Ming},\n  booktitle={Proceedings of the Ninth International Conference on Learning Representations (ICLR)},\n  year={2021}\n}\n\n@inproceedings{guo2022unixcoder,\n  title={{UniXcoder}: Unified Cross-Modal Pre-training for Code Representation},\n  author={Guo, Daya and Lu, Shuai and Duan, Nan and Wang, Yanlin and Zhou, Ming and Yin, Jian},\n  booktitle={Proceedings of the 60th Annual Meeting of the Association for Computational Linguistics (ACL)},\n  pages={7212--7225},\n  year={2022}\n}\n\n@inproceedings{alon2019code2vec,\n  title={code2vec: Learning Distributed Representations of Code},\n  author={Alon, Uri and Zilberstein, Meital and Levy, Omer and Yahav, Eran},\n  booktitle={Proceedings of the ACM on Programming Languages (POPL)},\n  volume={3},\n  pages={1--29},\n  year={2019}\n}\n\n@inproceedings{zhang2024codesage,\n  title={Code Representation Learning At Scale},\n  author={Zhang, Dejiao and Ahmad, Wasi Uddin and Tan, Ming and Ding, Hantian and Nallapati, Ramesh and Roth, Dan and Ma, Xiaofei and Xiang, Bing},\n  booktitle={Proceedings of the Twelfth International Conference on Learning Representations (ICLR)},\n  year={2024}\n}\n\n@inproceedings{reimers2019sentencebert,\n  title={Sentence-{BERT}: Sentence Embeddings using Siamese {BERT}-Networks},\n  author={Reimers, Nils and Gurevych, Iryna},\n  booktitle={Proceedings of the 2019 Conference on Empirical Methods in Natural Language Processing (EMNLP)},\n  pages={3982--3992},\n  year={2019}\n}\n\n@inproceedings{jain2021contracode,\n  title={Contrastive Code Representation Learning},\n  author={Jain, Paras and Jain, Ajil and Zhang, Tianjun and Abbeel, Pieter and Gonzalez, Joseph and Stoica, Ion},\n  booktitle={Proceedings of the 2021 Conference on Empirical Methods in Natural Language Processing (EMNLP)},\n  pages={5954--5971},\n  year={2021}\n}\n\n@inproceedings{li2022coderetriever,\n  title={{CodeRetriever}: A Large Scale Contrastive Pre-Training Method for Code Search},\n  author={Li, Xiaonan and Gong, Yeyun and Shen, Yelong and Qiu, Xipeng and Zhang, Hang and Yao, Bolun and Qi, Weizhen and Jiang, Daxin and Chen, Weizhu and Duan, Nan},\n  booktitle={Proceedings of the 2022 Conference on Empirical Methods in Natural Language Processing (EMNLP)},\n  pages={2898--2910},\n  year={2022}\n}\n\n@inproceedings{li2022scoder,\n  title={Soft-Labeled Contrastive Pre-training for Function-level Code Representation},\n  author={Li, Xiaonan and Guo, Daya and Gong, Yeyun and Lin, Yun and Shen, Yelong and Qiu, Xipeng and Jiang, Daxin and Chen, Weizhu and Duan, Nan},\n  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2022},\n  year={2022}\n}\n\n@inproceedings{ding2022programcontrasts,\n  title={Towards Learning (Dis)-Similarity of Source Code from Program Contrasts},\n  author={Ding, Yangruibo and Buratti, Luca and Pujar, Saurabh and Morari, Alessandro and Ray, Baishakhi and Parthasarathy, Saikat},\n  booktitle={Proceedings of the 60th Annual Meeting of the Association for Computational Linguistics (ACL)},\n  pages={6300--6312},\n  year={2022}\n}\n\n@inproceedings{bui2021infercode,\n  title={{InferCode}: Self-Supervised Learning of Code Representations by Predicting Subtrees},\n  author={Bui, Nghi D. Q. and Yu, Yijun and Jiang, Lingxiao},\n  booktitle={Proceedings of the 43rd IEEE/ACM International Conference on Software Engineering (ICSE)},\n  pages={1186--1197},\n  year={2021}\n}\n\n@article{lozhkov2024starcoder2,\n  title={{StarCoder} 2 and {The Stack} v2: The Next Generation},\n  author={Lozhkov, Anton and Li, Raymond and Ben Allal, Loubna and Cassano, Federico and Lamy-Poirier, Joel and Tazi, Nouamane and Tang, Ao and Pykhtar, Dmytro and Liu, Jiawei and Wei, Yuxiang and others},\n  journal={arXiv preprint arXiv:2402.19173},\n  year={2024}\n}\n\n@article{hui2024qwen25coder,\n  title={{Qwen2.5-Coder} Technical Report},\n  author={Hui, Binyuan and Yang, Jian and Cui, Zeyu and Yang, Jiaxi and Liu, Dayiheng and Zhang, Lei and Liu, Tianyu and Zhang, Jiajun and Yu, Bowen and Lu, Keming and Dang, Kai and Fan, Yang and Zhang, Yichang and Yang, An and Men, Rui and Huang, Fei and Zheng, Bo and others},\n  journal={arXiv preprint arXiv:2409.12186},\n  year={2024}\n}\n\n% =============================================================================\n% Section 2.3: Hard Negative Mining\n% =============================================================================\n\n@inproceedings{chen2020simclr,\n  title={A Simple Framework for Contrastive Learning of Visual Representations},\n  author={Chen, Ting and Kornblith, Simon and Norouzi, Mohammad and Hinton, Geoffrey},\n  booktitle={Proceedings of the 37th International Conference on Machine Learning (ICML)},\n  pages={1597--1607},\n  year={2020}\n}\n\n@inproceedings{xiong2021ance,\n  title={Approximate Nearest Neighbor Negative Contrastive Learning for Dense Text Retrieval},\n  author={Xiong, Lee and Xiong, Chenyan and Li, Ye and Tang, Kwok-Fung and Liu, Jialin and Bennett, Paul and Ahmed, Junaid and Overwijk, Arnold},\n  booktitle={Proceedings of the Ninth International Conference on Learning Representations (ICLR)},\n  year={2021}\n}\n\n@inproceedings{zhan2021star,\n  title={Optimizing Dense Retrieval Model Training with Hard Negatives},\n  author={Zhan, Jingtao and Mao, Jiaxin and Liu, Yiqun and Guo, Jiafeng and Zhang, Min and Ma, Shaoping},\n  booktitle={Proceedings of the 44th International ACM SIGIR Conference on Research and Development in Information Retrieval},\n  pages={1503--1512},\n  year={2021}\n}\n\n@inproceedings{qu2021rocketqa,\n  title={{RocketQA}: An Optimized Training Approach to Dense Passage Retrieval for Open-Domain Question Answering},\n  author={Qu, Yingqi and Ding, Yuchen and Liu, Jing and Liu, Kai and Ren, Ruiyang and Zhao, Wayne Xin and Dong, Daxiang and Wu, Hua and Wang, Haifeng},\n  booktitle={Proceedings of the 2021 Conference of the North American Chapter of the Association for Computational Linguistics (NAACL-HLT)},\n  pages={5835--5847},\n  year={2021}\n}\n\n@inproceedings{zeng2022cldrd,\n  title={Curriculum Learning for Dense Retrieval Distillation},\n  author={Zeng, Hansi and Zamani, Hamed and Vinay, Vishwa},\n  booktitle={Proceedings of the 45th International ACM SIGIR Conference on Research and Development in Information Retrieval},\n  pages={1979--1983},\n  year={2022}\n}\n\n@article{fan2025cocohanere,\n  title={Effective Hard Negative Mining for Contrastive Learning-Based Code Search},\n  author={Fan, Ye and Li, Chuanyi and Ge, Jidong and Huang, LiGuo and Luo, Bin},\n  journal={ACM Transactions on Software Engineering and Methodology},\n  volume={34},\n  number={3},\n  year={2025},\n  publisher={ACM}\n}\n\n% =============================================================================\n% Section 2.4: Code Structure Analysis\n% =============================================================================\n\n@article{ferrante1987pdg,\n  title={The Program Dependence Graph and Its Use in Optimization},\n  author={Ferrante, Jeanne and Ottenstein, Karl J. and Warren, Joe D.},\n  journal={ACM Transactions on Programming Languages and Systems},\n  volume={9},\n  number={3},\n  pages={319--349},\n  year={1987},\n  publisher={ACM}\n}\n\n@inproceedings{yamaguchi2014cpg,\n  title={Modeling and Discovering Vulnerabilities with Code Property Graphs},\n  author={Yamaguchi, Fabian and Golde, Nico and Arp, Daniel and Rieck, Konrad},\n  booktitle={Proceedings of the 2014 IEEE Symposium on Security and Privacy (S\\&P)},\n  pages={590--604},\n  year={2014},\n  publisher={IEEE}\n}\n\n@inproceedings{avgustinov2016ql,\n  title={{QL}: Object-oriented Queries on Relational Data},\n  author={Avgustinov, Pavel and de Moor, Oege and Jones, Michael Peyton and Sch{\\\"a}fer, Max},\n  booktitle={30th European Conference on Object-Oriented Programming (ECOOP)},\n  series={LIPIcs},\n  volume={56},\n  pages={2:1--2:25},\n  year={2016}\n}\n\n% =============================================================================\n% Section 3: Method\n% =============================================================================\n\n@inproceedings{hu2022lora,\n  title={{LoRA}: Low-Rank Adaptation of Large Language Models},\n  author={Hu, Edward J. and Shen, Yelong and Wallis, Phillip and Allen-Zhu, Zeyuan and Li, Yuanzhi and Wang, Shean and Wang, Lu and Chen, Weizhu},\n  booktitle={Proceedings of the Tenth International Conference on Learning Representations (ICLR)},\n  year={2022}\n}\n\n@article{oord2018representation,\n  title={Representation Learning with Contrastive Predictive Coding},\n  author={van den Oord, A{\\\"a}ron and Li, Yazhe and Vinyals, Oriol},\n  journal={arXiv preprint arXiv:1807.03748},\n  year={2018}\n}\n\n% =============================================================================\n% Supplement: New citations added 2026-05-15\n% =============================================================================\n\n@article{wang2021syncobert,\n  title={{SynCoBERT}: Syntax-Guided Multi-Modal Contrastive Pre-Training for Code Representation},\n  author={Wang, Xin and Wang, Yasheng and Mi, Fei and Zhou, Pingyi and Wan, Yao and Liu, Xiao and Li, Li and Wu, Hao and Liu, Jin and Jiang, Xin},\n  journal={arXiv preprint arXiv:2108.04556},\n  year={2021}\n}\n\n@inproceedings{liu2023contrabert,\n  title={{ContraBERT}: Enhancing Code Pre-trained Models via Contrastive Learning},\n  author={Liu, Shangqing and Wu, Bozhi and Xie, Xiaofei and Meng, Guozhu and Liu, Yang},\n  booktitle={Proceedings of the 45th IEEE/ACM International Conference on Software Engineering (ICSE)},\n  pages={2476--2487},\n  year={2023}\n}\n\n@inproceedings{he2023capstone,\n  title={{CAPSTONE}: Curriculum Sampling for Dense Retrieval with Document Expansion},\n  author={He, Xingwei and Gong, Yeyun and Jin, A-Long and Zhang, Hang and Dong, Anlei and Jiao, Jian and Yiu, Siu Ming and Duan, Nan},\n  booktitle={Proceedings of the 2023 Conference on Empirical Methods in Natural Language Processing (EMNLP)},\n  pages={10531--10541},\n  year={2023}\n}\n\n@inproceedings{ding2023crosscodeeval,\n  title={{CrossCodeEval}: A Diverse and Multilingual Benchmark for Cross-File Code Completion},\n  author={Ding, Yangruibo and Wang, Zijian and Ahmad, Wasi Uddin and Ding, Hantian and Tan, Ming and Jain, Nihal and Ramanathan, Murali Krishna and Nallapati, Ramesh and Bhatia, Parminder and Roth, Dan and Xiang, Bing},\n  booktitle={Advances in Neural Information Processing Systems 36 (NeurIPS)},\n  year={2023}\n}\n\n@inproceedings{cummins2021programl,\n  title={{ProGraML}: A Graph-based Program Representation for Data Flow Analysis and Compiler Optimizations},\n  author={Cummins, Chris and Fisches, Zacharias V. and Ben-Nun, Tal and Hoefler, Torsten and O'Boyle, Michael F. P. and Leather, Hugh},\n  booktitle={Proceedings of the 38th International Conference on Machine Learning (ICML)},\n  pages={2244--2253},\n  year={2021},\n  publisher={PMLR}\n}\n\n@inproceedings{huang2021cosqa,\n  title={{CoSQA}: 20,000+ Web Queries for Code Search and Question Answering},\n  author={Huang, Junjie and Tang, Duyu and Shou, Linjun and Gong, Ming and Xu, Ke and Jiang, Daxin and Zhou, Ming and Duan, Nan},\n  booktitle={Proceedings of the 59th Annual Meeting of the Association for Computational Linguistics (ACL)},\n  pages={5690--5700},\n  year={2021}\n}\n",
    "structuredPatch": [
      {
        "oldStart": 248,
        "oldLines": 6,
        "newStart": 248,
        "newLines": 20,
        "lines": [
          "   publisher={ACM}",
          " }",
          " ",
          "+@article{shrivastava2023repofusion,",
          "+  title={{RepoFusion}: Training Code Models to Understand Your Repository},",
          "+  author={Shrivastava, Disha and Kocetkov, Denis and de Vries, Harm and Bahdanau, Dzmitry and Scholak, Torsten},",
          "+  journal={arXiv preprint arXiv:2306.10998},",
          "+  year={2023}",
          "+}",
          "+",
          "+@article{wang2025grace,",
          "+  title={{GRACE}: Graph-Guided Repository-Aware Code Completion through Hierarchical Code Fusion},",
          "+  author={Wang, Xingliang and Wang, Baoyi and Zhi, Chen and Han, Junxiao and Zhao, Xinkui and Yin, Jianwei and Deng, Shuiguang},",
          "+  journal={arXiv preprint arXiv:2509.05980},",
          "+  year={2025}",
          "+}",
          "+",
          " % =============================================================================",
          " % Section 2.4: Code Structure Analysis",
          " % ============================================================================="
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

_source line 47_

Let me verify the final state of both files.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "55d61c36-d9d4-429d-b3dc-2ee6e5b27ca9",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AHRUQfNC3BUjhBupsz9jLW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 593,
      "cache_read_input_tokens": 45300,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 593
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

_source line 48_

<details open><summary>🔧 Tool call — Read · `toolu_01DLgWz9VtQYRiXPP8z2C7p9`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "9645e18a-e1d6-4bf4-9722-65db79ebe1e5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01AHRUQfNC3BUjhBupsz9jLW",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 593,
      "cache_read_input_tokens": 45300,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 593
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

_source line 49 · 2026-05-15T10:22:12.579Z_

<details><summary>↩ Tool result · `toolu_01DLgWz9VtQYRiXPP8z2C7p9`</summary>

```text
1	# 2. Related Work
2	
3	## 2.1 Dense Retrieval for Code
4	
5	Code retrieval has evolved from sparse lexical methods such as BM25 \cite{robertson2009bm25} to dense neural approaches. Early pretrained code models---CodeBERT \cite{feng2020codebert}, UniXcoder \cite{guo2022unixcoder}, and InferCode \cite{bui2021infercode}---learn general-purpose code representations through masked language modeling and related pretraining objectives, enabling semantic matching beyond surface-level token overlap. More recent large-scale code models, including StarCoder2 \cite{lozhkov2024starcoder2} and Qwen2.5-Coder \cite{hui2024qwen25coder}, provide powerful encoder backbones trained on trillions of code tokens. In the retrieval domain, CodeSage \cite{zhang2024codesage} and SCodeR \cite{li2022scoder} introduce contrastive fine-tuning strategies that adapt pretrained representations for code search. The growing importance of repository-level retrieval---driven by benchmarks like SWE-bench \cite{jimenez2024swebench}---has motivated specialized systems: SweRank \cite{reddy2025swerank} formulates issue localization as code ranking, while SWE-Fixer \cite{xie2025swefixer} combines BM25 with neural reranking in a coarse-to-fine pipeline. StructFuse builds on this foundation by improving the contrastive fine-tuning stage: rather than modifying the retrieval architecture, we enhance the training signal through structure-grounded negative selection.
6	
7	## 2.2 Contrastive Learning for Code
8	
9	Sentence-BERT \cite{reimers2019sentencebert} established contrastive fine-tuning of pretrained encoders for dense text retrieval, a paradigm that has since become dominant for code representation learning. ContraCode \cite{jain2021contracode} generates functionally equivalent program variants through compiler transformations, training models to be invariant to syntactic variation. CodeRetriever \cite{li2022coderetriever} combines unimodal code-code and bimodal code-text contrastive objectives, achieving strong results across eleven code search benchmarks. SynCoBERT \cite{wang2021syncobert} introduces syntax-guided multi-modal contrastive pretraining that aligns code, natural language, and AST modalities through identifier prediction and edge prediction objectives. ContraBERT \cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. Ding et al.\ \cite{ding2022programcontrasts} use structure-guided code transformations to synthesize contrastive pairs, demonstrating that program-structure-aware augmentation improves code clone detection and vulnerability identification. GraphCodeBERT \cite{guo2021graphcodebert} incorporates data-flow edges into pretraining, demonstrating that structural information improves code understanding tasks. These methods enrich the positive pair construction space or the pretraining signal. While GraphCodeBERT uses structural edges as a pretraining objective, StructFuse addresses a complementary dimension: rather than improving how positive pairs are constructed, we improve which negatives the model trains against by grounding selection in inter-procedural data-flow structure.
10	
11	## 2.3 Hard Negative Mining
12	
13	The quality of negative examples critically affects contrastive learning \cite{chen2020simclr}. In dense text retrieval, DPR \cite{karpukhin2020dpr} established the practice of using BM25 top-ranked non-relevant passages as hard negatives. ANCE \cite{xiong2021ance} dynamically mines negatives from an approximate nearest neighbor index updated during training, while RocketQA \cite{qu2021rocketqa} introduces cross-batch denoised negatives with knowledge distillation. STAR \cite{zhan2021star} further refines this paradigm by using the retriever's own top-ranked passages as training negatives. Curriculum-based approaches---CL-DRD \cite{zeng2022cldrd} and CAPSTONE \cite{he2023capstone}---schedule negative difficulty progressively during training.
14	
15	In the code domain, CoCoHaNeRe \cite{fan2025cocohanere} proposes gradient-based hard negative mining for code search, evaluating both BM25-selected and embedding-based negatives and reporting limitations of each non-differentiable strategy. However, their evaluation targets the NL$\to$code search setting; whether static embedding-distance mining is similarly limited in structural code retrieval---where repository-level and file-level localization involve richer structural cues---remains untested. StructFuse addresses this gap with a systematic comparison of three mining strategies---random, embedding-distance, and dataflow-aware---across decoder-only encoders with distinct representation geometries. Our results show that static embedding-distance mining provides consistent retrieval gains at negligible cost, establishing it as a strong baseline that requires no gradient computation or dynamic index updates. We further introduce data-flow structure as an orthogonal signal for negative selection, grounding hardness in inter-procedural program semantics rather than embedding proximity alone.
16	
17	## 2.4 Code Structure in Machine Learning
18	
19	Program dependence graphs \cite{ferrante1987pdg} and code property graphs \cite{yamaguchi2014cpg} have long served program analysis; tools like CodeQL \cite{avgustinov2016ql} make inter-procedural analysis accessible at scale. In machine learning, code2vec \cite{alon2019code2vec} pioneered learning from AST paths, while ProGraML \cite{cummins2021programl} demonstrated that whole-program graph representations capturing control-flow, data-flow, and call relations are learnable and effective for compiler optimization tasks. CrossCodeEval \cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements. RepoFusion \cite{shrivastava2023repofusion} further demonstrates that training code models to incorporate cross-file repository context via Fusion-in-Decoder significantly improves completion quality, even outperforming much larger models that lack repository awareness.
20	
21	Recent inference-time graph methods bring structural reasoning to LLM-based software engineering. CodexGraph \cite{liu2025codexgraph} and RepoGraph \cite{ouyang2025repograph} build navigable code graph databases for LLM agents; LocAgent \cite{chen2025locagent} and RANGER \cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GRACE \cite{wang2025grace} constructs multi-level code graphs spanning repository, module, and function granularity---integrating AST, control-flow, and data-flow edges---for hierarchical retrieval-augmented code completion. GraphCoder \cite{liu2024graphcoder} and ARISE \cite{seddik2026arise} incorporate data-flow edges---control/data dependence and definition-use chains, respectively---but their data-flow analysis remains intra-procedural in scope. Critically, these methods primarily leverage structural graphs at inference time, incurring per-query latency proportional to graph complexity. StructFuse takes a fundamentally different approach: we leverage inter-procedural data-flow graphs at \emph{training time} to mine structure-grounded negatives, producing an encoder that internalizes cross-function data-flow semantics with zero inference overhead. The two paradigms are complementary---a StructFuse-trained encoder can serve as an efficient first-stage retriever for inference-time graph systems that perform targeted reranking.
22	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "de9fe8c2-c537-4a64-8454-cfc598ad2cfd",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0509_5/projects/structfuse-context/artifacts/paper_drafts/related_work_v1.md",
      "content": "# 2. Related Work\n\n## 2.1 Dense Retrieval for Code\n\nCode retrieval has evolved from sparse lexical methods such as BM25 \\cite{robertson2009bm25} to dense neural approaches. Early pretrained code models---CodeBERT \\cite{feng2020codebert}, UniXcoder \\cite{guo2022unixcoder}, and InferCode \\cite{bui2021infercode}---learn general-purpose code representations through masked language modeling and related pretraining objectives, enabling semantic matching beyond surface-level token overlap. More recent large-scale code models, including StarCoder2 \\cite{lozhkov2024starcoder2} and Qwen2.5-Coder \\cite{hui2024qwen25coder}, provide powerful encoder backbones trained on trillions of code tokens. In the retrieval domain, CodeSage \\cite{zhang2024codesage} and SCodeR \\cite{li2022scoder} introduce contrastive fine-tuning strategies that adapt pretrained representations for code search. The growing importance of repository-level retrieval---driven by benchmarks like SWE-bench \\cite{jimenez2024swebench}---has motivated specialized systems: SweRank \\cite{reddy2025swerank} formulates issue localization as code ranking, while SWE-Fixer \\cite{xie2025swefixer} combines BM25 with neural reranking in a coarse-to-fine pipeline. StructFuse builds on this foundation by improving the contrastive fine-tuning stage: rather than modifying the retrieval architecture, we enhance the training signal through structure-grounded negative selection.\n\n## 2.2 Contrastive Learning for Code\n\nSentence-BERT \\cite{reimers2019sentencebert} established contrastive fine-tuning of pretrained encoders for dense text retrieval, a paradigm that has since become dominant for code representation learning. ContraCode \\cite{jain2021contracode} generates functionally equivalent program variants through compiler transformations, training models to be invariant to syntactic variation. CodeRetriever \\cite{li2022coderetriever} combines unimodal code-code and bimodal code-text contrastive objectives, achieving strong results across eleven code search benchmarks. SynCoBERT \\cite{wang2021syncobert} introduces syntax-guided multi-modal contrastive pretraining that aligns code, natural language, and AST modalities through identifier prediction and edge prediction objectives. ContraBERT \\cite{liu2023contrabert} takes a complementary robustness-oriented approach, designing adversarial augmentation operators---including identifier renaming, dead code insertion, and operand swapping---to improve model robustness while maintaining retrieval performance. Ding et al.\\ \\cite{ding2022programcontrasts} use structure-guided code transformations to synthesize contrastive pairs, demonstrating that program-structure-aware augmentation improves code clone detection and vulnerability identification. GraphCodeBERT \\cite{guo2021graphcodebert} incorporates data-flow edges into pretraining, demonstrating that structural information improves code understanding tasks. These methods enrich the positive pair construction space or the pretraining signal. While GraphCodeBERT uses structural edges as a pretraining objective, StructFuse addresses a complementary dimension: rather than improving how positive pairs are constructed, we improve which negatives the model trains against by grounding selection in inter-procedural data-flow structure.\n\n## 2.3 Hard Negative Mining\n\nThe quality of negative examples critically affects contrastive learning \\cite{chen2020simclr}. In dense text retrieval, DPR \\cite{karpukhin2020dpr} established the practice of using BM25 top-ranked non-relevant passages as hard negatives. ANCE \\cite{xiong2021ance} dynamically mines negatives from an approximate nearest neighbor index updated during training, while RocketQA \\cite{qu2021rocketqa} introduces cross-batch denoised negatives with knowledge distillation. STAR \\cite{zhan2021star} further refines this paradigm by using the retriever's own top-ranked passages as training negatives. Curriculum-based approaches---CL-DRD \\cite{zeng2022cldrd} and CAPSTONE \\cite{he2023capstone}---schedule negative difficulty progressively during training.\n\nIn the code domain, CoCoHaNeRe \\cite{fan2025cocohanere} proposes gradient-based hard negative mining for code search, evaluating both BM25-selected and embedding-based negatives and reporting limitations of each non-differentiable strategy. However, their evaluation targets the NL$\\to$code search setting; whether static embedding-distance mining is similarly limited in structural code retrieval---where repository-level and file-level localization involve richer structural cues---remains untested. StructFuse addresses this gap with a systematic comparison of three mining strategies---random, embedding-distance, and dataflow-aware---across decoder-only encoders with distinct representation geometries. Our results show that static embedding-distance mining provides consistent retrieval gains at negligible cost, establishing it as a strong baseline that requires no gradient computation or dynamic index updates. We further introduce data-flow structure as an orthogonal signal for negative selection, grounding hardness in inter-procedural program semantics rather than embedding proximity alone.\n\n## 2.4 Code Structure in Machine Learning\n\nProgram dependence graphs \\cite{ferrante1987pdg} and code property graphs \\cite{yamaguchi2014cpg} have long served program analysis; tools like CodeQL \\cite{avgustinov2016ql} make inter-procedural analysis accessible at scale. In machine learning, code2vec \\cite{alon2019code2vec} pioneered learning from AST paths, while ProGraML \\cite{cummins2021programl} demonstrated that whole-program graph representations capturing control-flow, data-flow, and call relations are learnable and effective for compiler optimization tasks. CrossCodeEval \\cite{ding2023crosscodeeval} empirically validates that cross-file context is critical for code completion, with retrieval-augmented approaches yielding clear but still far-from-ceiling improvements. RepoFusion \\cite{shrivastava2023repofusion} further demonstrates that training code models to incorporate cross-file repository context via Fusion-in-Decoder significantly improves completion quality, even outperforming much larger models that lack repository awareness.\n\nRecent inference-time graph methods bring structural reasoning to LLM-based software engineering. CodexGraph \\cite{liu2025codexgraph} and RepoGraph \\cite{ouyang2025repograph} build navigable code graph databases for LLM agents; LocAgent \\cite{chen2025locagent} and RANGER \\cite{shah2025ranger} employ multi-hop graph reasoning and MCTS-based traversal for fault localization and retrieval, respectively. GRACE \\cite{wang2025grace} constructs multi-level code graphs spanning repository, module, and function granularity---integrating AST, control-flow, and data-flow edges---for hierarchical retrieval-augmented code completion. GraphCoder \\cite{liu2024graphcoder} and ARISE \\cite{seddik2026arise} incorporate data-flow edges---control/data dependence and definition-use chains, respectively---but their data-flow analysis remains intra-procedural in scope. Critically, these methods primarily leverage structural graphs at inference time, incurring per-query latency proportional to graph complexity. StructFuse takes a fundamentally different approach: we leverage inter-procedural data-flow graphs at \\emph{training time} to mine structure-grounded negatives, producing an encoder that internalizes cross-function data-flow semantics with zero inference overhead. The two paradigms are complementary---a StructFuse-trained encoder can serve as an efficient first-stage retriever for inference-time graph systems that perform targeted reranking.\n",
      "numLines": 22,
      "startLine": 1,
      "totalLines": 22
    }
  }
}
```

</details>

---

### Assistant

_source line 50_

全部修改完成。修改摘要：

**修正 1 — §2.3 CoCoHaNeRe gap 表述**：替换了模糊的 "More broadly..." 句，改为明确指出 CoCoHaNeRe 的评估针对 NL→code search setting，在 structural code retrieval（repo-level/file-level localization）下 static embedding-distance mining 是否同样受限尚未被测试。同时覆盖了 BM25 和 embedding-based 两种非梯度策略的局限性，消除 Intro/RW 不一致。

**修正 2 — §2.3 StructFuse 定位扩充**：从 1 句扩展为 3 句，涵盖：(1) systematic comparison of three mining strategies across encoders with distinct representation geometries；(2) static embedding-distance mining 提供 consistent gains 作为 strong baseline，无需 gradient computation；(3) data-flow structure 作为 orthogonal signal，基于 inter-procedural program semantics。无 hedge 语言。

**修正 3 — 补充 RepoFusion + GRACE**：
- RepoFusion `\cite{shrivastava2023repofusion}` 加入 §2.4，紧接 CrossCodeEval 后，描述 cross-file context 训练对 code completion 的提升
- GRACE `\cite{wang2025grace}` 加入 §2.4 inference-time graph methods 段落，描述 multi-level code graph（repo/module/function 粒度）
- 两条新 bib 条目已加入 references.bib

**修正 4 — Sentence-BERT + Ding et al. 2022**：
- Sentence-BERT `\cite{reimers2019sentencebert}` 加在 §2.2 开头作为从 NLP 到代码对比学习的过渡桥梁（bib 条目已存在）
- Ding et al. `\cite{ding2022programcontrasts}` 加在 §2.2 ContraBERT 之后，描述 structure-guided code transformations 用于合成对比样本对（bib 条目已存在）

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "uuid": "bb1a86ce-a86a-4608-8882-bc91930168f3",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ven4RzuRUwbm2Co77y7W7y",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2011,
      "cache_read_input_tokens": 45893,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2011
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

_source line 51_

全部修改完成。修改摘要：

**修正 1 — §2.3 CoCoHaNeRe gap 表述**：替换了模糊的 "More broadly..." 句，改为明确指出 CoCoHaNeRe 的评估针对 NL→code search setting，在 structural code retrieval（repo-level/file-level localization）下 static embedding-distance mining 是否同样受限尚未被测试。同时覆盖了 BM25 和 embedding-based 两种非梯度策略的局限性，消除 Intro/RW 不一致。

**修正 2 — §2.3 StructFuse 定位扩充**：从 1 句扩展为 3 句，涵盖：(1) systematic comparison of three mining strategies across encoders with distinct representation geometries；(2) static embedding-distance mining 提供 consistent gains 作为 strong baseline，无需 gradient computation；(3) data-flow structure 作为 orthogonal signal，基于 inter-procedural program semantics。无 hedge 语言。

**修正 3 — 补充 RepoFusion + GRACE**：
- RepoFusion `\cite{shrivastava2023repofusion}` 加入 §2.4，紧接 CrossCodeEval 后，描述 cross-file context 训练对 code completion 的提升
- GRACE `\cite{wang2025grace}` 加入 §2.4 inference-time graph methods 段落，描述 multi-level code graph（repo/module/function 粒度）
- 两条新 bib 条目已加入 references.bib

**修正 4 — Sentence-BERT + Ding et al. 2022**：
- Sentence-BERT `\cite{reimers2019sentencebert}` 加在 §2.2 开头作为从 NLP 到代码对比学习的过渡桥梁（bib 条目已存在）
- Ding et al. `\cite{ding2022programcontrasts}` 加在 §2.2 ContraBERT 之后，描述 structure-guided code transformations 用于合成对比样本对（bib 条目已存在）

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 142720,
  "duration_api_ms": 165337,
  "num_turns": 18,
  "stop_reason": "end_turn",
  "session_id": "0dfddad6-dc5a-4cd1-9a9e-8de1d463040f",
  "total_cost_usd": 0.7255572500000002,
  "usage": {
    "input_tokens": 618,
    "cache_creation_input_tokens": 36063,
    "cache_read_input_tokens": 311783,
    "output_tokens": 7134,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 36063,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 598,
        "cache_read_input_tokens": 45893,
        "cache_creation_input_tokens": 2011,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 2011
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 90402,
      "outputTokens": 2486,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 6,
      "costUSD": 0.16283199999999998,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 618,
      "outputTokens": 7134,
      "cacheReadInputTokens": 311783,
      "cacheCreationInputTokens": 36063,
      "webSearchRequests": 0,
      "costUSD": 0.5627252500000001,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "08a74619-ef33-4a18-9010-517ce0f58c44"
}
```

</details>

---
