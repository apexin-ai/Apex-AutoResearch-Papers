# paper edit bib final proofread

**DisPeD: A Controlled Study of Encoder Adaptation for Multi-Turn Jailbreak Detection** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 33
- **Recorded user turns:** 0
- **Tool calls:** 10
- **Original source:** `logs/workers/worker_paper-edit_bib-final-proofread_20260521T230909.log`
- **Structured JSON:** [`0e4da9e49ab56bd08f08.json`](../../sessions/0e/0e4da9e49ab56bd08f08.json)

## Before a recorded user message

33 recorded events

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
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
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
  "uuid": "8368026d-a04f-4372-8463-ece0e1d6dfe0",
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
    "resetsAt": 1779417600,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "c5d133ef-8a68-46e1-82e1-5a4f4c8d14ed",
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024"
}
```

---

### Assistant

_source line 4_

I'll start by reading the relevant files in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "a0682ca4-f89c-4a4b-b258-61e64e2fb98a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017ZFcsTNJRpYKNEQpfWLcCG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12501,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12501
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

_source line 5_

<details open><summary>🔧 Tool call — Read · `toolu_01REhpCtSJqg6CwoAVvbgZSF`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/references.bib"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "1da97779-7536-4abf-86fa-f9b6529d7a73",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017ZFcsTNJRpYKNEQpfWLcCG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12501,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12501
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

_source line 6_

<details open><summary>🔧 Tool call — Glob · `toolu_01GA8dbKtfVoS4MRPwfhqmAH`</summary>

```json
{
  "pattern": "*.tex",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "34c0551c-2883-4763-9937-c8100b423cdb",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017ZFcsTNJRpYKNEQpfWLcCG",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12501,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12501
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

_source line 7 · 2026-05-21T23:09:23.276Z_

<details><summary>↩ Tool result · `toolu_01GA8dbKtfVoS4MRPwfhqmAH`</summary>

```text
docs/paper/main.tex
docs/paper/method.tex
docs/paper/checklist.tex
docs/paper/appendix.tex
docs/paper/abstract.tex
docs/paper/introduction.tex
docs/paper/related_work.tex
docs/paper/experiments.tex
docs/paper/conclusion.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "5eafc44d-ee49-4e9c-9a1c-c32f530fa5e9",
  "tool_use_result": {
    "filenames": [
      "docs/paper/main.tex",
      "docs/paper/method.tex",
      "docs/paper/checklist.tex",
      "docs/paper/appendix.tex",
      "docs/paper/abstract.tex",
      "docs/paper/introduction.tex",
      "docs/paper/related_work.tex",
      "docs/paper/experiments.tex",
      "docs/paper/conclusion.tex"
    ],
    "durationMs": 7,
    "numFiles": 9,
    "truncated": false
  }
}
```

</details>

---

### Tool result

_source line 8 · 2026-05-21T23:09:23.553Z_

<details><summary>↩ Tool result · `toolu_01REhpCtSJqg6CwoAVvbgZSF`</summary>

```text
1	% References for persuasion_turn_jailbreak_detect
2	% Auto-generated from literature_map.yaml (2026-05-18)
3	% Total entries: 31
4	
5	% ============================================================
6	% Category 1: Production Multi-Turn Safety Systems
7	% ============================================================
8	
9	@article{inan2023llamaguard,
10	  title={Llama Guard: LLM-based Input-Output Safeguard for Human-AI Conversations},
11	  author={Inan, Hakan and Upasani, Kartikeya and Chi, Jianfeng and Rungta, Rashi and Iyer, Krithika and Mao, Yuning and Tontchev, Michael and Hu, Qing and Fuller, Brian and Testuggine, Davide and Khabsa, Madian},
12	  journal={arXiv preprint},
13	  year={2023},
14	  eprint={2312.06674},
15	  archivePrefix={arXiv},
16	}
17	
18	@misc{metallamaguard3_2024,
19	  title={Llama Guard 3},
20	  author={{Meta AI}},
21	  year={2024},
22	  howpublished={Meta AI (released with Llama 3.1)},
23	}
24	
25	@article{zeng2024shieldgemma,
26	  title={ShieldGemma: Generative AI Content Moderation Based on Gemma},
27	  author={Zeng, Wenjun and Liu, Yuchi and Mullins, Ryan and Peran, Ludovic and Fernandez, Joe and Harkous, Hamza and Narasimhan, Karthik and Proud, Drew and Kumar, Piyush and Radharapu, Bhaktipriya and Sturman, Olivia and Wahltinez, Oscar},
28	  journal={arXiv preprint},
29	  year={2024},
30	  eprint={2407.21772},
31	  archivePrefix={arXiv},
32	}
33	
34	@inproceedings{han2024wildguard,
35	  title={WildGuard: Open One-Stop Moderation Tools for Safety Risks, Jailbreaks, and Refusals of LLMs},
36	  author={Han, Seungju and Rao, Kavel and Ettinger, Allyson and Jiang, Liwei and Lin, Bill Yuchen and Lambert, Nathan and Choi, Yejin and Dziri, Nouha},
37	  booktitle={Advances in Neural Information Processing Systems},
38	  year={2024},
39	}
40	
41	@techreport{anthropic2025constitutional,
42	  title={Constitutional Classifiers: Defending against Universal Jailbreaks across Thousands of Hours of Red Teaming},
43	  author={Sharma, Mrinank and Tong, Meg and Mu, Jesse and Korbak, Tomek and others},
44	  institution={Anthropic},
45	  year={2025},
46	  eprint={2501.18837},
47	  archivePrefix={arXiv},
48	}
49	
50	% ============================================================
51	% Category 2: Multi-Turn Jailbreak Defenses
52	% ============================================================
53	
54	@article{deepcontext2026,
55	  title={DeepContext: Stateful Real-Time Detection of Multi-Turn Adversarial Intent Drift in LLMs},
56	  author={Albrethsen, Justin and Datta, Yash and Kumar, Kunal and Rajasekar, Sharath},
57	  journal={arXiv preprint},
58	  year={2026},
59	  eprint={2602.16935},
60	  archivePrefix={arXiv},
61	}
62	
63	@article{tong2025biid,
64	  title={Bidirectional Intention Inference Enhances LLMs' Defense Against Multi-Turn Jailbreak Attacks},
65	  author={Tong, Haibo and Zhao, Dongcheng and Shen, Guobin and He, Xiang and Lin, Dachuan and Zhao, Feifei and Zeng, Yi},
66	  journal={arXiv preprint},
67	  year={2025},
68	  eprint={2509.22732},
69	  archivePrefix={arXiv},
70	}
71	
72	@article{gguard2025,
73	  title={An Attention-Aware GNN-Based Input Defender Against Multi-Turn Jailbreak on LLMs},
74	  author={Huang, Zixuan and Huang, Kecheng and Yin, Lihao and He, Bowei and Zhen, Huiling and Yuan, Mingxuan and Shao, Zili},
75	  journal={arXiv preprint},
76	  year={2025},
77	  eprint={2507.07146},
78	  archivePrefix={arXiv},
79	}
80	
81	@article{safedream2026,
82	  title={SafeDream: Safety World Model for Proactive Early Jailbreak Detection},
83	  author={Yan, Bo and Lin, Weikai and Zhu, Yada and Wang, Song},
84	  journal={arXiv preprint},
85	  year={2026},
86	  eprint={2604.16824},
87	  archivePrefix={arXiv},
88	}
89	
90	@article{bullwinkel2025repeng,
91	  title={A Representation Engineering Perspective on the Effectiveness of Multi-Turn Jailbreaks},
92	  author={Bullwinkel, Blake and Russinovich, Mark and Salem, Ahmed and Zanella-Beguelin, Santiago and Jones, Daniel and Severi, Giorgio and Kim, Eugenia and Hines, Keegan and Minnich, Amanda and Zunger, Yonatan and Kumar, Ram Shankar Siva},
93	  journal={arXiv preprint},
94	  year={2025},
95	  eprint={2507.02956},
96	  archivePrefix={arXiv},
97	}
98	
99	% ============================================================
100	% Category 3: Discourse Analysis in NLP
101	% ============================================================
102	
103	@article{mann1988rst,
104	  title={Rhetorical Structure Theory: Toward a Functional Theory of Text Organization},
105	  author={Mann, William C. and Thompson, Sandra A.},
106	  journal={Text \& Talk},
107	  year={1988},
108	  volume={8},
109	  number={3},
110	  pages={243--281},
111	}
112	
113	@inproceedings{prasad2008pdtb,
114	  title={The Penn Discourse TreeBank 2.0},
115	  author={Prasad, Rashmi and Dinesh, Nikhil and Lee, Alan and Miltsakaki, Eleni and Robaldo, Livio and Joshi, Aravind and Webber, Bonnie},
116	  booktitle={Proceedings of the International Conference on Language Resources and Evaluation},
117	  year={2008},
118	}
119	
120	@article{stolcke2000dialogueact,
121	  title={Dialogue Act Modeling for Automatic Tagging and Recognition of Conversational Speech},
122	  author={Stolcke, Andreas and Ries, Klaus and Coccaro, Noah and Shriberg, Elizabeth and Bates, Rebecca and Jurafsky, Daniel and Taylor, Paul and Martin, Rachel and Van Ess-Dykema, Carol and Meteer, Marie},
123	  journal={Computational Linguistics},
124	  year={2000},
125	  volume={26},
126	  number={3},
127	  pages={339--374},
128	}
129	
130	@book{austin1962speechacts,
131	  title={How to Do Things with Words},
132	  author={Austin, J. L.},
133	  publisher={Harvard University Press},
134	  year={1962},
135	}
136	
137	@book{searle1969speechacts,
138	  title={Speech Acts: An Essay in the Philosophy of Language},
139	  author={Searle, J. R.},
140	  publisher={Cambridge University Press},
141	  year={1969},
142	}
143	
144	% ============================================================
145	% Category 4: Computational Persuasion Detection
146	% ============================================================
147	
148	@book{cialdini2001influence,
149	  title={Influence: Science and Practice},
150	  author={Cialdini, Robert B.},
151	  publisher={Allyn \& Bacon},
152	  year={2001},
153	  edition={4th},
154	}
155	
156	% ============================================================
157	% Category 5: Jailbreak Attacks & Taxonomies
158	% ============================================================
159	
160	@inproceedings{zeng2024pap,
161	  title={How Johnny Can Persuade LLMs to Jailbreak Them: Rethinking Persuasion to Challenge AI Safety by Humanizing LLMs},
162	  author={Zeng, Yi and Lin, Hongpeng and Zhang, Jingwen and Yang, Diyi and Jia, Ruoxi and Shi, Weiyan},
163	  booktitle={Proceedings of the Association for Computational Linguistics},
164	  year={2024},
165	}
166	
167	% Note: key retains "2024" for citation compatibility; paper published at USENIX Security 2025
168	@inproceedings{russinovich2024crescendo,
169	  title={Great, Now Write an Article About That: The Crescendo Multi-Turn LLM Jailbreak Attack},
170	  author={Russinovich, Mark and Salem, Ahmed and Eldan, Ronen},
171	  booktitle={USENIX Security Symposium},
172	  year={2025},
173	  eprint={2404.01833},
174	  archivePrefix={arXiv},
175	}
176	
177	% Note: key retains "2023" for citation compatibility; paper published at SaTML 2025
178	@inproceedings{chao2023pair,
179	  title={Jailbreaking Black Box Large Language Models in Twenty Queries},
180	  author={Chao, Patrick and Robey, Alexander and Dobriban, Edgar and Hassani, Hamed and Pappas, George J. and Wong, Eric},
181	  booktitle={IEEE Conference on Secure and Trustworthy Machine Learning},
182	  year={2025},
183	  eprint={2310.08419},
184	  archivePrefix={arXiv},
185	}
186	
187	@inproceedings{wei2023jailbroken,
188	  title={Jailbroken: How Does LLM Safety Training Fail?},
189	  author={Wei, Alexander and Haghtalab, Nika and Steinhardt, Jacob},
190	  booktitle={Advances in Neural Information Processing Systems},
191	  year={2023},
192	}
193	
194	@article{hagendorff2026reasoning,
195	  title={Large Reasoning Models Are Autonomous Jailbreak Agents},
196	  author={Hagendorff, Thilo and Derner, Erik and Oliver, Nuria},
197	  journal={Nature Communications},
198	  volume={17},
199	  pages={1435},
200	  year={2026},
201	  doi={10.1038/s41467-026-69010-1},
202	}
203	
204	@article{fitd2024,
205	  title={Foot In The Door: Understanding Large Language Model Jailbreaking via Cognitive Psychology},
206	  author={Wang, Zhenhua and Xie, Wei and Wang, Baosheng and Wang, Enze and Gui, Zhiwen and Ma, Shuoyoucheng and Chen, Kai},
207	  journal={arXiv preprint},
208	  year={2024},
209	  eprint={2402.15690},
210	  archivePrefix={arXiv},
211	}
212	
213	@techreport{deceptivedelight2024,
214	  title={Deceptive Delight: Jailbreak LLMs Through Camouflage and Distraction},
215	  author={{Palo Alto Networks Unit 42}},
216	  institution={Palo Alto Networks},
217	  year={2024},
218	}
219	
220	@inproceedings{ren2024actorattack,
221	  title={ActorAttack: Red-Teaming Large Language Models via Multi-Turn Actor Network Theory},
222	  author={Ren, Qibing and Li, Hao and Liu, Dongrui and Xie, Zhanxu and Lu, Xiaoya and Qiao, Yu and Sha, Lei and Yan, Junchi and Ma, Lizhuang and Shao, Jing},
223	  booktitle={International Conference on Learning Representations},
224	  year={2025},
225	}
226	
227	@article{zou2023gcg,
228	  title={Universal and Transferable Adversarial Attacks on Aligned Language Models},
229	  author={Zou, Andy and Wang, Zifan and Carlini, Nicholas and Nasr, Milad and Kolter, J. Zico and Fredrikson, Matt},
230	  journal={arXiv preprint},
231	  year={2023},
232	  eprint={2307.15043},
233	  archivePrefix={arXiv},
234	}
235	
236	% ============================================================
237	% Category 5b: Human Jailbreak Datasets
238	% ============================================================
239	
240	@inproceedings{lin2023toxicchat,
241	  title={ToxicChat: Unveiling Hidden Challenges of Toxicity Detection in Real-World User-{AI} Conversation},
242	  author={Lin, Zi and Wang, Zihan and Tong, Yongqi and Wang, Yangkun and Guo, Yuxin and Wang, Yujia and Shang, Jingbo},
243	  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2023},
244	  pages={4694--4702},
245	  year={2023},
246	}
247	
248	% ============================================================
249	% Category 6: Red-Teaming
250	% ============================================================
251	
252	@article{li2024mhj,
253	  title={LLM Defenses Are Not Robust to Multi-Turn Human Jailbreaks Yet},
254	  author={Li, Nathaniel and Han, Ziwen and Steneker, Ian and Primack, Willow and Goodside, Riley and Zhang, Hugh and Wang, Zifan and Menghini, Cristina and Yue, Summer},
255	  journal={arXiv preprint},
256	  year={2024},
257	  eprint={2408.15221},
258	  archivePrefix={arXiv},
259	}
260	
261	% ============================================================
262	% Category 7: Annotation Artifacts & Dataset Biases
263	% ============================================================
264	
265	@inproceedings{gururangan2018artifacts,
266	  title={Annotation Artifacts in Natural Language Inference Data},
267	  author={Gururangan, Suchin and Swayamdipta, Swabha and Levy, Omer and Schwartz, Roy and Bowman, Samuel and Smith, Noah A.},
268	  booktitle={Proceedings of the Conference of the North American Chapter of the Association for Computational Linguistics},
269	  year={2018},
270	}
271	
272	@inproceedings{niven2019probing,
273	  title={Probing Neural Network Comprehension of Natural Language Arguments},
274	  author={Niven, Timothy and Kao, Hung-Yu},
275	  booktitle={Proceedings of the Association for Computational Linguistics},
276	  year={2019},
277	}
278	
279	% ============================================================
280	% Category 8: Adaptive Attacks on Classifiers
281	% ============================================================
282	
283	@article{nasr2025attackermovessecond,
284	  title={The Attacker Moves Second: Stronger Adaptive Attacks Bypass Defenses Against LLM Jailbreaks and Prompt Injections},
285	  author={Nasr, Milad and Carlini, Nicholas and Sitawarin, Chawin and Schulhoff, Sander V. and Hayes, Jamie and Ilie, Michael and Pluto, Juliette and Song, Shuang and Chaudhari, Harsh and Shumailov, Ilia and Thakurta, Abhradeep and Xiao, Kai Yuanqing and Terzis, Andreas and Tram{\`e}r, Florian},
286	  journal={arXiv preprint},
287	  year={2025},
288	  eprint={2510.09023},
289	  archivePrefix={arXiv},
290	}
291	
292	@inproceedings{andriushchenko2024adaptive,
293	  title={Jailbreaking Leading Safety-Aligned LLMs with Simple Adaptive Attacks},
294	  author={Andriushchenko, Maksym and Croce, Francesco and Flammarion, Nicolas},
295	  booktitle={International Conference on Learning Representations},
296	  year={2025},
297	}
298	
299	% ============================================================
300	% Technical Foundation
301	% ============================================================
302	
303	@inproceedings{he2021deberta,
304	  title={DeBERTa: Decoding-enhanced BERT with Disentangled Attention},
305	  author={He, Pengcheng and Liu, Xiaodong and Gao, Jianfeng and Chen, Weizhu},
306	  booktitle={International Conference on Learning Representations},
307	  year={2021},
308	}
309	
310	@inproceedings{he2023debertav3,
311	  title={{DeBERTaV3}: Improving {DeBERTa} using {ELECTRA}-Style Pre-Training with Gradient-Disentangled Embedding Sharing},
312	  author={He, Pengcheng and Gao, Jianfeng and Chen, Weizhu},
313	  booktitle={International Conference on Learning Representations},
314	  year={2023},
315	}
316	
317	
318	@inproceedings{kornblith2019cka,
319	  title={Similarity of Neural Network Representations Revisited},
320	  author={Kornblith, Simon and Norouzi, Mohammad and Lee, Honglak and Hinton, Geoffrey},
321	  booktitle={International Conference on Machine Learning},
322	  pages={3519--3529},
323	  year={2019},
324	}
325	
326	@article{qwen3_2025,
327	  title={Qwen3 Technical Report},
328	  author={Yang, An and Yang, Baosong and Zhang, Beichen and Wang, Binyuan and Li, Bo and Lin, Bowen and others},
329	  journal={arXiv preprint},
330	  year={2025},
331	  eprint={2505.09388},
332	  archivePrefix={arXiv},
333	}
334	
335	% ============================================================
336	% Domain-Adaptive Pretraining & Multi-Task Learning
337	% ============================================================
338	
339	@inproceedings{gururangan2020dontstop,
340	  title={Don't Stop Pretraining: Adapt Language Models to Domains and Tasks},
341	  author={Gururangan, Suchin and Marasovi{\'c}, Ana and Swayamdipta, Swabha and Lo, Kyle and Beltagy, Iz and Downey, Doug and Smith, Noah A.},
342	  booktitle={Proceedings of the 58th Annual Meeting of the Association for Computational Linguistics},
343	  pages={8342--8360},
344	  year={2020},
345	}
346	
347	@article{caruana1997multitask,
348	  title={Multitask Learning},
349	  author={Caruana, Rich},
350	  journal={Machine Learning},
351	  volume={28},
352	  number={1},
353	  pages={41--75},
354	  year={1997},
355	}
356	
357	@article{phang2018stilts,
358	  title={Sentence Encoders on {STILTs}: Supplementary Training on Intermediate Labeled-data Tasks},
359	  author={Phang, Jason and F{\'e}vry, Thibault and Bowman, Samuel R.},
360	  journal={arXiv preprint arXiv:1811.01088},
361	  year={2018},
362	}
363	
364	@inproceedings{liu2019mtdnn,
365	  title={Multi-Task Deep Neural Networks for Natural Language Understanding},
366	  author={Liu, Xiaodong and He, Pengcheng and Chen, Weizhu and Gao, Jianfeng},
367	  booktitle={Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics},
368	  pages={4487--4496},
369	  year={2019},
370	}
371	
372	@inproceedings{howard2018ulmfit,
373	  title={Universal Language Model Fine-tuning for Text Classification},
374	  author={Howard, Jeremy and Ruder, Sebastian},
375	  booktitle={Proceedings of the 56th Annual Meeting of the Association for Computational Linguistics},
376	  pages={328--339},
377	  year={2018},
378	}
379	
380	% ============================================================
381	% Propaganda Detection
382	% ============================================================
383	
384	@inproceedings{dasanmartino2020semeval,
385	  title={{SemEval-2020 Task 11}: Detection of Propaganda Techniques in News Articles},
386	  author={Da San Martino, Giovanni and Barr\'{o}n-Cede\~{n}o, Alberto and Wachsmuth, Henning and Petrov, Rostislav and Nakov, Preslav},
387	  booktitle={Proceedings of the Fourteenth Workshop on Semantic Evaluation},
388	  pages={1377--1414},
389	  year={2020},
390	}
391	
392	@inproceedings{dasanmartino2019fine,
393	  title={Fine-Grained Analysis of Propaganda in News Articles},
394	  author={Da San Martino, Giovanni and Yu, Seunghak and Barr\'{o}n-Cede\~{n}o, Alberto and Petrov, Rostislav and Nakov, Preslav},
395	  booktitle={Proceedings of the 2019 Conference on Empirical Methods in Natural Language Processing},
396	  pages={5636--5646},
397	  year={2019},
398	}
399	
400	% ============================================================
401	% Adversarial NLP
402	% ============================================================
403	
404	@inproceedings{jin2020textfooler,
405	  title={Is {BERT} Really Robust? A Strong Baseline for Natural Language Attack on Text Classification and Entailment},
406	  author={Jin, Di and Jin, Zhijing and Zhou, Joey Tianyi and Szolovits, Peter},
407	  booktitle={Proceedings of the AAAI Conference on Artificial Intelligence},
408	  volume={34},
409	  pages={8018--8025},
410	  year={2020},
411	}
412	
413	@inproceedings{li2020bertattack,
414	  title={{BERT-ATTACK}: Adversarial Attack Against {BERT} Using {BERT}},
415	  author={Li, Linyang and Ma, Ruotian and Guo, Qipeng and Xue, Xiangyang and Qiu, Xipeng},
416	  booktitle={Proceedings of the 2020 Conference on Empirical Methods in Natural Language Processing},
417	  pages={6193--6202},
418	  year={2020},
419	}
420	
421	% ============================================================
422	% Probing Classifiers
423	% ============================================================
424	
425	@inproceedings{devlin2019bert,
426	  title={{BERT}: Pre-training of Deep Bidirectional Transformers for Language Understanding},
427	  author={Devlin, Jacob and Chang, Ming-Wei and Lee, Kenton and Toutanova, Kristina},
428	  booktitle={Proceedings of the 2019 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies},
429	  pages={4171--4186},
430	  year={2019},
431	}
432	
433	@inproceedings{conneau2018probing,
434	  title={What you can cram into a single \$\&!\#* vector: Probing sentence embeddings for linguistic properties},
435	  author={Conneau, Alexis and Kruszewski, German and Lample, Guillaume and Barrault, Lo\"{i}c and Baroni, Marco},
436	  booktitle={Proceedings of the 56th Annual Meeting of the Association for Computational Linguistics},
437	  pages={2126--2136},
438	  year={2018},
439	}
440	
441	@inproceedings{hewitt2019structural,
442	  title={A Structural Probe for Finding Syntax in Word Representations},
443	  author={Hewitt, John and Manning, Christopher D.},
444	  booktitle={Proceedings of the 2019 Conference of the North American Chapter of the Association for Computational Linguistics},
445	  pages={4129--4138},
446	  year={2019},
447	}
448	
449	@article{liu2019roberta,
450	  title={RoBERTa: A Robustly Optimized BERT Pretraining Approach},
451	  author={Liu, Yinhan and Ott, Myle and Goyal, Naman and Du, Jingfei and Joshi, Mandar and Chen, Danqi and Levy, Omer and Lewis, Mike and Zettlemoyer, Luke and Stoyanov, Veselin},
452	  journal={arXiv preprint arXiv:1907.11692},
453	  year={2019},
454	}
455	
456	@inproceedings{wang2019persuasion,
457	  title={Persuasion for Good: Towards a Personalized Persuasive Dialogue System for Social Good},
458	  author={Wang, Xuewei and Shi, Weiyan and Kim, Richard and Oh, Yoojung and Yang, Sijia and Zhang, Jingwen and Yu, Zhou},
459	  booktitle={Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics},
460	  pages={5635--5649},
461	  year={2019},
462	}
463	
464	@inproceedings{robey2024smoothllm,
465	  title={SmoothLLM: Defending Large Language Models Against Jailbreaking Attacks},
466	  author={Robey, Alexander and Wong, Eric and Hassani, Hamed and Pappas, George J.},
467	  booktitle={Proceedings of the 41st International Conference on Machine Learning},
468	  year={2024},
469	}
470	
471	@inproceedings{mehrotra2024tap,
472	  title={Tree of Attacks: Jailbreaking Black-Box LLMs with the Pruning of Candidate Outputs},
473	  author={Mehrotra, Anay and Zampetakis, Manolis and Kassianik, Paul and Nelson, Blaine and Anderson, Hyrum and Singer, Yaron and Karbasi, Amin},
474	  booktitle={Advances in Neural Information Processing Systems},
475	  year={2024},
476	}
477	
478	@article{chao2024jailbreakbench,
479	  title={JailbreakBench: An Open Robustness Benchmark for Jailbreaking Large Language Models},
480	  author={Chao, Patrick and Robey, Alexander and Dobriban, Edgar and Hassani, Hamed and Pappas, George J. and Wong, Eric},
481	  journal={arXiv preprint arXiv:2404.01318},
482	  year={2024},
483	}
484	
485	@inproceedings{mazeika2024harmbench,
486	  title={HarmBench: A Standardized Evaluation Framework for Automated Red Teaming and Robust Refusal},
487	  author={Mazeika, Mantas and Phan, Long and Yin, Xuwang and Zou, Andy and Wang, Zifan and Mu, Norman and Sakhaee, Elham and Li, Nathaniel and Basart, Steven and Li, Bo and Forsyth, David and Hendrycks, Dan},
488	  booktitle={Proceedings of the 41st International Conference on Machine Learning},
489	  year={2024},
490	}
491	
492	@inproceedings{lu2025xboundary,
493	  title={X-Boundary: Establishing Exact Safety Boundary to Shield {LLMs} from Multi-Turn Jailbreaks without Compromising Usability},
494	  author={Lu, Xiaoya and Liu, Dongrui and Yu, Yi and Xu, Luxin and Shao, Jing},
495	  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2025},
496	  year={2025},
497	  eprint={2502.09990},
498	  archivePrefix={arXiv},
499	}
500	
501	@article{kadali2026trace,
502	  title={Jailbreaking Leaves a Trace: Understanding and Detecting Jailbreak Attacks from Internal Representations of Large Language Models},
503	  author={Kadali, Sri Durga Sai Sowmya and Papalexakis, Evangelos E.},
504	  journal={arXiv preprint arXiv:2602.11495},
505	  year={2026},
506	  eprint={2602.11495},
507	  archivePrefix={arXiv},
508	}
509	
510	@inproceedings{hua2026rcs,
511	  title={Rethinking Jailbreak Detection of Large Vision Language Models with Representational Contrastive Scoring},
512	  author={Hua, Peichun and Li, Hao and Shi, Shanghao and Yu, Zhiyuan and Zhang, Ning},
513	  booktitle={Proceedings of the 64th Annual Meeting of the Association for Computational Linguistics},
514	  year={2026},
515	  eprint={2512.12069},
516	  archivePrefix={arXiv},
517	}
518	
519	@article{jiang2024redqueen,
520	  title={{RED QUEEN}: Safeguarding Large Language Models against Concealed Multi-Turn Jailbreaking},
521	  author={Jiang, Yifan and Aggarwal, Kriti and Laud, Tanmay and Munir, Kashif and Pujara, Jay and Mukherjee, Subhabrata},
522	  journal={arXiv preprint},
523	  year={2024},
524	  eprint={2409.17458},
525	  archivePrefix={arXiv},
526	}
527	
528	@inproceedings{song2026multibreak,
529	  title={{MultiBreak}: A Scalable and Diverse Multi-turn Jailbreak Benchmark for Evaluating {LLM} Safety},
530	  author={Song, Jialin and Liu, Xiaodong and Yang, Weiwei and Chen, Wuyang and Feng, Mingqian and Zhu, Xuekai and Gao, Jianfeng},
531	  booktitle={International Conference on Machine Learning},
532	  year={2026},
533	  eprint={2605.01687},
534	  archivePrefix={arXiv},
535	}
536	
537	% ============================================================
538	% New citations (added 2026-05-21)
539	% ============================================================
540	
541	@inproceedings{xie2024gradsafe,
542	  title={{GradSafe}: Detecting Jailbreak Prompts for {LLMs} via Safety-Critical Gradient Analysis},
543	  author={Xie, Yueqi and Fang, Minghong and Pi, Renjie and Gong, Neil},
544	  booktitle={Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics},
545	  pages={507--518},
546	  year={2024},
547	}
548	
549	@inproceedings{xu2024safedecoding,
550	  title={{SafeDecoding}: Defending against Jailbreak Attacks via Safety-Aware Decoding},
551	  author={Xu, Zhangchen and Jiang, Fengqing and Niu, Luyao and Jia, Jinyuan and Lin, Bill Yuchen and Poovendran, Radha},
552	  booktitle={Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics},
553	  year={2024},
554	}
555	
556	@inproceedings{zou2024circuitbreakers,
557	  title={Improving Alignment and Robustness with Circuit Breakers},
558	  author={Zou, Andy and Phan, Long and Wang, Justin and Duenas, Derek and Lin, Maxwell and Andriushchenko, Maksym and Wang, Rowan and Kolter, Zico and Fredrikson, Matt and Hendrycks, Dan},
559	  booktitle={Advances in Neural Information Processing Systems},
560	  year={2024},
561	}
562	
563	% ============================================================
564	% New citations (added 2026-05-20)
565	% ============================================================
566	
567	@inproceedings{zhang2025jbshield,
568	  title={{JBShield}: Defending Large Language Models from Jailbreak Attacks through Activated Concept Analysis and Manipulation},
569	  author={Zhang, Shenyi and Zhai, Yuchen and Guo, Keyan and Hu, Hongxin and Guo, Shengnan and Fang, Zheng and Zhao, Lingchen and Shen, Chao and Wang, Cong and Wang, Qian},
570	  booktitle={USENIX Security Symposium},
571	  year={2025},
572	  eprint={2502.07557},
573	  archivePrefix={arXiv},
574	}
575	
576	@inproceedings{perez2022redteaming,
577	  title={Red Teaming Language Models with Language Models},
578	  author={Perez, Ethan and Huang, Saffron and Song, Francis and Cai, Trevor and Ring, Roman and Aslanides, John and Glaese, Amelia and McAleese, Nat and Irving, Geoffrey},
579	  booktitle={Proceedings of the 2022 Conference on Empirical Methods in Natural Language Processing},
580	  pages={3419--3448},
581	  year={2022},
582	}
583	
584	@article{kulkarni2026latentadversarial,
585	  title={Latent Adversarial Detection: Adaptive Probing of {LLM} Activations for Multi-Turn Attack Detection},
586	  author={Kulkarni, Prashant},
587	  journal={arXiv preprint},
588	  year={2026},
589	  eprint={2604.28129},
590	  archivePrefix={arXiv},
591	}
592	
593	@article{derya2026revisitingjbshield,
594	  title={Revisiting {JBShield}: Breaking and Rebuilding Representation-Level Jailbreak Defenses},
595	  author={Derya, Kemal and Sunar, Berk},
596	  journal={arXiv preprint},
597	  year={2026},
598	  eprint={2605.03095},
599	  archivePrefix={arXiv},
600	}
601	
602	@article{lee2020biobert,
603	  title={{BioBERT}: A Pre-trained Biomedical Language Representation Model for Biomedical Text Mining},
604	  author={Lee, Jinhyuk and Yoon, Wonjin and Kim, Sungdong and Kim, Donghyeon and Kim, Sunkyu and So, Chan Ho and Kang, Jaewoo},
605	  journal={Bioinformatics},
606	  volume={36},
607	  number={4},
608	  pages={1234--1240},
609	  year={2020},
610	  publisher={Oxford University Press},
611	}
612	
613	@inproceedings{beltagy2019scibert,
614	  title={{SciBERT}: A Pretrained Language Model for Scientific Text},
615	  author={Beltagy, Iz and Lo, Kyle and Cohan, Arman},
616	  booktitle={Proceedings of the 2019 Conference on Empirical Methods in Natural Language Processing (EMNLP)},
617	  pages={3615--3620},
618	  year={2019},
619	}
620	
621	@inproceedings{chen2020simclr,
622	  title={A Simple Framework for Contrastive Learning of Visual Representations},
623	  author={Chen, Ting and Kornblith, Simon and Norouzi, Mohammad and Hinton, Geoffrey},
624	  booktitle={International Conference on Machine Learning (ICML)},
625	  pages={1597--1607},
626	  year={2020},
627	}
628	
629	@inproceedings{grill2020byol,
630	  title={Bootstrap Your Own Latent: A New Approach to Self-Supervised Learning},
631	  author={Grill, Jean-Bastien and Strub, Florian and Altch{\'e}, Florent and Tallec, Corentin and Richemond, Pierre H. and Buchatber, Elena and Doersch, Carl and Pires, Bernardo Avila and Guo, Zhaohan Daniel and Azar, Mohammad Gheshlaghi and Piot, Bilal and Kavukcuoglu, Koray and Munos, R{\'e}mi and Valko, Michal},
632	  booktitle={Advances in Neural Information Processing Systems (NeurIPS)},
633	  year={2020},
634	}
635	
636	% ============================================================
637	% New citations (Round 10 fixes)
638	% ============================================================
639	
640	@article{zhang2021understanding,
641	  title={Understanding Deep Learning (Still) Requires Rethinking Generalization},
642	  author={Zhang, Chiyuan and Bengio, Samy and Hardt, Moritz and Recht, Benjamin and Vinyals, Oriol},
643	  journal={Communications of the ACM},
644	  volume={64},
645	  number={3},
646	  pages={107--115},
647	  year={2021},
648	  doi={10.1145/3446776},
649	}
650	
651	@inproceedings{maennel2020random,
652	  title={What Do Neural Networks Learn When Trained With Random Labels?},
653	  author={Maennel, Hartmut and Alabdulmohsin, Ibrahim M. and Tolstikhin, Ilya O. and Baldock, Robert J. N. and Bousquet, Olivier and Gelly, Sylvain and Keysers, Daniel},
654	  booktitle={Advances in Neural Information Processing Systems},
655	  year={2020},
656	}
657	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "226983de-eb29-42f7-954e-5fa31bdc329b",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/references.bib",
      "content": "% References for persuasion_turn_jailbreak_detect\n% Auto-generated from literature_map.yaml (2026-05-18)\n% Total entries: 31\n\n% ============================================================\n% Category 1: Production Multi-Turn Safety Systems\n% ============================================================\n\n@article{inan2023llamaguard,\n  title={Llama Guard: LLM-based Input-Output Safeguard for Human-AI Conversations},\n  author={Inan, Hakan and Upasani, Kartikeya and Chi, Jianfeng and Rungta, Rashi and Iyer, Krithika and Mao, Yuning and Tontchev, Michael and Hu, Qing and Fuller, Brian and Testuggine, Davide and Khabsa, Madian},\n  journal={arXiv preprint},\n  year={2023},\n  eprint={2312.06674},\n  archivePrefix={arXiv},\n}\n\n@misc{metallamaguard3_2024,\n  title={Llama Guard 3},\n  author={{Meta AI}},\n  year={2024},\n  howpublished={Meta AI (released with Llama 3.1)},\n}\n\n@article{zeng2024shieldgemma,\n  title={ShieldGemma: Generative AI Content Moderation Based on Gemma},\n  author={Zeng, Wenjun and Liu, Yuchi and Mullins, Ryan and Peran, Ludovic and Fernandez, Joe and Harkous, Hamza and Narasimhan, Karthik and Proud, Drew and Kumar, Piyush and Radharapu, Bhaktipriya and Sturman, Olivia and Wahltinez, Oscar},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2407.21772},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{han2024wildguard,\n  title={WildGuard: Open One-Stop Moderation Tools for Safety Risks, Jailbreaks, and Refusals of LLMs},\n  author={Han, Seungju and Rao, Kavel and Ettinger, Allyson and Jiang, Liwei and Lin, Bill Yuchen and Lambert, Nathan and Choi, Yejin and Dziri, Nouha},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2024},\n}\n\n@techreport{anthropic2025constitutional,\n  title={Constitutional Classifiers: Defending against Universal Jailbreaks across Thousands of Hours of Red Teaming},\n  author={Sharma, Mrinank and Tong, Meg and Mu, Jesse and Korbak, Tomek and others},\n  institution={Anthropic},\n  year={2025},\n  eprint={2501.18837},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 2: Multi-Turn Jailbreak Defenses\n% ============================================================\n\n@article{deepcontext2026,\n  title={DeepContext: Stateful Real-Time Detection of Multi-Turn Adversarial Intent Drift in LLMs},\n  author={Albrethsen, Justin and Datta, Yash and Kumar, Kunal and Rajasekar, Sharath},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2602.16935},\n  archivePrefix={arXiv},\n}\n\n@article{tong2025biid,\n  title={Bidirectional Intention Inference Enhances LLMs' Defense Against Multi-Turn Jailbreak Attacks},\n  author={Tong, Haibo and Zhao, Dongcheng and Shen, Guobin and He, Xiang and Lin, Dachuan and Zhao, Feifei and Zeng, Yi},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2509.22732},\n  archivePrefix={arXiv},\n}\n\n@article{gguard2025,\n  title={An Attention-Aware GNN-Based Input Defender Against Multi-Turn Jailbreak on LLMs},\n  author={Huang, Zixuan and Huang, Kecheng and Yin, Lihao and He, Bowei and Zhen, Huiling and Yuan, Mingxuan and Shao, Zili},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2507.07146},\n  archivePrefix={arXiv},\n}\n\n@article{safedream2026,\n  title={SafeDream: Safety World Model for Proactive Early Jailbreak Detection},\n  author={Yan, Bo and Lin, Weikai and Zhu, Yada and Wang, Song},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2604.16824},\n  archivePrefix={arXiv},\n}\n\n@article{bullwinkel2025repeng,\n  title={A Representation Engineering Perspective on the Effectiveness of Multi-Turn Jailbreaks},\n  author={Bullwinkel, Blake and Russinovich, Mark and Salem, Ahmed and Zanella-Beguelin, Santiago and Jones, Daniel and Severi, Giorgio and Kim, Eugenia and Hines, Keegan and Minnich, Amanda and Zunger, Yonatan and Kumar, Ram Shankar Siva},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2507.02956},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 3: Discourse Analysis in NLP\n% ============================================================\n\n@article{mann1988rst,\n  title={Rhetorical Structure Theory: Toward a Functional Theory of Text Organization},\n  author={Mann, William C. and Thompson, Sandra A.},\n  journal={Text \\& Talk},\n  year={1988},\n  volume={8},\n  number={3},\n  pages={243--281},\n}\n\n@inproceedings{prasad2008pdtb,\n  title={The Penn Discourse TreeBank 2.0},\n  author={Prasad, Rashmi and Dinesh, Nikhil and Lee, Alan and Miltsakaki, Eleni and Robaldo, Livio and Joshi, Aravind and Webber, Bonnie},\n  booktitle={Proceedings of the International Conference on Language Resources and Evaluation},\n  year={2008},\n}\n\n@article{stolcke2000dialogueact,\n  title={Dialogue Act Modeling for Automatic Tagging and Recognition of Conversational Speech},\n  author={Stolcke, Andreas and Ries, Klaus and Coccaro, Noah and Shriberg, Elizabeth and Bates, Rebecca and Jurafsky, Daniel and Taylor, Paul and Martin, Rachel and Van Ess-Dykema, Carol and Meteer, Marie},\n  journal={Computational Linguistics},\n  year={2000},\n  volume={26},\n  number={3},\n  pages={339--374},\n}\n\n@book{austin1962speechacts,\n  title={How to Do Things with Words},\n  author={Austin, J. L.},\n  publisher={Harvard University Press},\n  year={1962},\n}\n\n@book{searle1969speechacts,\n  title={Speech Acts: An Essay in the Philosophy of Language},\n  author={Searle, J. R.},\n  publisher={Cambridge University Press},\n  year={1969},\n}\n\n% ============================================================\n% Category 4: Computational Persuasion Detection\n% ============================================================\n\n@book{cialdini2001influence,\n  title={Influence: Science and Practice},\n  author={Cialdini, Robert B.},\n  publisher={Allyn \\& Bacon},\n  year={2001},\n  edition={4th},\n}\n\n% ============================================================\n% Category 5: Jailbreak Attacks & Taxonomies\n% ============================================================\n\n@inproceedings{zeng2024pap,\n  title={How Johnny Can Persuade LLMs to Jailbreak Them: Rethinking Persuasion to Challenge AI Safety by Humanizing LLMs},\n  author={Zeng, Yi and Lin, Hongpeng and Zhang, Jingwen and Yang, Diyi and Jia, Ruoxi and Shi, Weiyan},\n  booktitle={Proceedings of the Association for Computational Linguistics},\n  year={2024},\n}\n\n% Note: key retains \"2024\" for citation compatibility; paper published at USENIX Security 2025\n@inproceedings{russinovich2024crescendo,\n  title={Great, Now Write an Article About That: The Crescendo Multi-Turn LLM Jailbreak Attack},\n  author={Russinovich, Mark and Salem, Ahmed and Eldan, Ronen},\n  booktitle={USENIX Security Symposium},\n  year={2025},\n  eprint={2404.01833},\n  archivePrefix={arXiv},\n}\n\n% Note: key retains \"2023\" for citation compatibility; paper published at SaTML 2025\n@inproceedings{chao2023pair,\n  title={Jailbreaking Black Box Large Language Models in Twenty Queries},\n  author={Chao, Patrick and Robey, Alexander and Dobriban, Edgar and Hassani, Hamed and Pappas, George J. and Wong, Eric},\n  booktitle={IEEE Conference on Secure and Trustworthy Machine Learning},\n  year={2025},\n  eprint={2310.08419},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{wei2023jailbroken,\n  title={Jailbroken: How Does LLM Safety Training Fail?},\n  author={Wei, Alexander and Haghtalab, Nika and Steinhardt, Jacob},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2023},\n}\n\n@article{hagendorff2026reasoning,\n  title={Large Reasoning Models Are Autonomous Jailbreak Agents},\n  author={Hagendorff, Thilo and Derner, Erik and Oliver, Nuria},\n  journal={Nature Communications},\n  volume={17},\n  pages={1435},\n  year={2026},\n  doi={10.1038/s41467-026-69010-1},\n}\n\n@article{fitd2024,\n  title={Foot In The Door: Understanding Large Language Model Jailbreaking via Cognitive Psychology},\n  author={Wang, Zhenhua and Xie, Wei and Wang, Baosheng and Wang, Enze and Gui, Zhiwen and Ma, Shuoyoucheng and Chen, Kai},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2402.15690},\n  archivePrefix={arXiv},\n}\n\n@techreport{deceptivedelight2024,\n  title={Deceptive Delight: Jailbreak LLMs Through Camouflage and Distraction},\n  author={{Palo Alto Networks Unit 42}},\n  institution={Palo Alto Networks},\n  year={2024},\n}\n\n@inproceedings{ren2024actorattack,\n  title={ActorAttack: Red-Teaming Large Language Models via Multi-Turn Actor Network Theory},\n  author={Ren, Qibing and Li, Hao and Liu, Dongrui and Xie, Zhanxu and Lu, Xiaoya and Qiao, Yu and Sha, Lei and Yan, Junchi and Ma, Lizhuang and Shao, Jing},\n  booktitle={International Conference on Learning Representations},\n  year={2025},\n}\n\n@article{zou2023gcg,\n  title={Universal and Transferable Adversarial Attacks on Aligned Language Models},\n  author={Zou, Andy and Wang, Zifan and Carlini, Nicholas and Nasr, Milad and Kolter, J. Zico and Fredrikson, Matt},\n  journal={arXiv preprint},\n  year={2023},\n  eprint={2307.15043},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 5b: Human Jailbreak Datasets\n% ============================================================\n\n@inproceedings{lin2023toxicchat,\n  title={ToxicChat: Unveiling Hidden Challenges of Toxicity Detection in Real-World User-{AI} Conversation},\n  author={Lin, Zi and Wang, Zihan and Tong, Yongqi and Wang, Yangkun and Guo, Yuxin and Wang, Yujia and Shang, Jingbo},\n  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2023},\n  pages={4694--4702},\n  year={2023},\n}\n\n% ============================================================\n% Category 6: Red-Teaming\n% ============================================================\n\n@article{li2024mhj,\n  title={LLM Defenses Are Not Robust to Multi-Turn Human Jailbreaks Yet},\n  author={Li, Nathaniel and Han, Ziwen and Steneker, Ian and Primack, Willow and Goodside, Riley and Zhang, Hugh and Wang, Zifan and Menghini, Cristina and Yue, Summer},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2408.15221},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 7: Annotation Artifacts & Dataset Biases\n% ============================================================\n\n@inproceedings{gururangan2018artifacts,\n  title={Annotation Artifacts in Natural Language Inference Data},\n  author={Gururangan, Suchin and Swayamdipta, Swabha and Levy, Omer and Schwartz, Roy and Bowman, Samuel and Smith, Noah A.},\n  booktitle={Proceedings of the Conference of the North American Chapter of the Association for Computational Linguistics},\n  year={2018},\n}\n\n@inproceedings{niven2019probing,\n  title={Probing Neural Network Comprehension of Natural Language Arguments},\n  author={Niven, Timothy and Kao, Hung-Yu},\n  booktitle={Proceedings of the Association for Computational Linguistics},\n  year={2019},\n}\n\n% ============================================================\n% Category 8: Adaptive Attacks on Classifiers\n% ============================================================\n\n@article{nasr2025attackermovessecond,\n  title={The Attacker Moves Second: Stronger Adaptive Attacks Bypass Defenses Against LLM Jailbreaks and Prompt Injections},\n  author={Nasr, Milad and Carlini, Nicholas and Sitawarin, Chawin and Schulhoff, Sander V. and Hayes, Jamie and Ilie, Michael and Pluto, Juliette and Song, Shuang and Chaudhari, Harsh and Shumailov, Ilia and Thakurta, Abhradeep and Xiao, Kai Yuanqing and Terzis, Andreas and Tram{\\`e}r, Florian},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2510.09023},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{andriushchenko2024adaptive,\n  title={Jailbreaking Leading Safety-Aligned LLMs with Simple Adaptive Attacks},\n  author={Andriushchenko, Maksym and Croce, Francesco and Flammarion, Nicolas},\n  booktitle={International Conference on Learning Representations},\n  year={2025},\n}\n\n% ============================================================\n% Technical Foundation\n% ============================================================\n\n@inproceedings{he2021deberta,\n  title={DeBERTa: Decoding-enhanced BERT with Disentangled Attention},\n  author={He, Pengcheng and Liu, Xiaodong and Gao, Jianfeng and Chen, Weizhu},\n  booktitle={International Conference on Learning Representations},\n  year={2021},\n}\n\n@inproceedings{he2023debertav3,\n  title={{DeBERTaV3}: Improving {DeBERTa} using {ELECTRA}-Style Pre-Training with Gradient-Disentangled Embedding Sharing},\n  author={He, Pengcheng and Gao, Jianfeng and Chen, Weizhu},\n  booktitle={International Conference on Learning Representations},\n  year={2023},\n}\n\n\n@inproceedings{kornblith2019cka,\n  title={Similarity of Neural Network Representations Revisited},\n  author={Kornblith, Simon and Norouzi, Mohammad and Lee, Honglak and Hinton, Geoffrey},\n  booktitle={International Conference on Machine Learning},\n  pages={3519--3529},\n  year={2019},\n}\n\n@article{qwen3_2025,\n  title={Qwen3 Technical Report},\n  author={Yang, An and Yang, Baosong and Zhang, Beichen and Wang, Binyuan and Li, Bo and Lin, Bowen and others},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2505.09388},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Domain-Adaptive Pretraining & Multi-Task Learning\n% ============================================================\n\n@inproceedings{gururangan2020dontstop,\n  title={Don't Stop Pretraining: Adapt Language Models to Domains and Tasks},\n  author={Gururangan, Suchin and Marasovi{\\'c}, Ana and Swayamdipta, Swabha and Lo, Kyle and Beltagy, Iz and Downey, Doug and Smith, Noah A.},\n  booktitle={Proceedings of the 58th Annual Meeting of the Association for Computational Linguistics},\n  pages={8342--8360},\n  year={2020},\n}\n\n@article{caruana1997multitask,\n  title={Multitask Learning},\n  author={Caruana, Rich},\n  journal={Machine Learning},\n  volume={28},\n  number={1},\n  pages={41--75},\n  year={1997},\n}\n\n@article{phang2018stilts,\n  title={Sentence Encoders on {STILTs}: Supplementary Training on Intermediate Labeled-data Tasks},\n  author={Phang, Jason and F{\\'e}vry, Thibault and Bowman, Samuel R.},\n  journal={arXiv preprint arXiv:1811.01088},\n  year={2018},\n}\n\n@inproceedings{liu2019mtdnn,\n  title={Multi-Task Deep Neural Networks for Natural Language Understanding},\n  author={Liu, Xiaodong and He, Pengcheng and Chen, Weizhu and Gao, Jianfeng},\n  booktitle={Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics},\n  pages={4487--4496},\n  year={2019},\n}\n\n@inproceedings{howard2018ulmfit,\n  title={Universal Language Model Fine-tuning for Text Classification},\n  author={Howard, Jeremy and Ruder, Sebastian},\n  booktitle={Proceedings of the 56th Annual Meeting of the Association for Computational Linguistics},\n  pages={328--339},\n  year={2018},\n}\n\n% ============================================================\n% Propaganda Detection\n% ============================================================\n\n@inproceedings{dasanmartino2020semeval,\n  title={{SemEval-2020 Task 11}: Detection of Propaganda Techniques in News Articles},\n  author={Da San Martino, Giovanni and Barr\\'{o}n-Cede\\~{n}o, Alberto and Wachsmuth, Henning and Petrov, Rostislav and Nakov, Preslav},\n  booktitle={Proceedings of the Fourteenth Workshop on Semantic Evaluation},\n  pages={1377--1414},\n  year={2020},\n}\n\n@inproceedings{dasanmartino2019fine,\n  title={Fine-Grained Analysis of Propaganda in News Articles},\n  author={Da San Martino, Giovanni and Yu, Seunghak and Barr\\'{o}n-Cede\\~{n}o, Alberto and Petrov, Rostislav and Nakov, Preslav},\n  booktitle={Proceedings of the 2019 Conference on Empirical Methods in Natural Language Processing},\n  pages={5636--5646},\n  year={2019},\n}\n\n% ============================================================\n% Adversarial NLP\n% ============================================================\n\n@inproceedings{jin2020textfooler,\n  title={Is {BERT} Really Robust? A Strong Baseline for Natural Language Attack on Text Classification and Entailment},\n  author={Jin, Di and Jin, Zhijing and Zhou, Joey Tianyi and Szolovits, Peter},\n  booktitle={Proceedings of the AAAI Conference on Artificial Intelligence},\n  volume={34},\n  pages={8018--8025},\n  year={2020},\n}\n\n@inproceedings{li2020bertattack,\n  title={{BERT-ATTACK}: Adversarial Attack Against {BERT} Using {BERT}},\n  author={Li, Linyang and Ma, Ruotian and Guo, Qipeng and Xue, Xiangyang and Qiu, Xipeng},\n  booktitle={Proceedings of the 2020 Conference on Empirical Methods in Natural Language Processing},\n  pages={6193--6202},\n  year={2020},\n}\n\n% ============================================================\n% Probing Classifiers\n% ============================================================\n\n@inproceedings{devlin2019bert,\n  title={{BERT}: Pre-training of Deep Bidirectional Transformers for Language Understanding},\n  author={Devlin, Jacob and Chang, Ming-Wei and Lee, Kenton and Toutanova, Kristina},\n  booktitle={Proceedings of the 2019 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies},\n  pages={4171--4186},\n  year={2019},\n}\n\n@inproceedings{conneau2018probing,\n  title={What you can cram into a single \\$\\&!\\#* vector: Probing sentence embeddings for linguistic properties},\n  author={Conneau, Alexis and Kruszewski, German and Lample, Guillaume and Barrault, Lo\\\"{i}c and Baroni, Marco},\n  booktitle={Proceedings of the 56th Annual Meeting of the Association for Computational Linguistics},\n  pages={2126--2136},\n  year={2018},\n}\n\n@inproceedings{hewitt2019structural,\n  title={A Structural Probe for Finding Syntax in Word Representations},\n  author={Hewitt, John and Manning, Christopher D.},\n  booktitle={Proceedings of the 2019 Conference of the North American Chapter of the Association for Computational Linguistics},\n  pages={4129--4138},\n  year={2019},\n}\n\n@article{liu2019roberta,\n  title={RoBERTa: A Robustly Optimized BERT Pretraining Approach},\n  author={Liu, Yinhan and Ott, Myle and Goyal, Naman and Du, Jingfei and Joshi, Mandar and Chen, Danqi and Levy, Omer and Lewis, Mike and Zettlemoyer, Luke and Stoyanov, Veselin},\n  journal={arXiv preprint arXiv:1907.11692},\n  year={2019},\n}\n\n@inproceedings{wang2019persuasion,\n  title={Persuasion for Good: Towards a Personalized Persuasive Dialogue System for Social Good},\n  author={Wang, Xuewei and Shi, Weiyan and Kim, Richard and Oh, Yoojung and Yang, Sijia and Zhang, Jingwen and Yu, Zhou},\n  booktitle={Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics},\n  pages={5635--5649},\n  year={2019},\n}\n\n@inproceedings{robey2024smoothllm,\n  title={SmoothLLM: Defending Large Language Models Against Jailbreaking Attacks},\n  author={Robey, Alexander and Wong, Eric and Hassani, Hamed and Pappas, George J.},\n  booktitle={Proceedings of the 41st International Conference on Machine Learning},\n  year={2024},\n}\n\n@inproceedings{mehrotra2024tap,\n  title={Tree of Attacks: Jailbreaking Black-Box LLMs with the Pruning of Candidate Outputs},\n  author={Mehrotra, Anay and Zampetakis, Manolis and Kassianik, Paul and Nelson, Blaine and Anderson, Hyrum and Singer, Yaron and Karbasi, Amin},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2024},\n}\n\n@article{chao2024jailbreakbench,\n  title={JailbreakBench: An Open Robustness Benchmark for Jailbreaking Large Language Models},\n  author={Chao, Patrick and Robey, Alexander and Dobriban, Edgar and Hassani, Hamed and Pappas, George J. and Wong, Eric},\n  journal={arXiv preprint arXiv:2404.01318},\n  year={2024},\n}\n\n@inproceedings{mazeika2024harmbench,\n  title={HarmBench: A Standardized Evaluation Framework for Automated Red Teaming and Robust Refusal},\n  author={Mazeika, Mantas and Phan, Long and Yin, Xuwang and Zou, Andy and Wang, Zifan and Mu, Norman and Sakhaee, Elham and Li, Nathaniel and Basart, Steven and Li, Bo and Forsyth, David and Hendrycks, Dan},\n  booktitle={Proceedings of the 41st International Conference on Machine Learning},\n  year={2024},\n}\n\n@inproceedings{lu2025xboundary,\n  title={X-Boundary: Establishing Exact Safety Boundary to Shield {LLMs} from Multi-Turn Jailbreaks without Compromising Usability},\n  author={Lu, Xiaoya and Liu, Dongrui and Yu, Yi and Xu, Luxin and Shao, Jing},\n  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2025},\n  year={2025},\n  eprint={2502.09990},\n  archivePrefix={arXiv},\n}\n\n@article{kadali2026trace,\n  title={Jailbreaking Leaves a Trace: Understanding and Detecting Jailbreak Attacks from Internal Representations of Large Language Models},\n  author={Kadali, Sri Durga Sai Sowmya and Papalexakis, Evangelos E.},\n  journal={arXiv preprint arXiv:2602.11495},\n  year={2026},\n  eprint={2602.11495},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{hua2026rcs,\n  title={Rethinking Jailbreak Detection of Large Vision Language Models with Representational Contrastive Scoring},\n  author={Hua, Peichun and Li, Hao and Shi, Shanghao and Yu, Zhiyuan and Zhang, Ning},\n  booktitle={Proceedings of the 64th Annual Meeting of the Association for Computational Linguistics},\n  year={2026},\n  eprint={2512.12069},\n  archivePrefix={arXiv},\n}\n\n@article{jiang2024redqueen,\n  title={{RED QUEEN}: Safeguarding Large Language Models against Concealed Multi-Turn Jailbreaking},\n  author={Jiang, Yifan and Aggarwal, Kriti and Laud, Tanmay and Munir, Kashif and Pujara, Jay and Mukherjee, Subhabrata},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2409.17458},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{song2026multibreak,\n  title={{MultiBreak}: A Scalable and Diverse Multi-turn Jailbreak Benchmark for Evaluating {LLM} Safety},\n  author={Song, Jialin and Liu, Xiaodong and Yang, Weiwei and Chen, Wuyang and Feng, Mingqian and Zhu, Xuekai and Gao, Jianfeng},\n  booktitle={International Conference on Machine Learning},\n  year={2026},\n  eprint={2605.01687},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% New citations (added 2026-05-21)\n% ============================================================\n\n@inproceedings{xie2024gradsafe,\n  title={{GradSafe}: Detecting Jailbreak Prompts for {LLMs} via Safety-Critical Gradient Analysis},\n  author={Xie, Yueqi and Fang, Minghong and Pi, Renjie and Gong, Neil},\n  booktitle={Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics},\n  pages={507--518},\n  year={2024},\n}\n\n@inproceedings{xu2024safedecoding,\n  title={{SafeDecoding}: Defending against Jailbreak Attacks via Safety-Aware Decoding},\n  author={Xu, Zhangchen and Jiang, Fengqing and Niu, Luyao and Jia, Jinyuan and Lin, Bill Yuchen and Poovendran, Radha},\n  booktitle={Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics},\n  year={2024},\n}\n\n@inproceedings{zou2024circuitbreakers,\n  title={Improving Alignment and Robustness with Circuit Breakers},\n  author={Zou, Andy and Phan, Long and Wang, Justin and Duenas, Derek and Lin, Maxwell and Andriushchenko, Maksym and Wang, Rowan and Kolter, Zico and Fredrikson, Matt and Hendrycks, Dan},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2024},\n}\n\n% ============================================================\n% New citations (added 2026-05-20)\n% ============================================================\n\n@inproceedings{zhang2025jbshield,\n  title={{JBShield}: Defending Large Language Models from Jailbreak Attacks through Activated Concept Analysis and Manipulation},\n  author={Zhang, Shenyi and Zhai, Yuchen and Guo, Keyan and Hu, Hongxin and Guo, Shengnan and Fang, Zheng and Zhao, Lingchen and Shen, Chao and Wang, Cong and Wang, Qian},\n  booktitle={USENIX Security Symposium},\n  year={2025},\n  eprint={2502.07557},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{perez2022redteaming,\n  title={Red Teaming Language Models with Language Models},\n  author={Perez, Ethan and Huang, Saffron and Song, Francis and Cai, Trevor and Ring, Roman and Aslanides, John and Glaese, Amelia and McAleese, Nat and Irving, Geoffrey},\n  booktitle={Proceedings of the 2022 Conference on Empirical Methods in Natural Language Processing},\n  pages={3419--3448},\n  year={2022},\n}\n\n@article{kulkarni2026latentadversarial,\n  title={Latent Adversarial Detection: Adaptive Probing of {LLM} Activations for Multi-Turn Attack Detection},\n  author={Kulkarni, Prashant},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2604.28129},\n  archivePrefix={arXiv},\n}\n\n@article{derya2026revisitingjbshield,\n  title={Revisiting {JBShield}: Breaking and Rebuilding Representation-Level Jailbreak Defenses},\n  author={Derya, Kemal and Sunar, Berk},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2605.03095},\n  archivePrefix={arXiv},\n}\n\n@article{lee2020biobert,\n  title={{BioBERT}: A Pre-trained Biomedical Language Representation Model for Biomedical Text Mining},\n  author={Lee, Jinhyuk and Yoon, Wonjin and Kim, Sungdong and Kim, Donghyeon and Kim, Sunkyu and So, Chan Ho and Kang, Jaewoo},\n  journal={Bioinformatics},\n  volume={36},\n  number={4},\n  pages={1234--1240},\n  year={2020},\n  publisher={Oxford University Press},\n}\n\n@inproceedings{beltagy2019scibert,\n  title={{SciBERT}: A Pretrained Language Model for Scientific Text},\n  author={Beltagy, Iz and Lo, Kyle and Cohan, Arman},\n  booktitle={Proceedings of the 2019 Conference on Empirical Methods in Natural Language Processing (EMNLP)},\n  pages={3615--3620},\n  year={2019},\n}\n\n@inproceedings{chen2020simclr,\n  title={A Simple Framework for Contrastive Learning of Visual Representations},\n  author={Chen, Ting and Kornblith, Simon and Norouzi, Mohammad and Hinton, Geoffrey},\n  booktitle={International Conference on Machine Learning (ICML)},\n  pages={1597--1607},\n  year={2020},\n}\n\n@inproceedings{grill2020byol,\n  title={Bootstrap Your Own Latent: A New Approach to Self-Supervised Learning},\n  author={Grill, Jean-Bastien and Strub, Florian and Altch{\\'e}, Florent and Tallec, Corentin and Richemond, Pierre H. and Buchatber, Elena and Doersch, Carl and Pires, Bernardo Avila and Guo, Zhaohan Daniel and Azar, Mohammad Gheshlaghi and Piot, Bilal and Kavukcuoglu, Koray and Munos, R{\\'e}mi and Valko, Michal},\n  booktitle={Advances in Neural Information Processing Systems (NeurIPS)},\n  year={2020},\n}\n\n% ============================================================\n% New citations (Round 10 fixes)\n% ============================================================\n\n@article{zhang2021understanding,\n  title={Understanding Deep Learning (Still) Requires Rethinking Generalization},\n  author={Zhang, Chiyuan and Bengio, Samy and Hardt, Moritz and Recht, Benjamin and Vinyals, Oriol},\n  journal={Communications of the ACM},\n  volume={64},\n  number={3},\n  pages={107--115},\n  year={2021},\n  doi={10.1145/3446776},\n}\n\n@inproceedings{maennel2020random,\n  title={What Do Neural Networks Learn When Trained With Random Labels?},\n  author={Maennel, Hartmut and Alabdulmohsin, Ibrahim M. and Tolstikhin, Ilya O. and Baldock, Robert J. N. and Bousquet, Olivier and Gelly, Sylvain and Keysers, Daniel},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2020},\n}\n",
      "numLines": 657,
      "startLine": 1,
      "totalLines": 657
    }
  }
}
```

</details>

---

### Assistant

_source line 9_

<details><summary>Logged reasoning block</summary>

```text
Now I need to:
1. Confirm Austin and Cialdini entries are correct (already read them)
2. Search for "maennel" in all .tex files
3. Search for all bib keys in .tex files to find orphaned entries
4. Check for bib mismatches

Let me do the searches in parallel. I have all 31 bib keys from the file. Let me extract them and search.

Bib keys from references.bib:
1. inan2023llamaguard
2. metallamaguard3_2024


3. zeng2024shieldgemma
4. han2024wildguard
5. anthropic2025constitutional
6. deepcontext2026
7. tong2025biid
8. gguard2025
9. safedream2026
10. bullwinkel2025repeng
11. mann1988rst
12. prasad2008pdtb
13. stolcke2000dialogueact
14. austin1962speechacts
15. searle1969speechacts
16. cialdini2001influence
17. zeng2024pap
18. russinovich2024crescendo
19. chao2023pair
20. wei2023jailbroken
21. hag

2026endorff2025reasoning
22. fitd2024
23. deceptivedelight2024
24. ren2024actorattack
25. zou2023gcg
26. lin2023toxicchat
27. li2024mhj
28. gururangan2018artifacts
29. niven2019probing
30. nasr2025attackermovessecond
31. andriushchenko2024adaptive
32. he2021deberta
33. he2023debertav3
34. kornblith2019cka
35. qwen3_2025
36. gururangan2020dontstop
37. caruana1997multitask
38. phang2018stilts
39. liu2019mtdnn
40. howard2018ulmfit
41. dasanmartino2020semeval
42. dasanmartino2019fine
43. jin2020textf

Continuing to compile the bibliography...

44. li2020bertattack
45. devlin2019bert
46. conneau2018probing
47. hewitt2019structural
48. liu2019roberta
49. wang2019persuasion
50. robey2024smoothllm
51. mehrotra2024tap
52. chao2024jailbreakbench
53. mazeika2024harmbench
54. lu2025xboundary
55. kadali2026trace
56. hua2026rcs
57. jiang2024redqueen
58. song2026multibreak
59. xie2024gradsafe
60. xu2024safedecoding
61. zou2024circuitbreakers
62. zhang2025jbshield
63. perez2022redteaming
64. kulkarni2026latentadversarial
65. derya2026revisitingjbshield
66. lee2020biobert
67. beltagy2019scibert
68. chen2020simclr
69. grill2020byol
70. zhang2021understanding
71. maennel2020random

Now I need to search through the tex files for all the citation commands to identify which reference keys are actually being used.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "02566e2c-662a-4508-b084-cee5685d86d1",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JhMoDesKnmyC2rHYy4bdQx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 106,
      "cache_creation_input_tokens": 10654,
      "cache_read_input_tokens": 24342,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10654
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

_source line 10_

Now let me search for maennel citations and gather all cite references from the .tex files.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "ed92fe76-104a-4ced-9b5a-03b6bc45cab6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JhMoDesKnmyC2rHYy4bdQx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 106,
      "cache_creation_input_tokens": 10654,
      "cache_read_input_tokens": 24342,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10654
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

_source line 11_

<details open><summary>🔧 Tool call — Grep · `toolu_0143ZYokGCcnjWpgsKuF32ha`</summary>

```json
{
  "pattern": "maennel",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper",
  "glob": "*.tex",
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
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "806b90cc-757a-4de5-a8a7-7ddb9b290571",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JhMoDesKnmyC2rHYy4bdQx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 106,
      "cache_creation_input_tokens": 10654,
      "cache_read_input_tokens": 24342,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10654
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

_source line 12 · 2026-05-21T23:09:45.537Z_

<details><summary>↩ Tool result · `toolu_0143ZYokGCcnjWpgsKuF32ha`</summary>

```text
No matches found
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "b9293b59-ace9-47fe-a955-e781175a442f",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "",
    "numLines": 0
  }
}
```

</details>

---

### Tool call

_source line 13_

<details open><summary>🔧 Tool call — Grep · `toolu_01H2LLhPbv6C487ty7bLxecL`</summary>

```json
{
  "pattern": "\\\\cite[tp]?\\{[^}]+\\}",
  "path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper",
  "glob": "*.tex",
  "output_mode": "content",
  "head_limit": 0
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "da2db8f4-1312-42ae-ae96-fc05aaea98da",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01JhMoDesKnmyC2rHYy4bdQx",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 106,
      "cache_creation_input_tokens": 10654,
      "cache_read_input_tokens": 24342,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 10654
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

_source line 14 · 2026-05-21T23:09:46.762Z_

<details><summary>↩ Tool result · `toolu_01H2LLhPbv6C487ty7bLxecL`</summary>

```text
docs/paper/related_work.tex:6:[Omitted long matching line]
docs/paper/related_work.tex:9:[Omitted long matching line]
docs/paper/related_work.tex:12:[Omitted long matching line]
docs/paper/related_work.tex:15:[Omitted long matching line]
docs/paper/experiments.tex:6:[Omitted long matching line]
docs/paper/experiments.tex:11:All synthetic data is generated by Qwen3-8B~\citep{qwen3_2025}.
docs/paper/experiments.tex:12:The IID dataset contains 250 Crescendo~\citep{russinovich2024crescendo} jailbreak and 250 topic-anchored benign conversations, split into training (350), validation (74), and test (76) sets with balanced class ratios (e.g., test = 38 jailbreak + 38 benign).
docs/paper/experiments.tex:14:OOD evaluation pairs attack-specific jailbreak conversations with the 38 IID-test benign conversations: 80 FITD~\citep{fitd2024} (non-discriminative; Section~\ref{sec:decomposition}) + 38 benign = 118 total, 80 Deceptive Delight (DD)~\citep{deceptivedelight2024} + 38 benign = 118 total, and 80 ActorAttack~\citep{ren2024actorattack} + 38 benign = 118 total.
docs/paper/experiments.tex:17:For human data validation, we use ToxicChat~\citep{lin2023toxicchat} (204 jailbreak + 204 benign from real LMSYS user interactions), entirely independent of Qwen3-8B generation.
docs/paper/experiments.tex:21:Our vanilla DeBERTa+BiGRU configuration is architecturally equivalent to DeepContext~\citep{deepcontext2026}, differing only in encoder choice (DeBERTa-v3-base vs.\ BERT); it serves as our primary baseline.
docs/paper/experiments.tex:22:For cross-encoder validation, we replicate vanilla, MLM, and 9-class variants on RoBERTa-base~\citep{liu2019roberta} (Section~\ref{sec:cross_encoder}).
docs/paper/experiments.tex:23:We also compare TF-IDF LR, LLM-as-judge (Appendix~\ref{sec:llm_judge}), and Llama Guard~3~8B~\citep{metallamaguard3_2024} (zero-shot; evaluates last-response safety given conversation context), which detects only 1.8\% of multi-turn jailbreaks (Table~\ref{tab:evidence_hierarchy}).
docs/paper/experiments.tex:58:On OOD DD, vanilla DeBERTa collapses to F1 = 0.312$\pm$0.026, worsening with more turns (0.628 at $K$=1 to 0.312 at Full), consistent with attack turns occupying ``benign'' embedding regions~\citep{bullwinkel2025repeng}.
docs/paper/experiments.tex:111:MLM bridges $\sim$60\,pp from vanilla (0.312$\pm$0.026 $\to$ 0.914$\pm$0.115) without labels; this supports the DAPT interpretation~\citep{gururangan2020dontstop}. TF-IDF collapse on ActorAttack (0.261 vs.\ 9-class 0.972) confirms that domain-adapted representations capture features beyond lexical overlap.
docs/paper/experiments.tex:124:ActorAttack~\citep{ren2024actorattack} uses multi-persona steering across longer conversation structures and provides a more challenging OOD benchmark than DD.
docs/paper/experiments.tex:174:To test whether the evidence hierarchy depends on encoder choice, we replicate vanilla, MLM, and 9-class on RoBERTa-base~\citep{liu2019roberta} (Table~\ref{tab:cross_encoder}).
docs/paper/experiments.tex:183:CKA analysis~\citep{kornblith2019cka} and linear probing confirm that DAPT reshapes representations substantially (Figure~\ref{fig:cka_heatmap}), though comparable CKA shifts yield different detection gains across starting points (Appendix~\ref{sec:cka_heatmap}).
docs/paper/experiments.tex:196:Since both training and OOD evaluation data are Qwen3-8B-generated, we validate on ToxicChat~\citep{lin2023toxicchat} (204 human-written jailbreak attempts + 204 benign conversations from real LMSYS interactions).
docs/paper/experiments.tex:201:\caption{Human data validation on ToxicChat~\citep{lin2023toxicchat} (macro F1, 3-seed mean$\pm$std). Bold indicates best. Single-turn data from real LMSYS user interactions, independent of Qwen3-8B.}
docs/paper/conclusion.tex:19:[Omitted long matching line]
docs/paper/conclusion.tex:35:Three encoders (125M--355M) differ in architecture and pretraining; same-architecture scaling is needed to isolate the capacity effect, and whether findings hold at LLM-scale encoders (7B+) remains open. Only persuasion-mediated multi-turn attacks fall within scope; single-turn token-level attacks~\citep{zou2023gcg}, non-persuasive strategies, and non-text modalities are not addressed. Total pipeline cost is under 4 GPU-hours on a single A100.
docs/paper/checklist.tex:27:  \item Did you cite the creators of artifacts you used? \textbf{Yes.} DeBERTa-v3~\citep{he2023debertav3}, RoBERTa~\citep{liu2019roberta}, Qwen3-8B~\citep{qwen3_2025} (for data generation).
docs/paper/method.tex:14:Each user turn $u_i$ is encoded by DeBERTa-v3-base~\citep{he2023debertav3}; the \texttt{[CLS]} embedding $h_i \in \mathbb{R}^d$ serves as the turn representation. Seven variants, summarized in Table~\ref{tab:variants}, share the same training data but differ in objective.
docs/paper/method.tex:36:[Omitted long matching line]
docs/paper/appendix.tex:177:FITD conversations show a markedly sparser pattern (541 transitions), with Role$\to$Obfuscation (161) as the dominant transition, consistent with FITD's commitment-consistency exploitation~\citep{cialdini2001influence}.
docs/paper/appendix.tex:178:DD conversations span 5 active source strategies (565 transitions), with Emotion$\to$Obfuscation (129) as the dominant transition, aligning with DD's design of embedding harmful content within emotionally engaging contexts~\citep{deceptivedelight2024}.
docs/paper/appendix.tex:186:\caption{Centered CKA similarity~\citep{kornblith2019cka} between encoder variants on IID and OOD data for DeBERTa-v3 and RoBERTa. Low off-diagonal values (vanilla vs.\ adapted variants) confirm that continued pretraining substantially reshapes representations; the MLM vs.\ 9-class block shows distinct geometries (CKA $\leq$ 0.2 on RoBERTa OOD).}
docs/paper/appendix.tex:401:\caption{BERT-base-uncased (110M) frozen probing without DAPT, matching DeepContext's encoder family~\citep{deepcontext2026}. 3-seed mean$\pm$std. DeBERTa-v3 results from Table~\ref{tab:cross_encoder} for comparison.}
docs/paper/introduction.tex:5:[Omitted long matching line]
docs/paper/introduction.tex:7:[Omitted long matching line]
docs/paper/introduction.tex:9:Pretrained language understanding does not suffice at base model scale: vanilla DeBERTa-v3~\citep{he2021deberta} with temporal aggregation (cf.\ DeepContext) drops from F1\,=\,1.000 in-distribution to 0.312 on OOD Deceptive Delight, and GPT-5.5 reaches only 0.191--0.449 F1 with 30--47\% unparseable responses (Appendix~\ref{sec:llm_judge}). The bottleneck is distributional: cross-attack generalization requires domain adaptation, not a better classifier.
docs/paper/introduction.tex:20:[Omitted long matching line]
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "efab19cb-d1b2-4bca-afb7-389b0e572ceb",
  "tool_use_result": {
    "mode": "content",
    "numFiles": 0,
    "filenames": [],
    "content": "docs/paper/related_work.tex:6:[Omitted long matching line]\ndocs/paper/related_work.tex:9:[Omitted long matching line]\ndocs/paper/related_work.tex:12:[Omitted long matching line]\ndocs/paper/related_work.tex:15:[Omitted long matching line]\ndocs/paper/experiments.tex:6:[Omitted long matching line]\ndocs/paper/experiments.tex:11:All synthetic data is generated by Qwen3-8B~\\citep{qwen3_2025}.\ndocs/paper/experiments.tex:12:The IID dataset contains 250 Crescendo~\\citep{russinovich2024crescendo} jailbreak and 250 topic-anchored benign conversations, split into training (350), validation (74), and test (76) sets with balanced class ratios (e.g., test = 38 jailbreak + 38 benign).\ndocs/paper/experiments.tex:14:OOD evaluation pairs attack-specific jailbreak conversations with the 38 IID-test benign conversations: 80 FITD~\\citep{fitd2024} (non-discriminative; Section~\\ref{sec:decomposition}) + 38 benign = 118 total, 80 Deceptive Delight (DD)~\\citep{deceptivedelight2024} + 38 benign = 118 total, and 80 ActorAttack~\\citep{ren2024actorattack} + 38 benign = 118 total.\ndocs/paper/experiments.tex:17:For human data validation, we use ToxicChat~\\citep{lin2023toxicchat} (204 jailbreak + 204 benign from real LMSYS user interactions), entirely independent of Qwen3-8B generation.\ndocs/paper/experiments.tex:21:Our vanilla DeBERTa+BiGRU configuration is architecturally equivalent to DeepContext~\\citep{deepcontext2026}, differing only in encoder choice (DeBERTa-v3-base vs.\\ BERT); it serves as our primary baseline.\ndocs/paper/experiments.tex:22:For cross-encoder validation, we replicate vanilla, MLM, and 9-class variants on RoBERTa-base~\\citep{liu2019roberta} (Section~\\ref{sec:cross_encoder}).\ndocs/paper/experiments.tex:23:We also compare TF-IDF LR, LLM-as-judge (Appendix~\\ref{sec:llm_judge}), and Llama Guard~3~8B~\\citep{metallamaguard3_2024} (zero-shot; evaluates last-response safety given conversation context), which detects only 1.8\\% of multi-turn jailbreaks (Table~\\ref{tab:evidence_hierarchy}).\ndocs/paper/experiments.tex:58:On OOD DD, vanilla DeBERTa collapses to F1 = 0.312$\\pm$0.026, worsening with more turns (0.628 at $K$=1 to 0.312 at Full), consistent with attack turns occupying ``benign'' embedding regions~\\citep{bullwinkel2025repeng}.\ndocs/paper/experiments.tex:111:MLM bridges $\\sim$60\\,pp from vanilla (0.312$\\pm$0.026 $\\to$ 0.914$\\pm$0.115) without labels; this supports the DAPT interpretation~\\citep{gururangan2020dontstop}. TF-IDF collapse on ActorAttack (0.261 vs.\\ 9-class 0.972) confirms that domain-adapted representations capture features beyond lexical overlap.\ndocs/paper/experiments.tex:124:ActorAttack~\\citep{ren2024actorattack} uses multi-persona steering across longer conversation structures and provides a more challenging OOD benchmark than DD.\ndocs/paper/experiments.tex:174:To test whether the evidence hierarchy depends on encoder choice, we replicate vanilla, MLM, and 9-class on RoBERTa-base~\\citep{liu2019roberta} (Table~\\ref{tab:cross_encoder}).\ndocs/paper/experiments.tex:183:CKA analysis~\\citep{kornblith2019cka} and linear probing confirm that DAPT reshapes representations substantially (Figure~\\ref{fig:cka_heatmap}), though comparable CKA shifts yield different detection gains across starting points (Appendix~\\ref{sec:cka_heatmap}).\ndocs/paper/experiments.tex:196:Since both training and OOD evaluation data are Qwen3-8B-generated, we validate on ToxicChat~\\citep{lin2023toxicchat} (204 human-written jailbreak attempts + 204 benign conversations from real LMSYS interactions).\ndocs/paper/experiments.tex:201:\\caption{Human data validation on ToxicChat~\\citep{lin2023toxicchat} (macro F1, 3-seed mean$\\pm$std). Bold indicates best. Single-turn data from real LMSYS user interactions, independent of Qwen3-8B.}\ndocs/paper/conclusion.tex:19:[Omitted long matching line]\ndocs/paper/conclusion.tex:35:Three encoders (125M--355M) differ in architecture and pretraining; same-architecture scaling is needed to isolate the capacity effect, and whether findings hold at LLM-scale encoders (7B+) remains open. Only persuasion-mediated multi-turn attacks fall within scope; single-turn token-level attacks~\\citep{zou2023gcg}, non-persuasive strategies, and non-text modalities are not addressed. Total pipeline cost is under 4 GPU-hours on a single A100.\ndocs/paper/checklist.tex:27:  \\item Did you cite the creators of artifacts you used? \\textbf{Yes.} DeBERTa-v3~\\citep{he2023debertav3}, RoBERTa~\\citep{liu2019roberta}, Qwen3-8B~\\citep{qwen3_2025} (for data generation).\ndocs/paper/method.tex:14:Each user turn $u_i$ is encoded by DeBERTa-v3-base~\\citep{he2023debertav3}; the \\texttt{[CLS]} embedding $h_i \\in \\mathbb{R}^d$ serves as the turn representation. Seven variants, summarized in Table~\\ref{tab:variants}, share the same training data but differ in objective.\ndocs/paper/method.tex:36:[Omitted long matching line]\ndocs/paper/appendix.tex:177:FITD conversations show a markedly sparser pattern (541 transitions), with Role$\\to$Obfuscation (161) as the dominant transition, consistent with FITD's commitment-consistency exploitation~\\citep{cialdini2001influence}.\ndocs/paper/appendix.tex:178:DD conversations span 5 active source strategies (565 transitions), with Emotion$\\to$Obfuscation (129) as the dominant transition, aligning with DD's design of embedding harmful content within emotionally engaging contexts~\\citep{deceptivedelight2024}.\ndocs/paper/appendix.tex:186:\\caption{Centered CKA similarity~\\citep{kornblith2019cka} between encoder variants on IID and OOD data for DeBERTa-v3 and RoBERTa. Low off-diagonal values (vanilla vs.\\ adapted variants) confirm that continued pretraining substantially reshapes representations; the MLM vs.\\ 9-class block shows distinct geometries (CKA $\\leq$ 0.2 on RoBERTa OOD).}\ndocs/paper/appendix.tex:401:\\caption{BERT-base-uncased (110M) frozen probing without DAPT, matching DeepContext's encoder family~\\citep{deepcontext2026}. 3-seed mean$\\pm$std. DeBERTa-v3 results from Table~\\ref{tab:cross_encoder} for comparison.}\ndocs/paper/introduction.tex:5:[Omitted long matching line]\ndocs/paper/introduction.tex:7:[Omitted long matching line]\ndocs/paper/introduction.tex:9:Pretrained language understanding does not suffice at base model scale: vanilla DeBERTa-v3~\\citep{he2021deberta} with temporal aggregation (cf.\\ DeepContext) drops from F1\\,=\\,1.000 in-distribution to 0.312 on OOD Deceptive Delight, and GPT-5.5 reaches only 0.191--0.449 F1 with 30--47\\% unparseable responses (Appendix~\\ref{sec:llm_judge}). The bottleneck is distributional: cross-attack generalization requires domain adaptation, not a better classifier.\ndocs/paper/introduction.tex:20:[Omitted long matching line]",
    "numLines": 32
  }
}
```

</details>

---

### Assistant

_source line 15_

<details><summary>Logged reasoning block</summary>

```text
maennel2020random is NOT cited in any .tex file. I need to add it alongside zhang2021understanding in conclusion.tex. Let me read the relevant part of conclusion.tex to find the exact text.

Now let me also extract all the cited keys from the tex files to find orphaned bib entries. Let me get the full content of the omitted long lines.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "a478c51e-3ef2-452e-a5c0-d9bc6b06ffe5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WpCnKmRcV1gCwirGvwui5r",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3504,
      "cache_read_input_tokens": 34996,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3504
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

_source line 16_

maennel2020random is not cited. Let me read the conclusion.tex Discussion section and also extract all cited keys more precisely.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "1cef30b4-c4e5-47a7-b31f-521dbf7b7c4f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WpCnKmRcV1gCwirGvwui5r",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3504,
      "cache_read_input_tokens": 34996,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3504
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

_source line 17_

<details open><summary>🔧 Tool call — Read · `toolu_01Fj8ihwoV6RCXoyHNvbS2no`</summary>

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
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "a3adde66-8fd4-4672-b08c-c3bb672c5538",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WpCnKmRcV1gCwirGvwui5r",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3504,
      "cache_read_input_tokens": 34996,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3504
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

_source line 18 · 2026-05-21T23:09:52.058Z_

<details><summary>↩ Tool result · `toolu_01Fj8ihwoV6RCXoyHNvbS2no`</summary>

```text
1	% conclusion.tex — compressed for 8-page limit
2	
3	\section{Discussion}
4	\label{sec:discussion}
5	
6	\paragraph{Topic shortcut and label equivalence.}
7	Three observations argue against a topic shortcut: unstable topic OOD (F1\,=\,0.541$\pm$0.207), scrambled labels within 3.9\,pp, and label-free MLM detection (F1\,$\geq$\,0.97).
8	
9	\paragraph{Single-LLM confound.}
10	ToxicChat (+18--42\,pp; Table~\ref{tab:human_data}) and cross-LLM experiments (Appendix~\ref{app:cross_llm}) confirm transfer. Mixed-LLM 9-class maintains DD F1\,=\,0.818$\pm$0.096 (+53\,pp) while MLM collapses to vanilla level.
11	
12	\paragraph{Variance reversal on human data.}
13	Classification supervision is associated with lower variance on synthetic OOD (4--20$\times$ observed range, 3 seeds); on ToxicChat this reverses (std\,=\,0.087 vs.\ 0.013). Frozen probing localizes MLM instability to Stage-2 (Appendix~\ref{app:frozen_verify}).
14	
15	\paragraph{Encoder capacity and lexical analysis.}
16	Three encoders (125M--355M) differ in pretraining; same-architecture scaling is needed. TF-IDF collapses on ActorAttack (0.261 vs.\ 0.961 on DD).
17	
18	\paragraph{Regularization mechanism.}
19	Frozen probing near-parity (AA gap 3.1\,pp), label irrelevance ($d$\,=\,0.09), and mean pooling matching BiGRU ($|\Delta| < 1$\,pp) converge: classification DAPT provides robustness through optimization regularization, not semantic feature learning, paralleling self-supervised results where training structure matters more than label content~\citep{chen2020simclr,grill2020byol}. Unlike random-label memorization~\citep{zhang2021understanding}, random-label \emph{pretraining} here produces transferable representations, suggesting that classification structure regularizes the space. Three extensions emerge: MLM collapses under mixed-LLM training despite single-LLM effectiveness, frozen probing near-parity coexists with 8\,pp end-to-end gaps, and the hierarchy reverses on human data.
20	
21	\paragraph{Benign distribution as the remaining bottleneck.}
22	OOD F1 figures are upper bounds (benign is IID). On WildChat, 9-class FPR reaches 68.1\% (Appendix~\ref{app:wildchat_fpr}); cross-LLM error decomposition confirms collapse is driven by false positives on unfamiliar benign text.
23	
24	\section{Conclusion}
25	
26	On synthetic multi-turn evaluations, classification-based DAPT is the most robust adaptation for base-size encoders, providing robustness through optimization regularization rather than semantic learning; unsupervised pretraining collapses under mixed-LLM training. Negative results on label correctness (TOST-confirmed on DD at $n$\,=\,5; $d$\,=\,0.09 on ActorAttack), temporal order, and domain specificity constrain which properties matter; continued pretraining is 266$\times$ faster than LLM-as-judge (Appendix~\ref{app:efficiency}), offering a practical alternative given matched benign distributions (Appendix~\ref{app:wildchat_fpr}).
27	
28	\section{Limitations}
29	\label{sec:limitations}
30	
31	All multi-turn findings derive from synthetic conversations generated by Qwen3-8B (350 training, 76--118 test per family). ToxicChat validates transfer to human-authored single-turn attacks (+18--42\,pp over vanilla), but no human-generated multi-turn jailbreak dataset exists. Whether the evidence hierarchy generalizes to human-authored multi-turn attacks remains the primary open question (length confound analysis in Appendix~\ref{app:length_independence}).
32	
33	OOD results reflect attack-side generalization only: benign data is IID, so OOD F1 figures are upper bounds (Section~\ref{sec:discussion}). On WildChat, 9-class FPR reaches 68.1\% (Appendix~\ref{app:wildchat_fpr}); residual calibration error (ECE\,=\,0.126--0.141; Appendix~\ref{app:calibration}) suggests temperature scaling is needed for deployment.
34	
35	Three encoders (125M--355M) differ in architecture and pretraining; same-architecture scaling is needed to isolate the capacity effect, and whether findings hold at LLM-scale encoders (7B+) remains open. Only persuasion-mediated multi-turn attacks fall within scope; single-turn token-level attacks~\citep{zou2023gcg}, non-persuasive strategies, and non-text modalities are not addressed. Total pipeline cost is under 4 GPU-hours on a single A100.
36	
37	\section*{Ethics Statement}
38	
39	This work is defensive: it improves detection of multi-turn jailbreak attacks rather than developing new attacks. We acknowledge dual-use risk, as the persuasion taxonomy could inform adversarial actors. We mitigate this by using only synthetic conversations (no real harmful content), withholding attack-generation prompts, and focusing contributions on detection mechanisms. No human subjects were involved; all data will be released under CC BY-NC 4.0.
40	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "a57e3235-7a70-48b9-86a7-defa84896d69",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/conclusion.tex",
      "content": "% conclusion.tex — compressed for 8-page limit\n\n\\section{Discussion}\n\\label{sec:discussion}\n\n\\paragraph{Topic shortcut and label equivalence.}\nThree observations argue against a topic shortcut: unstable topic OOD (F1\\,=\\,0.541$\\pm$0.207), scrambled labels within 3.9\\,pp, and label-free MLM detection (F1\\,$\\geq$\\,0.97).\n\n\\paragraph{Single-LLM confound.}\nToxicChat (+18--42\\,pp; Table~\\ref{tab:human_data}) and cross-LLM experiments (Appendix~\\ref{app:cross_llm}) confirm transfer. Mixed-LLM 9-class maintains DD F1\\,=\\,0.818$\\pm$0.096 (+53\\,pp) while MLM collapses to vanilla level.\n\n\\paragraph{Variance reversal on human data.}\nClassification supervision is associated with lower variance on synthetic OOD (4--20$\\times$ observed range, 3 seeds); on ToxicChat this reverses (std\\,=\\,0.087 vs.\\ 0.013). Frozen probing localizes MLM instability to Stage-2 (Appendix~\\ref{app:frozen_verify}).\n\n\\paragraph{Encoder capacity and lexical analysis.}\nThree encoders (125M--355M) differ in pretraining; same-architecture scaling is needed. TF-IDF collapses on ActorAttack (0.261 vs.\\ 0.961 on DD).\n\n\\paragraph{Regularization mechanism.}\nFrozen probing near-parity (AA gap 3.1\\,pp), label irrelevance ($d$\\,=\\,0.09), and mean pooling matching BiGRU ($|\\Delta| < 1$\\,pp) converge: classification DAPT provides robustness through optimization regularization, not semantic feature learning, paralleling self-supervised results where training structure matters more than label content~\\citep{chen2020simclr,grill2020byol}. Unlike random-label memorization~\\citep{zhang2021understanding}, random-label \\emph{pretraining} here produces transferable representations, suggesting that classification structure regularizes the space. Three extensions emerge: MLM collapses under mixed-LLM training despite single-LLM effectiveness, frozen probing near-parity coexists with 8\\,pp end-to-end gaps, and the hierarchy reverses on human data.\n\n\\paragraph{Benign distribution as the remaining bottleneck.}\nOOD F1 figures are upper bounds (benign is IID). On WildChat, 9-class FPR reaches 68.1\\% (Appendix~\\ref{app:wildchat_fpr}); cross-LLM error decomposition confirms collapse is driven by false positives on unfamiliar benign text.\n\n\\section{Conclusion}\n\nOn synthetic multi-turn evaluations, classification-based DAPT is the most robust adaptation for base-size encoders, providing robustness through optimization regularization rather than semantic learning; unsupervised pretraining collapses under mixed-LLM training. Negative results on label correctness (TOST-confirmed on DD at $n$\\,=\\,5; $d$\\,=\\,0.09 on ActorAttack), temporal order, and domain specificity constrain which properties matter; continued pretraining is 266$\\times$ faster than LLM-as-judge (Appendix~\\ref{app:efficiency}), offering a practical alternative given matched benign distributions (Appendix~\\ref{app:wildchat_fpr}).\n\n\\section{Limitations}\n\\label{sec:limitations}\n\nAll multi-turn findings derive from synthetic conversations generated by Qwen3-8B (350 training, 76--118 test per family). ToxicChat validates transfer to human-authored single-turn attacks (+18--42\\,pp over vanilla), but no human-generated multi-turn jailbreak dataset exists. Whether the evidence hierarchy generalizes to human-authored multi-turn attacks remains the primary open question (length confound analysis in Appendix~\\ref{app:length_independence}).\n\nOOD results reflect attack-side generalization only: benign data is IID, so OOD F1 figures are upper bounds (Section~\\ref{sec:discussion}). On WildChat, 9-class FPR reaches 68.1\\% (Appendix~\\ref{app:wildchat_fpr}); residual calibration error (ECE\\,=\\,0.126--0.141; Appendix~\\ref{app:calibration}) suggests temperature scaling is needed for deployment.\n\nThree encoders (125M--355M) differ in architecture and pretraining; same-architecture scaling is needed to isolate the capacity effect, and whether findings hold at LLM-scale encoders (7B+) remains open. Only persuasion-mediated multi-turn attacks fall within scope; single-turn token-level attacks~\\citep{zou2023gcg}, non-persuasive strategies, and non-text modalities are not addressed. Total pipeline cost is under 4 GPU-hours on a single A100.\n\n\\section*{Ethics Statement}\n\nThis work is defensive: it improves detection of multi-turn jailbreak attacks rather than developing new attacks. We acknowledge dual-use risk, as the persuasion taxonomy could inform adversarial actors. We mitigate this by using only synthetic conversations (no real harmful content), withholding attack-generation prompts, and focusing contributions on detection mechanisms. No human subjects were involved; all data will be released under CC BY-NC 4.0.\n",
      "numLines": 40,
      "startLine": 1,
      "totalLines": 40
    }
  }
}
```

</details>

---

### Tool call

_source line 19_

<details open><summary>🔧 Tool call — Bash · `toolu_016MnBnbUCvVg9emmBniKZjZ`</summary>

```json
{
  "command": "cd /home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper && grep -oP '\\\\cite[tp]?\\{[^}]+\\}' *.tex | grep -oP '\\{[^}]+\\}' | tr -d '{}' | tr ',' '\\n' | sed 's/^ *//;s/ *$//' | sort -u",
  "description": "Extract all unique cited bib keys from .tex files"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "6dfd456a-12b3-4e2f-8629-544f0fad16ce",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01WpCnKmRcV1gCwirGvwui5r",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3504,
      "cache_read_input_tokens": 34996,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3504
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

_source line 20 · 2026-05-21T23:09:53.660Z_

<details><summary>↩ Tool result · `toolu_016MnBnbUCvVg9emmBniKZjZ`</summary>

```text
andriushchenko2024adaptive
anthropic2025constitutional
austin1962speechacts
beltagy2019scibert
bullwinkel2025repeng
caruana1997multitask
chao2023pair
chao2024jailbreakbench
chen2020simclr
cialdini2001influence
conneau2018probing
dasanmartino2019fine
dasanmartino2020semeval
deceptivedelight2024
deepcontext2026
derya2026revisitingjbshield
fitd2024
gguard2025
grill2020byol
gururangan2018artifacts
gururangan2020dontstop
hagendorff2026reasoning
han2024wildguard
he2021deberta
he2023debertav3
hewitt2019structural
howard2018ulmfit
hua2026rcs
inan2023llamaguard
jiang2024redqueen
jin2020textfooler
kadali2026trace
kornblith2019cka
kulkarni2026latentadversarial
lee2020biobert
li2020bertattack
li2024mhj
lin2023toxicchat
liu2019mtdnn
liu2019roberta
lu2025xboundary
mann1988rst
mazeika2024harmbench
mehrotra2024tap
metallamaguard3_2024
nasr2025attackermovessecond
niven2019probing
perez2022redteaming
phang2018stilts
prasad2008pdtb
qwen3_2025
ren2024actorattack
robey2024smoothllm
russinovich2024crescendo
safedream2026
searle1969speechacts
song2026multibreak
stolcke2000dialogueact
tong2025biid
wang2019persuasion
wei2023jailbroken
xie2024gradsafe
xu2024safedecoding
zeng2024pap
zeng2024shieldgemma
zhang2021understanding
zhang2025jbshield
zou2023gcg
zou2024circuitbreakers
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "7eeedf64-216f-4e2d-9d49-c54d84433771",
  "tool_use_result": {
    "stdout": "andriushchenko2024adaptive\nanthropic2025constitutional\naustin1962speechacts\nbeltagy2019scibert\nbullwinkel2025repeng\ncaruana1997multitask\nchao2023pair\nchao2024jailbreakbench\nchen2020simclr\ncialdini2001influence\nconneau2018probing\ndasanmartino2019fine\ndasanmartino2020semeval\ndeceptivedelight2024\ndeepcontext2026\nderya2026revisitingjbshield\nfitd2024\ngguard2025\ngrill2020byol\ngururangan2018artifacts\ngururangan2020dontstop\nhagendorff2026reasoning\nhan2024wildguard\nhe2021deberta\nhe2023debertav3\nhewitt2019structural\nhoward2018ulmfit\nhua2026rcs\ninan2023llamaguard\njiang2024redqueen\njin2020textfooler\nkadali2026trace\nkornblith2019cka\nkulkarni2026latentadversarial\nlee2020biobert\nli2020bertattack\nli2024mhj\nlin2023toxicchat\nliu2019mtdnn\nliu2019roberta\nlu2025xboundary\nmann1988rst\nmazeika2024harmbench\nmehrotra2024tap\nmetallamaguard3_2024\nnasr2025attackermovessecond\nniven2019probing\nperez2022redteaming\nphang2018stilts\nprasad2008pdtb\nqwen3_2025\nren2024actorattack\nrobey2024smoothllm\nrussinovich2024crescendo\nsafedream2026\nsearle1969speechacts\nsong2026multibreak\nstolcke2000dialogueact\ntong2025biid\nwang2019persuasion\nwei2023jailbroken\nxie2024gradsafe\nxu2024safedecoding\nzeng2024pap\nzeng2024shieldgemma\nzhang2021understanding\nzhang2025jbshield\nzou2023gcg\nzou2024circuitbreakers",
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

_source line 21_

<details><summary>Logged reasoning block</summary>

```text
Now let me compare the bib keys in references.bib with the cited keys in .tex files.

Bib keys from references.bib:
1. inan2023llamaguard
2. metallamaguard3_2024
3. zeng2024shieldgemma
4. han2024wildguard
5. anthropic2025constitutional
6. deepcontext2026
7. tong2025biid
8. gguard2025
9. safedream2026
10. bullwinkel2025repeng
11. mann1988rst
12. prasad2008pdtb


13. stolcke2000dialogueact
14. austin1962speechacts
15. searle1969speechacts
16. cialdini2001influence
17. zeng2024pap
18. russinovich2024crescendo
19. chao2023pair
20. wei2023jailbroken
21. hagendorff2026reasoning
22. fitd2024
23. deceptivedelight2024
24. ren2024actorattack
25. zou2023gcg
26. lin2023toxicchat
27. li2024mhj
28. gururangan2018artifacts
29. niven2019probing
30. na
31. sr2025attackermovessecond
32. andriushchenko2024adaptive
33. he2021deberta
34. he2023debertav3
35. kornblith2019cka
36. qwen3_2025
37. gururangan2020dontstop
38. caruana1997multitask
39. phang2018stilts
40. liu2019mtdnn
41. howard2018ulmfit
42. dasanmartino2020semeval
43. dasanmartino2019fine
44. jin2020textfooler
45. li2020bertattack
46. devlin2019bert
47. conneau2018probing
48. hewitt2019structural
49. liu2019roberta
50. wang2019persuasion
51. robey2024smoothllm
52. meh
53. rotra2024tap
54. chao2024jailbreakbench
55. mazeika2024harmbench
56. lu2025xboundary
57. kadali2026trace
58. hua2026rcs
59. jiang2024redqueen
60. song2026multibreak
61. xie2024gradsafe
62. xu2024safedecoding
63. zou2024circuitbreakers
64. zhang2025jbshield
65. perez2022redteaming
66. kulkarni2026latentadversarial
67. derya2026revisitingjbshield
68. lee2020biobert
69. beltagy2019scibert
70. chen2020simclr
71. grill2020byol
72. zhang2021understanding
73. maennel2020random

Now I'm cross-referencing the cited keys from the tex files to see which papers are actually being used in the document, checking against the full bibliography list I've compiled. I'm continuing through the bibliography to identify which citations are missing from the list I've already compiled.

Looking at the entries, devlin2019bert and maennel2020random aren't in my cited references, though I'm about to add a citation for maennel2020random, so devlin2019bert will be the only truly orphaned entry after my edits.

I'm also noticing a key-year mismatch with russinovich2024crescendo, where the key indicates 2024 but the bibliography shows 2025 for the USENIX Security publication—though there's already a comment explaining this discrepancy.

For chao2023pair, there's a similar situation with the key saying 2023 but the actual publication year being 2025 for SaTML, which also has an explanatory comment.

However, andriushchenko2024adaptive has a 2024 key but lists 2025 as the year for ICLR 2025, and this one lacks any comment explaining the mismatch—I should add one.

The bibliography entries appear to follow consistent formatting conventions overall, with arXiv papers using @article, published conference papers using @inproceedings, and metallamaguard3_2024 appropriately marked as @misc since it's not a formal publication.

I'm starting to check author name formatting and notice some entries have special characters that might need attention.

Looking at grill2020byol, the author field shows "Buchatber, Elena" but I'm fairly certain the correct name from the BYOL paper is Elena Buchatskaya, not Buchatber—this appears to be an error that needs fixing. typo. Now I'm checking the other entries — ren2024actorattack has the key listed as 2024 but the year is 2025 for ICLR 2025, same inconsistency as andriushchenko2024adaptive. I've also found that maennel2020random isn't actually cited anywhere, so I need to add that citation. Looking at the full picture, I've confirmed Austin and Cialdini are correct, but there's an orphaned devlin2019bert entry once I add the maennel citation, plus these bibliography mismatches to fix.

Now I'm ready to make the corrections: adding the maennel2020random citation to the conclusion, fixing the author name from Buchatber to Buchatskaya, and adding comment fields to the entries with key-year mismatches.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "f49c25c3-2b3c-4466-b0eb-776274de43aa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XmUUcfxEnLqkmnN9DguYHw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2402,
      "cache_read_input_tokens": 38500,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2402
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

_source line 22_

Found the data I need. Now let me make the edits. Two orphaned entries found: `devlin2019bert` and `maennel2020random`. One author typo: "Buchatber" should be "Buchatskaya" in grill2020byol. Two key-year mismatches need comments.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "17a71aea-0082-4b18-b734-ea57e9a08729",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XmUUcfxEnLqkmnN9DguYHw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2402,
      "cache_read_input_tokens": 38500,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2402
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

_source line 23_

<details open><summary>🔧 Tool call — Edit · `toolu_016KcYWhzRZRiHWeAhJRCwcy`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/conclusion.tex",
  "old_string": "Unlike random-label memorization~\\citep{zhang2021understanding}, random-label",
  "new_string": "Unlike random-label memorization~\\citep{zhang2021understanding,maennel2020random}, random-label"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "46ac7b4b-78e5-4063-b72b-edbcbbe981cf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XmUUcfxEnLqkmnN9DguYHw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2402,
      "cache_read_input_tokens": 38500,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2402
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

_source line 24 · 2026-05-21T23:10:32.952Z_

<details><summary>↩ Tool result · `toolu_016KcYWhzRZRiHWeAhJRCwcy`</summary>

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
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "12a50016-f6d8-4f55-bbe8-6d0d4c62dea2",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/conclusion.tex",
    "oldString": "Unlike random-label memorization~\\citep{zhang2021understanding}, random-label",
    "newString": "Unlike random-label memorization~\\citep{zhang2021understanding,maennel2020random}, random-label",
    "originalFile": "% conclusion.tex — compressed for 8-page limit\n\n\\section{Discussion}\n\\label{sec:discussion}\n\n\\paragraph{Topic shortcut and label equivalence.}\nThree observations argue against a topic shortcut: unstable topic OOD (F1\\,=\\,0.541$\\pm$0.207), scrambled labels within 3.9\\,pp, and label-free MLM detection (F1\\,$\\geq$\\,0.97).\n\n\\paragraph{Single-LLM confound.}\nToxicChat (+18--42\\,pp; Table~\\ref{tab:human_data}) and cross-LLM experiments (Appendix~\\ref{app:cross_llm}) confirm transfer. Mixed-LLM 9-class maintains DD F1\\,=\\,0.818$\\pm$0.096 (+53\\,pp) while MLM collapses to vanilla level.\n\n\\paragraph{Variance reversal on human data.}\nClassification supervision is associated with lower variance on synthetic OOD (4--20$\\times$ observed range, 3 seeds); on ToxicChat this reverses (std\\,=\\,0.087 vs.\\ 0.013). Frozen probing localizes MLM instability to Stage-2 (Appendix~\\ref{app:frozen_verify}).\n\n\\paragraph{Encoder capacity and lexical analysis.}\nThree encoders (125M--355M) differ in pretraining; same-architecture scaling is needed. TF-IDF collapses on ActorAttack (0.261 vs.\\ 0.961 on DD).\n\n\\paragraph{Regularization mechanism.}\nFrozen probing near-parity (AA gap 3.1\\,pp), label irrelevance ($d$\\,=\\,0.09), and mean pooling matching BiGRU ($|\\Delta| < 1$\\,pp) converge: classification DAPT provides robustness through optimization regularization, not semantic feature learning, paralleling self-supervised results where training structure matters more than label content~\\citep{chen2020simclr,grill2020byol}. Unlike random-label memorization~\\citep{zhang2021understanding}, random-label \\emph{pretraining} here produces transferable representations, suggesting that classification structure regularizes the space. Three extensions emerge: MLM collapses under mixed-LLM training despite single-LLM effectiveness, frozen probing near-parity coexists with 8\\,pp end-to-end gaps, and the hierarchy reverses on human data.\n\n\\paragraph{Benign distribution as the remaining bottleneck.}\nOOD F1 figures are upper bounds (benign is IID). On WildChat, 9-class FPR reaches 68.1\\% (Appendix~\\ref{app:wildchat_fpr}); cross-LLM error decomposition confirms collapse is driven by false positives on unfamiliar benign text.\n\n\\section{Conclusion}\n\nOn synthetic multi-turn evaluations, classification-based DAPT is the most robust adaptation for base-size encoders, providing robustness through optimization regularization rather than semantic learning; unsupervised pretraining collapses under mixed-LLM training. Negative results on label correctness (TOST-confirmed on DD at $n$\\,=\\,5; $d$\\,=\\,0.09 on ActorAttack), temporal order, and domain specificity constrain which properties matter; continued pretraining is 266$\\times$ faster than LLM-as-judge (Appendix~\\ref{app:efficiency}), offering a practical alternative given matched benign distributions (Appendix~\\ref{app:wildchat_fpr}).\n\n\\section{Limitations}\n\\label{sec:limitations}\n\nAll multi-turn findings derive from synthetic conversations generated by Qwen3-8B (350 training, 76--118 test per family). ToxicChat validates transfer to human-authored single-turn attacks (+18--42\\,pp over vanilla), but no human-generated multi-turn jailbreak dataset exists. Whether the evidence hierarchy generalizes to human-authored multi-turn attacks remains the primary open question (length confound analysis in Appendix~\\ref{app:length_independence}).\n\nOOD results reflect attack-side generalization only: benign data is IID, so OOD F1 figures are upper bounds (Section~\\ref{sec:discussion}). On WildChat, 9-class FPR reaches 68.1\\% (Appendix~\\ref{app:wildchat_fpr}); residual calibration error (ECE\\,=\\,0.126--0.141; Appendix~\\ref{app:calibration}) suggests temperature scaling is needed for deployment.\n\nThree encoders (125M--355M) differ in architecture and pretraining; same-architecture scaling is needed to isolate the capacity effect, and whether findings hold at LLM-scale encoders (7B+) remains open. Only persuasion-mediated multi-turn attacks fall within scope; single-turn token-level attacks~\\citep{zou2023gcg}, non-persuasive strategies, and non-text modalities are not addressed. Total pipeline cost is under 4 GPU-hours on a single A100.\n\n\\section*{Ethics Statement}\n\nThis work is defensive: it improves detection of multi-turn jailbreak attacks rather than developing new attacks. We acknowledge dual-use risk, as the persuasion taxonomy could inform adversarial actors. We mitigate this by using only synthetic conversations (no real harmful content), withholding attack-generation prompts, and focusing contributions on detection mechanisms. No human subjects were involved; all data will be released under CC BY-NC 4.0.\n",
    "structuredPatch": [
      {
        "oldStart": 16,
        "oldLines": 7,
        "newStart": 16,
        "newLines": 7,
        "lines": [
          " Three encoders (125M--355M) differ in pretraining; same-architecture scaling is needed. TF-IDF collapses on ActorAttack (0.261 vs.\\ 0.961 on DD).",
          " ",
          " \\paragraph{Regularization mechanism.}",
          "-Frozen probing near-parity (AA gap 3.1\\,pp), label irrelevance ($d$\\,=\\,0.09), and mean pooling matching BiGRU ($|\\Delta| < 1$\\,pp) converge: classification DAPT provides robustness through optimization regularization, not semantic feature learning, paralleling self-supervised results where training structure matters more than label content~\\citep{chen2020simclr,grill2020byol}. Unlike random-label memorization~\\citep{zhang2021understanding}, random-label \\emph{pretraining} here produces transferable representations, suggesting that classification structure regularizes the space. Three extensions emerge: MLM collapses under mixed-LLM training despite single-LLM effectiveness, frozen probing near-parity coexists with 8\\,pp end-to-end gaps, and the hierarchy reverses on human data.",
          "+Frozen probing near-parity (AA gap 3.1\\,pp), label irrelevance ($d$\\,=\\,0.09), and mean pooling matching BiGRU ($|\\Delta| < 1$\\,pp) converge: classification DAPT provides robustness through optimization regularization, not semantic feature learning, paralleling self-supervised results where training structure matters more than label content~\\citep{chen2020simclr,grill2020byol}. Unlike random-label memorization~\\citep{zhang2021understanding,maennel2020random}, random-label \\emph{pretraining} here produces transferable representations, suggesting that classification structure regularizes the space. Three extensions emerge: MLM collapses under mixed-LLM training despite single-LLM effectiveness, frozen probing near-parity coexists with 8\\,pp end-to-end gaps, and the hierarchy reverses on human data.",
          " ",
          " \\paragraph{Benign distribution as the remaining bottleneck.}",
          " OOD F1 figures are upper bounds (benign is IID). On WildChat, 9-class FPR reaches 68.1\\% (Appendix~\\ref{app:wildchat_fpr}); cross-LLM error decomposition confirms collapse is driven by false positives on unfamiliar benign text."
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

_source line 25_

<details open><summary>🔧 Tool call — Edit · `toolu_018mdTFetzmwHp2b4UvpVBMr`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/references.bib",
  "old_string": "Buchatber, Elena",
  "new_string": "Buchatskaya, Elena"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "c2e173d2-cced-47d7-9098-d6928ca08650",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01XmUUcfxEnLqkmnN9DguYHw",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 2402,
      "cache_read_input_tokens": 38500,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 2402
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

_source line 26 · 2026-05-21T23:10:34.019Z_

<details><summary>↩ Tool result · `toolu_018mdTFetzmwHp2b4UvpVBMr`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/references.bib has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "7c44e072-e9db-46f4-b52e-a95b1999f57a",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/references.bib",
    "oldString": "Buchatber, Elena",
    "newString": "Buchatskaya, Elena",
    "originalFile": "% References for persuasion_turn_jailbreak_detect\n% Auto-generated from literature_map.yaml (2026-05-18)\n% Total entries: 31\n\n% ============================================================\n% Category 1: Production Multi-Turn Safety Systems\n% ============================================================\n\n@article{inan2023llamaguard,\n  title={Llama Guard: LLM-based Input-Output Safeguard for Human-AI Conversations},\n  author={Inan, Hakan and Upasani, Kartikeya and Chi, Jianfeng and Rungta, Rashi and Iyer, Krithika and Mao, Yuning and Tontchev, Michael and Hu, Qing and Fuller, Brian and Testuggine, Davide and Khabsa, Madian},\n  journal={arXiv preprint},\n  year={2023},\n  eprint={2312.06674},\n  archivePrefix={arXiv},\n}\n\n@misc{metallamaguard3_2024,\n  title={Llama Guard 3},\n  author={{Meta AI}},\n  year={2024},\n  howpublished={Meta AI (released with Llama 3.1)},\n}\n\n@article{zeng2024shieldgemma,\n  title={ShieldGemma: Generative AI Content Moderation Based on Gemma},\n  author={Zeng, Wenjun and Liu, Yuchi and Mullins, Ryan and Peran, Ludovic and Fernandez, Joe and Harkous, Hamza and Narasimhan, Karthik and Proud, Drew and Kumar, Piyush and Radharapu, Bhaktipriya and Sturman, Olivia and Wahltinez, Oscar},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2407.21772},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{han2024wildguard,\n  title={WildGuard: Open One-Stop Moderation Tools for Safety Risks, Jailbreaks, and Refusals of LLMs},\n  author={Han, Seungju and Rao, Kavel and Ettinger, Allyson and Jiang, Liwei and Lin, Bill Yuchen and Lambert, Nathan and Choi, Yejin and Dziri, Nouha},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2024},\n}\n\n@techreport{anthropic2025constitutional,\n  title={Constitutional Classifiers: Defending against Universal Jailbreaks across Thousands of Hours of Red Teaming},\n  author={Sharma, Mrinank and Tong, Meg and Mu, Jesse and Korbak, Tomek and others},\n  institution={Anthropic},\n  year={2025},\n  eprint={2501.18837},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 2: Multi-Turn Jailbreak Defenses\n% ============================================================\n\n@article{deepcontext2026,\n  title={DeepContext: Stateful Real-Time Detection of Multi-Turn Adversarial Intent Drift in LLMs},\n  author={Albrethsen, Justin and Datta, Yash and Kumar, Kunal and Rajasekar, Sharath},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2602.16935},\n  archivePrefix={arXiv},\n}\n\n@article{tong2025biid,\n  title={Bidirectional Intention Inference Enhances LLMs' Defense Against Multi-Turn Jailbreak Attacks},\n  author={Tong, Haibo and Zhao, Dongcheng and Shen, Guobin and He, Xiang and Lin, Dachuan and Zhao, Feifei and Zeng, Yi},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2509.22732},\n  archivePrefix={arXiv},\n}\n\n@article{gguard2025,\n  title={An Attention-Aware GNN-Based Input Defender Against Multi-Turn Jailbreak on LLMs},\n  author={Huang, Zixuan and Huang, Kecheng and Yin, Lihao and He, Bowei and Zhen, Huiling and Yuan, Mingxuan and Shao, Zili},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2507.07146},\n  archivePrefix={arXiv},\n}\n\n@article{safedream2026,\n  title={SafeDream: Safety World Model for Proactive Early Jailbreak Detection},\n  author={Yan, Bo and Lin, Weikai and Zhu, Yada and Wang, Song},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2604.16824},\n  archivePrefix={arXiv},\n}\n\n@article{bullwinkel2025repeng,\n  title={A Representation Engineering Perspective on the Effectiveness of Multi-Turn Jailbreaks},\n  author={Bullwinkel, Blake and Russinovich, Mark and Salem, Ahmed and Zanella-Beguelin, Santiago and Jones, Daniel and Severi, Giorgio and Kim, Eugenia and Hines, Keegan and Minnich, Amanda and Zunger, Yonatan and Kumar, Ram Shankar Siva},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2507.02956},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 3: Discourse Analysis in NLP\n% ============================================================\n\n@article{mann1988rst,\n  title={Rhetorical Structure Theory: Toward a Functional Theory of Text Organization},\n  author={Mann, William C. and Thompson, Sandra A.},\n  journal={Text \\& Talk},\n  year={1988},\n  volume={8},\n  number={3},\n  pages={243--281},\n}\n\n@inproceedings{prasad2008pdtb,\n  title={The Penn Discourse TreeBank 2.0},\n  author={Prasad, Rashmi and Dinesh, Nikhil and Lee, Alan and Miltsakaki, Eleni and Robaldo, Livio and Joshi, Aravind and Webber, Bonnie},\n  booktitle={Proceedings of the International Conference on Language Resources and Evaluation},\n  year={2008},\n}\n\n@article{stolcke2000dialogueact,\n  title={Dialogue Act Modeling for Automatic Tagging and Recognition of Conversational Speech},\n  author={Stolcke, Andreas and Ries, Klaus and Coccaro, Noah and Shriberg, Elizabeth and Bates, Rebecca and Jurafsky, Daniel and Taylor, Paul and Martin, Rachel and Van Ess-Dykema, Carol and Meteer, Marie},\n  journal={Computational Linguistics},\n  year={2000},\n  volume={26},\n  number={3},\n  pages={339--374},\n}\n\n@book{austin1962speechacts,\n  title={How to Do Things with Words},\n  author={Austin, J. L.},\n  publisher={Harvard University Press},\n  year={1962},\n}\n\n@book{searle1969speechacts,\n  title={Speech Acts: An Essay in the Philosophy of Language},\n  author={Searle, J. R.},\n  publisher={Cambridge University Press},\n  year={1969},\n}\n\n% ============================================================\n% Category 4: Computational Persuasion Detection\n% ============================================================\n\n@book{cialdini2001influence,\n  title={Influence: Science and Practice},\n  author={Cialdini, Robert B.},\n  publisher={Allyn \\& Bacon},\n  year={2001},\n  edition={4th},\n}\n\n% ============================================================\n% Category 5: Jailbreak Attacks & Taxonomies\n% ============================================================\n\n@inproceedings{zeng2024pap,\n  title={How Johnny Can Persuade LLMs to Jailbreak Them: Rethinking Persuasion to Challenge AI Safety by Humanizing LLMs},\n  author={Zeng, Yi and Lin, Hongpeng and Zhang, Jingwen and Yang, Diyi and Jia, Ruoxi and Shi, Weiyan},\n  booktitle={Proceedings of the Association for Computational Linguistics},\n  year={2024},\n}\n\n% Note: key retains \"2024\" for citation compatibility; paper published at USENIX Security 2025\n@inproceedings{russinovich2024crescendo,\n  title={Great, Now Write an Article About That: The Crescendo Multi-Turn LLM Jailbreak Attack},\n  author={Russinovich, Mark and Salem, Ahmed and Eldan, Ronen},\n  booktitle={USENIX Security Symposium},\n  year={2025},\n  eprint={2404.01833},\n  archivePrefix={arXiv},\n}\n\n% Note: key retains \"2023\" for citation compatibility; paper published at SaTML 2025\n@inproceedings{chao2023pair,\n  title={Jailbreaking Black Box Large Language Models in Twenty Queries},\n  author={Chao, Patrick and Robey, Alexander and Dobriban, Edgar and Hassani, Hamed and Pappas, George J. and Wong, Eric},\n  booktitle={IEEE Conference on Secure and Trustworthy Machine Learning},\n  year={2025},\n  eprint={2310.08419},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{wei2023jailbroken,\n  title={Jailbroken: How Does LLM Safety Training Fail?},\n  author={Wei, Alexander and Haghtalab, Nika and Steinhardt, Jacob},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2023},\n}\n\n@article{hagendorff2026reasoning,\n  title={Large Reasoning Models Are Autonomous Jailbreak Agents},\n  author={Hagendorff, Thilo and Derner, Erik and Oliver, Nuria},\n  journal={Nature Communications},\n  volume={17},\n  pages={1435},\n  year={2026},\n  doi={10.1038/s41467-026-69010-1},\n}\n\n@article{fitd2024,\n  title={Foot In The Door: Understanding Large Language Model Jailbreaking via Cognitive Psychology},\n  author={Wang, Zhenhua and Xie, Wei and Wang, Baosheng and Wang, Enze and Gui, Zhiwen and Ma, Shuoyoucheng and Chen, Kai},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2402.15690},\n  archivePrefix={arXiv},\n}\n\n@techreport{deceptivedelight2024,\n  title={Deceptive Delight: Jailbreak LLMs Through Camouflage and Distraction},\n  author={{Palo Alto Networks Unit 42}},\n  institution={Palo Alto Networks},\n  year={2024},\n}\n\n@inproceedings{ren2024actorattack,\n  title={ActorAttack: Red-Teaming Large Language Models via Multi-Turn Actor Network Theory},\n  author={Ren, Qibing and Li, Hao and Liu, Dongrui and Xie, Zhanxu and Lu, Xiaoya and Qiao, Yu and Sha, Lei and Yan, Junchi and Ma, Lizhuang and Shao, Jing},\n  booktitle={International Conference on Learning Representations},\n  year={2025},\n}\n\n@article{zou2023gcg,\n  title={Universal and Transferable Adversarial Attacks on Aligned Language Models},\n  author={Zou, Andy and Wang, Zifan and Carlini, Nicholas and Nasr, Milad and Kolter, J. Zico and Fredrikson, Matt},\n  journal={arXiv preprint},\n  year={2023},\n  eprint={2307.15043},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 5b: Human Jailbreak Datasets\n% ============================================================\n\n@inproceedings{lin2023toxicchat,\n  title={ToxicChat: Unveiling Hidden Challenges of Toxicity Detection in Real-World User-{AI} Conversation},\n  author={Lin, Zi and Wang, Zihan and Tong, Yongqi and Wang, Yangkun and Guo, Yuxin and Wang, Yujia and Shang, Jingbo},\n  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2023},\n  pages={4694--4702},\n  year={2023},\n}\n\n% ============================================================\n% Category 6: Red-Teaming\n% ============================================================\n\n@article{li2024mhj,\n  title={LLM Defenses Are Not Robust to Multi-Turn Human Jailbreaks Yet},\n  author={Li, Nathaniel and Han, Ziwen and Steneker, Ian and Primack, Willow and Goodside, Riley and Zhang, Hugh and Wang, Zifan and Menghini, Cristina and Yue, Summer},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2408.15221},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 7: Annotation Artifacts & Dataset Biases\n% ============================================================\n\n@inproceedings{gururangan2018artifacts,\n  title={Annotation Artifacts in Natural Language Inference Data},\n  author={Gururangan, Suchin and Swayamdipta, Swabha and Levy, Omer and Schwartz, Roy and Bowman, Samuel and Smith, Noah A.},\n  booktitle={Proceedings of the Conference of the North American Chapter of the Association for Computational Linguistics},\n  year={2018},\n}\n\n@inproceedings{niven2019probing,\n  title={Probing Neural Network Comprehension of Natural Language Arguments},\n  author={Niven, Timothy and Kao, Hung-Yu},\n  booktitle={Proceedings of the Association for Computational Linguistics},\n  year={2019},\n}\n\n% ============================================================\n% Category 8: Adaptive Attacks on Classifiers\n% ============================================================\n\n@article{nasr2025attackermovessecond,\n  title={The Attacker Moves Second: Stronger Adaptive Attacks Bypass Defenses Against LLM Jailbreaks and Prompt Injections},\n  author={Nasr, Milad and Carlini, Nicholas and Sitawarin, Chawin and Schulhoff, Sander V. and Hayes, Jamie and Ilie, Michael and Pluto, Juliette and Song, Shuang and Chaudhari, Harsh and Shumailov, Ilia and Thakurta, Abhradeep and Xiao, Kai Yuanqing and Terzis, Andreas and Tram{\\`e}r, Florian},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2510.09023},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{andriushchenko2024adaptive,\n  title={Jailbreaking Leading Safety-Aligned LLMs with Simple Adaptive Attacks},\n  author={Andriushchenko, Maksym and Croce, Francesco and Flammarion, Nicolas},\n  booktitle={International Conference on Learning Representations},\n  year={2025},\n}\n\n% ============================================================\n% Technical Foundation\n% ============================================================\n\n@inproceedings{he2021deberta,\n  title={DeBERTa: Decoding-enhanced BERT with Disentangled Attention},\n  author={He, Pengcheng and Liu, Xiaodong and Gao, Jianfeng and Chen, Weizhu},\n  booktitle={International Conference on Learning Representations},\n  year={2021},\n}\n\n@inproceedings{he2023debertav3,\n  title={{DeBERTaV3}: Improving {DeBERTa} using {ELECTRA}-Style Pre-Training with Gradient-Disentangled Embedding Sharing},\n  author={He, Pengcheng and Gao, Jianfeng and Chen, Weizhu},\n  booktitle={International Conference on Learning Representations},\n  year={2023},\n}\n\n\n@inproceedings{kornblith2019cka,\n  title={Similarity of Neural Network Representations Revisited},\n  author={Kornblith, Simon and Norouzi, Mohammad and Lee, Honglak and Hinton, Geoffrey},\n  booktitle={International Conference on Machine Learning},\n  pages={3519--3529},\n  year={2019},\n}\n\n@article{qwen3_2025,\n  title={Qwen3 Technical Report},\n  author={Yang, An and Yang, Baosong and Zhang, Beichen and Wang, Binyuan and Li, Bo and Lin, Bowen and others},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2505.09388},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Domain-Adaptive Pretraining & Multi-Task Learning\n% ============================================================\n\n@inproceedings{gururangan2020dontstop,\n  title={Don't Stop Pretraining: Adapt Language Models to Domains and Tasks},\n  author={Gururangan, Suchin and Marasovi{\\'c}, Ana and Swayamdipta, Swabha and Lo, Kyle and Beltagy, Iz and Downey, Doug and Smith, Noah A.},\n  booktitle={Proceedings of the 58th Annual Meeting of the Association for Computational Linguistics},\n  pages={8342--8360},\n  year={2020},\n}\n\n@article{caruana1997multitask,\n  title={Multitask Learning},\n  author={Caruana, Rich},\n  journal={Machine Learning},\n  volume={28},\n  number={1},\n  pages={41--75},\n  year={1997},\n}\n\n@article{phang2018stilts,\n  title={Sentence Encoders on {STILTs}: Supplementary Training on Intermediate Labeled-data Tasks},\n  author={Phang, Jason and F{\\'e}vry, Thibault and Bowman, Samuel R.},\n  journal={arXiv preprint arXiv:1811.01088},\n  year={2018},\n}\n\n@inproceedings{liu2019mtdnn,\n  title={Multi-Task Deep Neural Networks for Natural Language Understanding},\n  author={Liu, Xiaodong and He, Pengcheng and Chen, Weizhu and Gao, Jianfeng},\n  booktitle={Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics},\n  pages={4487--4496},\n  year={2019},\n}\n\n@inproceedings{howard2018ulmfit,\n  title={Universal Language Model Fine-tuning for Text Classification},\n  author={Howard, Jeremy and Ruder, Sebastian},\n  booktitle={Proceedings of the 56th Annual Meeting of the Association for Computational Linguistics},\n  pages={328--339},\n  year={2018},\n}\n\n% ============================================================\n% Propaganda Detection\n% ============================================================\n\n@inproceedings{dasanmartino2020semeval,\n  title={{SemEval-2020 Task 11}: Detection of Propaganda Techniques in News Articles},\n  author={Da San Martino, Giovanni and Barr\\'{o}n-Cede\\~{n}o, Alberto and Wachsmuth, Henning and Petrov, Rostislav and Nakov, Preslav},\n  booktitle={Proceedings of the Fourteenth Workshop on Semantic Evaluation},\n  pages={1377--1414},\n  year={2020},\n}\n\n@inproceedings{dasanmartino2019fine,\n  title={Fine-Grained Analysis of Propaganda in News Articles},\n  author={Da San Martino, Giovanni and Yu, Seunghak and Barr\\'{o}n-Cede\\~{n}o, Alberto and Petrov, Rostislav and Nakov, Preslav},\n  booktitle={Proceedings of the 2019 Conference on Empirical Methods in Natural Language Processing},\n  pages={5636--5646},\n  year={2019},\n}\n\n% ============================================================\n% Adversarial NLP\n% ============================================================\n\n@inproceedings{jin2020textfooler,\n  title={Is {BERT} Really Robust? A Strong Baseline for Natural Language Attack on Text Classification and Entailment},\n  author={Jin, Di and Jin, Zhijing and Zhou, Joey Tianyi and Szolovits, Peter},\n  booktitle={Proceedings of the AAAI Conference on Artificial Intelligence},\n  volume={34},\n  pages={8018--8025},\n  year={2020},\n}\n\n@inproceedings{li2020bertattack,\n  title={{BERT-ATTACK}: Adversarial Attack Against {BERT} Using {BERT}},\n  author={Li, Linyang and Ma, Ruotian and Guo, Qipeng and Xue, Xiangyang and Qiu, Xipeng},\n  booktitle={Proceedings of the 2020 Conference on Empirical Methods in Natural Language Processing},\n  pages={6193--6202},\n  year={2020},\n}\n\n% ============================================================\n% Probing Classifiers\n% ============================================================\n\n@inproceedings{devlin2019bert,\n  title={{BERT}: Pre-training of Deep Bidirectional Transformers for Language Understanding},\n  author={Devlin, Jacob and Chang, Ming-Wei and Lee, Kenton and Toutanova, Kristina},\n  booktitle={Proceedings of the 2019 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies},\n  pages={4171--4186},\n  year={2019},\n}\n\n@inproceedings{conneau2018probing,\n  title={What you can cram into a single \\$\\&!\\#* vector: Probing sentence embeddings for linguistic properties},\n  author={Conneau, Alexis and Kruszewski, German and Lample, Guillaume and Barrault, Lo\\\"{i}c and Baroni, Marco},\n  booktitle={Proceedings of the 56th Annual Meeting of the Association for Computational Linguistics},\n  pages={2126--2136},\n  year={2018},\n}\n\n@inproceedings{hewitt2019structural,\n  title={A Structural Probe for Finding Syntax in Word Representations},\n  author={Hewitt, John and Manning, Christopher D.},\n  booktitle={Proceedings of the 2019 Conference of the North American Chapter of the Association for Computational Linguistics},\n  pages={4129--4138},\n  year={2019},\n}\n\n@article{liu2019roberta,\n  title={RoBERTa: A Robustly Optimized BERT Pretraining Approach},\n  author={Liu, Yinhan and Ott, Myle and Goyal, Naman and Du, Jingfei and Joshi, Mandar and Chen, Danqi and Levy, Omer and Lewis, Mike and Zettlemoyer, Luke and Stoyanov, Veselin},\n  journal={arXiv preprint arXiv:1907.11692},\n  year={2019},\n}\n\n@inproceedings{wang2019persuasion,\n  title={Persuasion for Good: Towards a Personalized Persuasive Dialogue System for Social Good},\n  author={Wang, Xuewei and Shi, Weiyan and Kim, Richard and Oh, Yoojung and Yang, Sijia and Zhang, Jingwen and Yu, Zhou},\n  booktitle={Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics},\n  pages={5635--5649},\n  year={2019},\n}\n\n@inproceedings{robey2024smoothllm,\n  title={SmoothLLM: Defending Large Language Models Against Jailbreaking Attacks},\n  author={Robey, Alexander and Wong, Eric and Hassani, Hamed and Pappas, George J.},\n  booktitle={Proceedings of the 41st International Conference on Machine Learning},\n  year={2024},\n}\n\n@inproceedings{mehrotra2024tap,\n  title={Tree of Attacks: Jailbreaking Black-Box LLMs with the Pruning of Candidate Outputs},\n  author={Mehrotra, Anay and Zampetakis, Manolis and Kassianik, Paul and Nelson, Blaine and Anderson, Hyrum and Singer, Yaron and Karbasi, Amin},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2024},\n}\n\n@article{chao2024jailbreakbench,\n  title={JailbreakBench: An Open Robustness Benchmark for Jailbreaking Large Language Models},\n  author={Chao, Patrick and Robey, Alexander and Dobriban, Edgar and Hassani, Hamed and Pappas, George J. and Wong, Eric},\n  journal={arXiv preprint arXiv:2404.01318},\n  year={2024},\n}\n\n@inproceedings{mazeika2024harmbench,\n  title={HarmBench: A Standardized Evaluation Framework for Automated Red Teaming and Robust Refusal},\n  author={Mazeika, Mantas and Phan, Long and Yin, Xuwang and Zou, Andy and Wang, Zifan and Mu, Norman and Sakhaee, Elham and Li, Nathaniel and Basart, Steven and Li, Bo and Forsyth, David and Hendrycks, Dan},\n  booktitle={Proceedings of the 41st International Conference on Machine Learning},\n  year={2024},\n}\n\n@inproceedings{lu2025xboundary,\n  title={X-Boundary: Establishing Exact Safety Boundary to Shield {LLMs} from Multi-Turn Jailbreaks without Compromising Usability},\n  author={Lu, Xiaoya and Liu, Dongrui and Yu, Yi and Xu, Luxin and Shao, Jing},\n  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2025},\n  year={2025},\n  eprint={2502.09990},\n  archivePrefix={arXiv},\n}\n\n@article{kadali2026trace,\n  title={Jailbreaking Leaves a Trace: Understanding and Detecting Jailbreak Attacks from Internal Representations of Large Language Models},\n  author={Kadali, Sri Durga Sai Sowmya and Papalexakis, Evangelos E.},\n  journal={arXiv preprint arXiv:2602.11495},\n  year={2026},\n  eprint={2602.11495},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{hua2026rcs,\n  title={Rethinking Jailbreak Detection of Large Vision Language Models with Representational Contrastive Scoring},\n  author={Hua, Peichun and Li, Hao and Shi, Shanghao and Yu, Zhiyuan and Zhang, Ning},\n  booktitle={Proceedings of the 64th Annual Meeting of the Association for Computational Linguistics},\n  year={2026},\n  eprint={2512.12069},\n  archivePrefix={arXiv},\n}\n\n@article{jiang2024redqueen,\n  title={{RED QUEEN}: Safeguarding Large Language Models against Concealed Multi-Turn Jailbreaking},\n  author={Jiang, Yifan and Aggarwal, Kriti and Laud, Tanmay and Munir, Kashif and Pujara, Jay and Mukherjee, Subhabrata},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2409.17458},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{song2026multibreak,\n  title={{MultiBreak}: A Scalable and Diverse Multi-turn Jailbreak Benchmark for Evaluating {LLM} Safety},\n  author={Song, Jialin and Liu, Xiaodong and Yang, Weiwei and Chen, Wuyang and Feng, Mingqian and Zhu, Xuekai and Gao, Jianfeng},\n  booktitle={International Conference on Machine Learning},\n  year={2026},\n  eprint={2605.01687},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% New citations (added 2026-05-21)\n% ============================================================\n\n@inproceedings{xie2024gradsafe,\n  title={{GradSafe}: Detecting Jailbreak Prompts for {LLMs} via Safety-Critical Gradient Analysis},\n  author={Xie, Yueqi and Fang, Minghong and Pi, Renjie and Gong, Neil},\n  booktitle={Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics},\n  pages={507--518},\n  year={2024},\n}\n\n@inproceedings{xu2024safedecoding,\n  title={{SafeDecoding}: Defending against Jailbreak Attacks via Safety-Aware Decoding},\n  author={Xu, Zhangchen and Jiang, Fengqing and Niu, Luyao and Jia, Jinyuan and Lin, Bill Yuchen and Poovendran, Radha},\n  booktitle={Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics},\n  year={2024},\n}\n\n@inproceedings{zou2024circuitbreakers,\n  title={Improving Alignment and Robustness with Circuit Breakers},\n  author={Zou, Andy and Phan, Long and Wang, Justin and Duenas, Derek and Lin, Maxwell and Andriushchenko, Maksym and Wang, Rowan and Kolter, Zico and Fredrikson, Matt and Hendrycks, Dan},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2024},\n}\n\n% ============================================================\n% New citations (added 2026-05-20)\n% ============================================================\n\n@inproceedings{zhang2025jbshield,\n  title={{JBShield}: Defending Large Language Models from Jailbreak Attacks through Activated Concept Analysis and Manipulation},\n  author={Zhang, Shenyi and Zhai, Yuchen and Guo, Keyan and Hu, Hongxin and Guo, Shengnan and Fang, Zheng and Zhao, Lingchen and Shen, Chao and Wang, Cong and Wang, Qian},\n  booktitle={USENIX Security Symposium},\n  year={2025},\n  eprint={2502.07557},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{perez2022redteaming,\n  title={Red Teaming Language Models with Language Models},\n  author={Perez, Ethan and Huang, Saffron and Song, Francis and Cai, Trevor and Ring, Roman and Aslanides, John and Glaese, Amelia and McAleese, Nat and Irving, Geoffrey},\n  booktitle={Proceedings of the 2022 Conference on Empirical Methods in Natural Language Processing},\n  pages={3419--3448},\n  year={2022},\n}\n\n@article{kulkarni2026latentadversarial,\n  title={Latent Adversarial Detection: Adaptive Probing of {LLM} Activations for Multi-Turn Attack Detection},\n  author={Kulkarni, Prashant},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2604.28129},\n  archivePrefix={arXiv},\n}\n\n@article{derya2026revisitingjbshield,\n  title={Revisiting {JBShield}: Breaking and Rebuilding Representation-Level Jailbreak Defenses},\n  author={Derya, Kemal and Sunar, Berk},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2605.03095},\n  archivePrefix={arXiv},\n}\n\n@article{lee2020biobert,\n  title={{BioBERT}: A Pre-trained Biomedical Language Representation Model for Biomedical Text Mining},\n  author={Lee, Jinhyuk and Yoon, Wonjin and Kim, Sungdong and Kim, Donghyeon and Kim, Sunkyu and So, Chan Ho and Kang, Jaewoo},\n  journal={Bioinformatics},\n  volume={36},\n  number={4},\n  pages={1234--1240},\n  year={2020},\n  publisher={Oxford University Press},\n}\n\n@inproceedings{beltagy2019scibert,\n  title={{SciBERT}: A Pretrained Language Model for Scientific Text},\n  author={Beltagy, Iz and Lo, Kyle and Cohan, Arman},\n  booktitle={Proceedings of the 2019 Conference on Empirical Methods in Natural Language Processing (EMNLP)},\n  pages={3615--3620},\n  year={2019},\n}\n\n@inproceedings{chen2020simclr,\n  title={A Simple Framework for Contrastive Learning of Visual Representations},\n  author={Chen, Ting and Kornblith, Simon and Norouzi, Mohammad and Hinton, Geoffrey},\n  booktitle={International Conference on Machine Learning (ICML)},\n  pages={1597--1607},\n  year={2020},\n}\n\n@inproceedings{grill2020byol,\n  title={Bootstrap Your Own Latent: A New Approach to Self-Supervised Learning},\n  author={Grill, Jean-Bastien and Strub, Florian and Altch{\\'e}, Florent and Tallec, Corentin and Richemond, Pierre H. and Buchatber, Elena and Doersch, Carl and Pires, Bernardo Avila and Guo, Zhaohan Daniel and Azar, Mohammad Gheshlaghi and Piot, Bilal and Kavukcuoglu, Koray and Munos, R{\\'e}mi and Valko, Michal},\n  booktitle={Advances in Neural Information Processing Systems (NeurIPS)},\n  year={2020},\n}\n\n% ============================================================\n% New citations (Round 10 fixes)\n% ============================================================\n\n@article{zhang2021understanding,\n  title={Understanding Deep Learning (Still) Requires Rethinking Generalization},\n  author={Zhang, Chiyuan and Bengio, Samy and Hardt, Moritz and Recht, Benjamin and Vinyals, Oriol},\n  journal={Communications of the ACM},\n  volume={64},\n  number={3},\n  pages={107--115},\n  year={2021},\n  doi={10.1145/3446776},\n}\n\n@inproceedings{maennel2020random,\n  title={What Do Neural Networks Learn When Trained With Random Labels?},\n  author={Maennel, Hartmut and Alabdulmohsin, Ibrahim M. and Tolstikhin, Ilya O. and Baldock, Robert J. N. and Bousquet, Olivier and Gelly, Sylvain and Keysers, Daniel},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2020},\n}\n",
    "structuredPatch": [
      {
        "oldStart": 628,
        "oldLines": 7,
        "newStart": 628,
        "newLines": 7,
        "lines": [
          " ",
          " @inproceedings{grill2020byol,",
          "   title={Bootstrap Your Own Latent: A New Approach to Self-Supervised Learning},",
          "-  author={Grill, Jean-Bastien and Strub, Florian and Altch{\\'e}, Florent and Tallec, Corentin and Richemond, Pierre H. and Buchatber, Elena and Doersch, Carl and Pires, Bernardo Avila and Guo, Zhaohan Daniel and Azar, Mohammad Gheshlaghi and Piot, Bilal and Kavukcuoglu, Koray and Munos, R{\\'e}mi and Valko, Michal},",
          "+  author={Grill, Jean-Bastien and Strub, Florian and Altch{\\'e}, Florent and Tallec, Corentin and Richemond, Pierre H. and Buchatskaya, Elena and Doersch, Carl and Pires, Bernardo Avila and Guo, Zhaohan Daniel and Azar, Mohammad Gheshlaghi and Piot, Bilal and Kavukcuoglu, Koray and Munos, R{\\'e}mi and Valko, Michal},",
          "   booktitle={Advances in Neural Information Processing Systems (NeurIPS)},",
          "   year={2020},",
          " }"
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

_source line 27_

Now add missing key-year mismatch comments for the two entries without them.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "8442bce8-65a0-4157-85a2-29db79ac1048",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01L4fc4TonuQGduT45Y6fVh2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3097,
      "cache_read_input_tokens": 40902,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3097
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

_source line 28_

<details open><summary>🔧 Tool call — Edit · `toolu_01A8ThNcghbjX358Y2REFaSG`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/references.bib",
  "old_string": "@inproceedings{andriushchenko2024adaptive,",
  "new_string": "% Note: key retains \"2024\" for citation compatibility; paper published at ICLR 2025\n@inproceedings{andriushchenko2024adaptive,"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "d6a42d8d-e10a-4ad1-9d81-9e8e5eaeee76",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01L4fc4TonuQGduT45Y6fVh2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3097,
      "cache_read_input_tokens": 40902,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3097
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

_source line 29 · 2026-05-21T23:10:39.745Z_

<details><summary>↩ Tool result · `toolu_01A8ThNcghbjX358Y2REFaSG`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/references.bib has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "8662c30b-5224-4f42-afdf-6957b22e8e37",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/references.bib",
    "oldString": "@inproceedings{andriushchenko2024adaptive,",
    "newString": "% Note: key retains \"2024\" for citation compatibility; paper published at ICLR 2025\n@inproceedings{andriushchenko2024adaptive,",
    "originalFile": "% References for persuasion_turn_jailbreak_detect\n% Auto-generated from literature_map.yaml (2026-05-18)\n% Total entries: 31\n\n% ============================================================\n% Category 1: Production Multi-Turn Safety Systems\n% ============================================================\n\n@article{inan2023llamaguard,\n  title={Llama Guard: LLM-based Input-Output Safeguard for Human-AI Conversations},\n  author={Inan, Hakan and Upasani, Kartikeya and Chi, Jianfeng and Rungta, Rashi and Iyer, Krithika and Mao, Yuning and Tontchev, Michael and Hu, Qing and Fuller, Brian and Testuggine, Davide and Khabsa, Madian},\n  journal={arXiv preprint},\n  year={2023},\n  eprint={2312.06674},\n  archivePrefix={arXiv},\n}\n\n@misc{metallamaguard3_2024,\n  title={Llama Guard 3},\n  author={{Meta AI}},\n  year={2024},\n  howpublished={Meta AI (released with Llama 3.1)},\n}\n\n@article{zeng2024shieldgemma,\n  title={ShieldGemma: Generative AI Content Moderation Based on Gemma},\n  author={Zeng, Wenjun and Liu, Yuchi and Mullins, Ryan and Peran, Ludovic and Fernandez, Joe and Harkous, Hamza and Narasimhan, Karthik and Proud, Drew and Kumar, Piyush and Radharapu, Bhaktipriya and Sturman, Olivia and Wahltinez, Oscar},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2407.21772},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{han2024wildguard,\n  title={WildGuard: Open One-Stop Moderation Tools for Safety Risks, Jailbreaks, and Refusals of LLMs},\n  author={Han, Seungju and Rao, Kavel and Ettinger, Allyson and Jiang, Liwei and Lin, Bill Yuchen and Lambert, Nathan and Choi, Yejin and Dziri, Nouha},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2024},\n}\n\n@techreport{anthropic2025constitutional,\n  title={Constitutional Classifiers: Defending against Universal Jailbreaks across Thousands of Hours of Red Teaming},\n  author={Sharma, Mrinank and Tong, Meg and Mu, Jesse and Korbak, Tomek and others},\n  institution={Anthropic},\n  year={2025},\n  eprint={2501.18837},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 2: Multi-Turn Jailbreak Defenses\n% ============================================================\n\n@article{deepcontext2026,\n  title={DeepContext: Stateful Real-Time Detection of Multi-Turn Adversarial Intent Drift in LLMs},\n  author={Albrethsen, Justin and Datta, Yash and Kumar, Kunal and Rajasekar, Sharath},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2602.16935},\n  archivePrefix={arXiv},\n}\n\n@article{tong2025biid,\n  title={Bidirectional Intention Inference Enhances LLMs' Defense Against Multi-Turn Jailbreak Attacks},\n  author={Tong, Haibo and Zhao, Dongcheng and Shen, Guobin and He, Xiang and Lin, Dachuan and Zhao, Feifei and Zeng, Yi},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2509.22732},\n  archivePrefix={arXiv},\n}\n\n@article{gguard2025,\n  title={An Attention-Aware GNN-Based Input Defender Against Multi-Turn Jailbreak on LLMs},\n  author={Huang, Zixuan and Huang, Kecheng and Yin, Lihao and He, Bowei and Zhen, Huiling and Yuan, Mingxuan and Shao, Zili},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2507.07146},\n  archivePrefix={arXiv},\n}\n\n@article{safedream2026,\n  title={SafeDream: Safety World Model for Proactive Early Jailbreak Detection},\n  author={Yan, Bo and Lin, Weikai and Zhu, Yada and Wang, Song},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2604.16824},\n  archivePrefix={arXiv},\n}\n\n@article{bullwinkel2025repeng,\n  title={A Representation Engineering Perspective on the Effectiveness of Multi-Turn Jailbreaks},\n  author={Bullwinkel, Blake and Russinovich, Mark and Salem, Ahmed and Zanella-Beguelin, Santiago and Jones, Daniel and Severi, Giorgio and Kim, Eugenia and Hines, Keegan and Minnich, Amanda and Zunger, Yonatan and Kumar, Ram Shankar Siva},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2507.02956},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 3: Discourse Analysis in NLP\n% ============================================================\n\n@article{mann1988rst,\n  title={Rhetorical Structure Theory: Toward a Functional Theory of Text Organization},\n  author={Mann, William C. and Thompson, Sandra A.},\n  journal={Text \\& Talk},\n  year={1988},\n  volume={8},\n  number={3},\n  pages={243--281},\n}\n\n@inproceedings{prasad2008pdtb,\n  title={The Penn Discourse TreeBank 2.0},\n  author={Prasad, Rashmi and Dinesh, Nikhil and Lee, Alan and Miltsakaki, Eleni and Robaldo, Livio and Joshi, Aravind and Webber, Bonnie},\n  booktitle={Proceedings of the International Conference on Language Resources and Evaluation},\n  year={2008},\n}\n\n@article{stolcke2000dialogueact,\n  title={Dialogue Act Modeling for Automatic Tagging and Recognition of Conversational Speech},\n  author={Stolcke, Andreas and Ries, Klaus and Coccaro, Noah and Shriberg, Elizabeth and Bates, Rebecca and Jurafsky, Daniel and Taylor, Paul and Martin, Rachel and Van Ess-Dykema, Carol and Meteer, Marie},\n  journal={Computational Linguistics},\n  year={2000},\n  volume={26},\n  number={3},\n  pages={339--374},\n}\n\n@book{austin1962speechacts,\n  title={How to Do Things with Words},\n  author={Austin, J. L.},\n  publisher={Harvard University Press},\n  year={1962},\n}\n\n@book{searle1969speechacts,\n  title={Speech Acts: An Essay in the Philosophy of Language},\n  author={Searle, J. R.},\n  publisher={Cambridge University Press},\n  year={1969},\n}\n\n% ============================================================\n% Category 4: Computational Persuasion Detection\n% ============================================================\n\n@book{cialdini2001influence,\n  title={Influence: Science and Practice},\n  author={Cialdini, Robert B.},\n  publisher={Allyn \\& Bacon},\n  year={2001},\n  edition={4th},\n}\n\n% ============================================================\n% Category 5: Jailbreak Attacks & Taxonomies\n% ============================================================\n\n@inproceedings{zeng2024pap,\n  title={How Johnny Can Persuade LLMs to Jailbreak Them: Rethinking Persuasion to Challenge AI Safety by Humanizing LLMs},\n  author={Zeng, Yi and Lin, Hongpeng and Zhang, Jingwen and Yang, Diyi and Jia, Ruoxi and Shi, Weiyan},\n  booktitle={Proceedings of the Association for Computational Linguistics},\n  year={2024},\n}\n\n% Note: key retains \"2024\" for citation compatibility; paper published at USENIX Security 2025\n@inproceedings{russinovich2024crescendo,\n  title={Great, Now Write an Article About That: The Crescendo Multi-Turn LLM Jailbreak Attack},\n  author={Russinovich, Mark and Salem, Ahmed and Eldan, Ronen},\n  booktitle={USENIX Security Symposium},\n  year={2025},\n  eprint={2404.01833},\n  archivePrefix={arXiv},\n}\n\n% Note: key retains \"2023\" for citation compatibility; paper published at SaTML 2025\n@inproceedings{chao2023pair,\n  title={Jailbreaking Black Box Large Language Models in Twenty Queries},\n  author={Chao, Patrick and Robey, Alexander and Dobriban, Edgar and Hassani, Hamed and Pappas, George J. and Wong, Eric},\n  booktitle={IEEE Conference on Secure and Trustworthy Machine Learning},\n  year={2025},\n  eprint={2310.08419},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{wei2023jailbroken,\n  title={Jailbroken: How Does LLM Safety Training Fail?},\n  author={Wei, Alexander and Haghtalab, Nika and Steinhardt, Jacob},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2023},\n}\n\n@article{hagendorff2026reasoning,\n  title={Large Reasoning Models Are Autonomous Jailbreak Agents},\n  author={Hagendorff, Thilo and Derner, Erik and Oliver, Nuria},\n  journal={Nature Communications},\n  volume={17},\n  pages={1435},\n  year={2026},\n  doi={10.1038/s41467-026-69010-1},\n}\n\n@article{fitd2024,\n  title={Foot In The Door: Understanding Large Language Model Jailbreaking via Cognitive Psychology},\n  author={Wang, Zhenhua and Xie, Wei and Wang, Baosheng and Wang, Enze and Gui, Zhiwen and Ma, Shuoyoucheng and Chen, Kai},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2402.15690},\n  archivePrefix={arXiv},\n}\n\n@techreport{deceptivedelight2024,\n  title={Deceptive Delight: Jailbreak LLMs Through Camouflage and Distraction},\n  author={{Palo Alto Networks Unit 42}},\n  institution={Palo Alto Networks},\n  year={2024},\n}\n\n@inproceedings{ren2024actorattack,\n  title={ActorAttack: Red-Teaming Large Language Models via Multi-Turn Actor Network Theory},\n  author={Ren, Qibing and Li, Hao and Liu, Dongrui and Xie, Zhanxu and Lu, Xiaoya and Qiao, Yu and Sha, Lei and Yan, Junchi and Ma, Lizhuang and Shao, Jing},\n  booktitle={International Conference on Learning Representations},\n  year={2025},\n}\n\n@article{zou2023gcg,\n  title={Universal and Transferable Adversarial Attacks on Aligned Language Models},\n  author={Zou, Andy and Wang, Zifan and Carlini, Nicholas and Nasr, Milad and Kolter, J. Zico and Fredrikson, Matt},\n  journal={arXiv preprint},\n  year={2023},\n  eprint={2307.15043},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 5b: Human Jailbreak Datasets\n% ============================================================\n\n@inproceedings{lin2023toxicchat,\n  title={ToxicChat: Unveiling Hidden Challenges of Toxicity Detection in Real-World User-{AI} Conversation},\n  author={Lin, Zi and Wang, Zihan and Tong, Yongqi and Wang, Yangkun and Guo, Yuxin and Wang, Yujia and Shang, Jingbo},\n  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2023},\n  pages={4694--4702},\n  year={2023},\n}\n\n% ============================================================\n% Category 6: Red-Teaming\n% ============================================================\n\n@article{li2024mhj,\n  title={LLM Defenses Are Not Robust to Multi-Turn Human Jailbreaks Yet},\n  author={Li, Nathaniel and Han, Ziwen and Steneker, Ian and Primack, Willow and Goodside, Riley and Zhang, Hugh and Wang, Zifan and Menghini, Cristina and Yue, Summer},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2408.15221},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 7: Annotation Artifacts & Dataset Biases\n% ============================================================\n\n@inproceedings{gururangan2018artifacts,\n  title={Annotation Artifacts in Natural Language Inference Data},\n  author={Gururangan, Suchin and Swayamdipta, Swabha and Levy, Omer and Schwartz, Roy and Bowman, Samuel and Smith, Noah A.},\n  booktitle={Proceedings of the Conference of the North American Chapter of the Association for Computational Linguistics},\n  year={2018},\n}\n\n@inproceedings{niven2019probing,\n  title={Probing Neural Network Comprehension of Natural Language Arguments},\n  author={Niven, Timothy and Kao, Hung-Yu},\n  booktitle={Proceedings of the Association for Computational Linguistics},\n  year={2019},\n}\n\n% ============================================================\n% Category 8: Adaptive Attacks on Classifiers\n% ============================================================\n\n@article{nasr2025attackermovessecond,\n  title={The Attacker Moves Second: Stronger Adaptive Attacks Bypass Defenses Against LLM Jailbreaks and Prompt Injections},\n  author={Nasr, Milad and Carlini, Nicholas and Sitawarin, Chawin and Schulhoff, Sander V. and Hayes, Jamie and Ilie, Michael and Pluto, Juliette and Song, Shuang and Chaudhari, Harsh and Shumailov, Ilia and Thakurta, Abhradeep and Xiao, Kai Yuanqing and Terzis, Andreas and Tram{\\`e}r, Florian},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2510.09023},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{andriushchenko2024adaptive,\n  title={Jailbreaking Leading Safety-Aligned LLMs with Simple Adaptive Attacks},\n  author={Andriushchenko, Maksym and Croce, Francesco and Flammarion, Nicolas},\n  booktitle={International Conference on Learning Representations},\n  year={2025},\n}\n\n% ============================================================\n% Technical Foundation\n% ============================================================\n\n@inproceedings{he2021deberta,\n  title={DeBERTa: Decoding-enhanced BERT with Disentangled Attention},\n  author={He, Pengcheng and Liu, Xiaodong and Gao, Jianfeng and Chen, Weizhu},\n  booktitle={International Conference on Learning Representations},\n  year={2021},\n}\n\n@inproceedings{he2023debertav3,\n  title={{DeBERTaV3}: Improving {DeBERTa} using {ELECTRA}-Style Pre-Training with Gradient-Disentangled Embedding Sharing},\n  author={He, Pengcheng and Gao, Jianfeng and Chen, Weizhu},\n  booktitle={International Conference on Learning Representations},\n  year={2023},\n}\n\n\n@inproceedings{kornblith2019cka,\n  title={Similarity of Neural Network Representations Revisited},\n  author={Kornblith, Simon and Norouzi, Mohammad and Lee, Honglak and Hinton, Geoffrey},\n  booktitle={International Conference on Machine Learning},\n  pages={3519--3529},\n  year={2019},\n}\n\n@article{qwen3_2025,\n  title={Qwen3 Technical Report},\n  author={Yang, An and Yang, Baosong and Zhang, Beichen and Wang, Binyuan and Li, Bo and Lin, Bowen and others},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2505.09388},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Domain-Adaptive Pretraining & Multi-Task Learning\n% ============================================================\n\n@inproceedings{gururangan2020dontstop,\n  title={Don't Stop Pretraining: Adapt Language Models to Domains and Tasks},\n  author={Gururangan, Suchin and Marasovi{\\'c}, Ana and Swayamdipta, Swabha and Lo, Kyle and Beltagy, Iz and Downey, Doug and Smith, Noah A.},\n  booktitle={Proceedings of the 58th Annual Meeting of the Association for Computational Linguistics},\n  pages={8342--8360},\n  year={2020},\n}\n\n@article{caruana1997multitask,\n  title={Multitask Learning},\n  author={Caruana, Rich},\n  journal={Machine Learning},\n  volume={28},\n  number={1},\n  pages={41--75},\n  year={1997},\n}\n\n@article{phang2018stilts,\n  title={Sentence Encoders on {STILTs}: Supplementary Training on Intermediate Labeled-data Tasks},\n  author={Phang, Jason and F{\\'e}vry, Thibault and Bowman, Samuel R.},\n  journal={arXiv preprint arXiv:1811.01088},\n  year={2018},\n}\n\n@inproceedings{liu2019mtdnn,\n  title={Multi-Task Deep Neural Networks for Natural Language Understanding},\n  author={Liu, Xiaodong and He, Pengcheng and Chen, Weizhu and Gao, Jianfeng},\n  booktitle={Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics},\n  pages={4487--4496},\n  year={2019},\n}\n\n@inproceedings{howard2018ulmfit,\n  title={Universal Language Model Fine-tuning for Text Classification},\n  author={Howard, Jeremy and Ruder, Sebastian},\n  booktitle={Proceedings of the 56th Annual Meeting of the Association for Computational Linguistics},\n  pages={328--339},\n  year={2018},\n}\n\n% ============================================================\n% Propaganda Detection\n% ============================================================\n\n@inproceedings{dasanmartino2020semeval,\n  title={{SemEval-2020 Task 11}: Detection of Propaganda Techniques in News Articles},\n  author={Da San Martino, Giovanni and Barr\\'{o}n-Cede\\~{n}o, Alberto and Wachsmuth, Henning and Petrov, Rostislav and Nakov, Preslav},\n  booktitle={Proceedings of the Fourteenth Workshop on Semantic Evaluation},\n  pages={1377--1414},\n  year={2020},\n}\n\n@inproceedings{dasanmartino2019fine,\n  title={Fine-Grained Analysis of Propaganda in News Articles},\n  author={Da San Martino, Giovanni and Yu, Seunghak and Barr\\'{o}n-Cede\\~{n}o, Alberto and Petrov, Rostislav and Nakov, Preslav},\n  booktitle={Proceedings of the 2019 Conference on Empirical Methods in Natural Language Processing},\n  pages={5636--5646},\n  year={2019},\n}\n\n% ============================================================\n% Adversarial NLP\n% ============================================================\n\n@inproceedings{jin2020textfooler,\n  title={Is {BERT} Really Robust? A Strong Baseline for Natural Language Attack on Text Classification and Entailment},\n  author={Jin, Di and Jin, Zhijing and Zhou, Joey Tianyi and Szolovits, Peter},\n  booktitle={Proceedings of the AAAI Conference on Artificial Intelligence},\n  volume={34},\n  pages={8018--8025},\n  year={2020},\n}\n\n@inproceedings{li2020bertattack,\n  title={{BERT-ATTACK}: Adversarial Attack Against {BERT} Using {BERT}},\n  author={Li, Linyang and Ma, Ruotian and Guo, Qipeng and Xue, Xiangyang and Qiu, Xipeng},\n  booktitle={Proceedings of the 2020 Conference on Empirical Methods in Natural Language Processing},\n  pages={6193--6202},\n  year={2020},\n}\n\n% ============================================================\n% Probing Classifiers\n% ============================================================\n\n@inproceedings{devlin2019bert,\n  title={{BERT}: Pre-training of Deep Bidirectional Transformers for Language Understanding},\n  author={Devlin, Jacob and Chang, Ming-Wei and Lee, Kenton and Toutanova, Kristina},\n  booktitle={Proceedings of the 2019 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies},\n  pages={4171--4186},\n  year={2019},\n}\n\n@inproceedings{conneau2018probing,\n  title={What you can cram into a single \\$\\&!\\#* vector: Probing sentence embeddings for linguistic properties},\n  author={Conneau, Alexis and Kruszewski, German and Lample, Guillaume and Barrault, Lo\\\"{i}c and Baroni, Marco},\n  booktitle={Proceedings of the 56th Annual Meeting of the Association for Computational Linguistics},\n  pages={2126--2136},\n  year={2018},\n}\n\n@inproceedings{hewitt2019structural,\n  title={A Structural Probe for Finding Syntax in Word Representations},\n  author={Hewitt, John and Manning, Christopher D.},\n  booktitle={Proceedings of the 2019 Conference of the North American Chapter of the Association for Computational Linguistics},\n  pages={4129--4138},\n  year={2019},\n}\n\n@article{liu2019roberta,\n  title={RoBERTa: A Robustly Optimized BERT Pretraining Approach},\n  author={Liu, Yinhan and Ott, Myle and Goyal, Naman and Du, Jingfei and Joshi, Mandar and Chen, Danqi and Levy, Omer and Lewis, Mike and Zettlemoyer, Luke and Stoyanov, Veselin},\n  journal={arXiv preprint arXiv:1907.11692},\n  year={2019},\n}\n\n@inproceedings{wang2019persuasion,\n  title={Persuasion for Good: Towards a Personalized Persuasive Dialogue System for Social Good},\n  author={Wang, Xuewei and Shi, Weiyan and Kim, Richard and Oh, Yoojung and Yang, Sijia and Zhang, Jingwen and Yu, Zhou},\n  booktitle={Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics},\n  pages={5635--5649},\n  year={2019},\n}\n\n@inproceedings{robey2024smoothllm,\n  title={SmoothLLM: Defending Large Language Models Against Jailbreaking Attacks},\n  author={Robey, Alexander and Wong, Eric and Hassani, Hamed and Pappas, George J.},\n  booktitle={Proceedings of the 41st International Conference on Machine Learning},\n  year={2024},\n}\n\n@inproceedings{mehrotra2024tap,\n  title={Tree of Attacks: Jailbreaking Black-Box LLMs with the Pruning of Candidate Outputs},\n  author={Mehrotra, Anay and Zampetakis, Manolis and Kassianik, Paul and Nelson, Blaine and Anderson, Hyrum and Singer, Yaron and Karbasi, Amin},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2024},\n}\n\n@article{chao2024jailbreakbench,\n  title={JailbreakBench: An Open Robustness Benchmark for Jailbreaking Large Language Models},\n  author={Chao, Patrick and Robey, Alexander and Dobriban, Edgar and Hassani, Hamed and Pappas, George J. and Wong, Eric},\n  journal={arXiv preprint arXiv:2404.01318},\n  year={2024},\n}\n\n@inproceedings{mazeika2024harmbench,\n  title={HarmBench: A Standardized Evaluation Framework for Automated Red Teaming and Robust Refusal},\n  author={Mazeika, Mantas and Phan, Long and Yin, Xuwang and Zou, Andy and Wang, Zifan and Mu, Norman and Sakhaee, Elham and Li, Nathaniel and Basart, Steven and Li, Bo and Forsyth, David and Hendrycks, Dan},\n  booktitle={Proceedings of the 41st International Conference on Machine Learning},\n  year={2024},\n}\n\n@inproceedings{lu2025xboundary,\n  title={X-Boundary: Establishing Exact Safety Boundary to Shield {LLMs} from Multi-Turn Jailbreaks without Compromising Usability},\n  author={Lu, Xiaoya and Liu, Dongrui and Yu, Yi and Xu, Luxin and Shao, Jing},\n  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2025},\n  year={2025},\n  eprint={2502.09990},\n  archivePrefix={arXiv},\n}\n\n@article{kadali2026trace,\n  title={Jailbreaking Leaves a Trace: Understanding and Detecting Jailbreak Attacks from Internal Representations of Large Language Models},\n  author={Kadali, Sri Durga Sai Sowmya and Papalexakis, Evangelos E.},\n  journal={arXiv preprint arXiv:2602.11495},\n  year={2026},\n  eprint={2602.11495},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{hua2026rcs,\n  title={Rethinking Jailbreak Detection of Large Vision Language Models with Representational Contrastive Scoring},\n  author={Hua, Peichun and Li, Hao and Shi, Shanghao and Yu, Zhiyuan and Zhang, Ning},\n  booktitle={Proceedings of the 64th Annual Meeting of the Association for Computational Linguistics},\n  year={2026},\n  eprint={2512.12069},\n  archivePrefix={arXiv},\n}\n\n@article{jiang2024redqueen,\n  title={{RED QUEEN}: Safeguarding Large Language Models against Concealed Multi-Turn Jailbreaking},\n  author={Jiang, Yifan and Aggarwal, Kriti and Laud, Tanmay and Munir, Kashif and Pujara, Jay and Mukherjee, Subhabrata},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2409.17458},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{song2026multibreak,\n  title={{MultiBreak}: A Scalable and Diverse Multi-turn Jailbreak Benchmark for Evaluating {LLM} Safety},\n  author={Song, Jialin and Liu, Xiaodong and Yang, Weiwei and Chen, Wuyang and Feng, Mingqian and Zhu, Xuekai and Gao, Jianfeng},\n  booktitle={International Conference on Machine Learning},\n  year={2026},\n  eprint={2605.01687},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% New citations (added 2026-05-21)\n% ============================================================\n\n@inproceedings{xie2024gradsafe,\n  title={{GradSafe}: Detecting Jailbreak Prompts for {LLMs} via Safety-Critical Gradient Analysis},\n  author={Xie, Yueqi and Fang, Minghong and Pi, Renjie and Gong, Neil},\n  booktitle={Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics},\n  pages={507--518},\n  year={2024},\n}\n\n@inproceedings{xu2024safedecoding,\n  title={{SafeDecoding}: Defending against Jailbreak Attacks via Safety-Aware Decoding},\n  author={Xu, Zhangchen and Jiang, Fengqing and Niu, Luyao and Jia, Jinyuan and Lin, Bill Yuchen and Poovendran, Radha},\n  booktitle={Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics},\n  year={2024},\n}\n\n@inproceedings{zou2024circuitbreakers,\n  title={Improving Alignment and Robustness with Circuit Breakers},\n  author={Zou, Andy and Phan, Long and Wang, Justin and Duenas, Derek and Lin, Maxwell and Andriushchenko, Maksym and Wang, Rowan and Kolter, Zico and Fredrikson, Matt and Hendrycks, Dan},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2024},\n}\n\n% ============================================================\n% New citations (added 2026-05-20)\n% ============================================================\n\n@inproceedings{zhang2025jbshield,\n  title={{JBShield}: Defending Large Language Models from Jailbreak Attacks through Activated Concept Analysis and Manipulation},\n  author={Zhang, Shenyi and Zhai, Yuchen and Guo, Keyan and Hu, Hongxin and Guo, Shengnan and Fang, Zheng and Zhao, Lingchen and Shen, Chao and Wang, Cong and Wang, Qian},\n  booktitle={USENIX Security Symposium},\n  year={2025},\n  eprint={2502.07557},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{perez2022redteaming,\n  title={Red Teaming Language Models with Language Models},\n  author={Perez, Ethan and Huang, Saffron and Song, Francis and Cai, Trevor and Ring, Roman and Aslanides, John and Glaese, Amelia and McAleese, Nat and Irving, Geoffrey},\n  booktitle={Proceedings of the 2022 Conference on Empirical Methods in Natural Language Processing},\n  pages={3419--3448},\n  year={2022},\n}\n\n@article{kulkarni2026latentadversarial,\n  title={Latent Adversarial Detection: Adaptive Probing of {LLM} Activations for Multi-Turn Attack Detection},\n  author={Kulkarni, Prashant},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2604.28129},\n  archivePrefix={arXiv},\n}\n\n@article{derya2026revisitingjbshield,\n  title={Revisiting {JBShield}: Breaking and Rebuilding Representation-Level Jailbreak Defenses},\n  author={Derya, Kemal and Sunar, Berk},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2605.03095},\n  archivePrefix={arXiv},\n}\n\n@article{lee2020biobert,\n  title={{BioBERT}: A Pre-trained Biomedical Language Representation Model for Biomedical Text Mining},\n  author={Lee, Jinhyuk and Yoon, Wonjin and Kim, Sungdong and Kim, Donghyeon and Kim, Sunkyu and So, Chan Ho and Kang, Jaewoo},\n  journal={Bioinformatics},\n  volume={36},\n  number={4},\n  pages={1234--1240},\n  year={2020},\n  publisher={Oxford University Press},\n}\n\n@inproceedings{beltagy2019scibert,\n  title={{SciBERT}: A Pretrained Language Model for Scientific Text},\n  author={Beltagy, Iz and Lo, Kyle and Cohan, Arman},\n  booktitle={Proceedings of the 2019 Conference on Empirical Methods in Natural Language Processing (EMNLP)},\n  pages={3615--3620},\n  year={2019},\n}\n\n@inproceedings{chen2020simclr,\n  title={A Simple Framework for Contrastive Learning of Visual Representations},\n  author={Chen, Ting and Kornblith, Simon and Norouzi, Mohammad and Hinton, Geoffrey},\n  booktitle={International Conference on Machine Learning (ICML)},\n  pages={1597--1607},\n  year={2020},\n}\n\n@inproceedings{grill2020byol,\n  title={Bootstrap Your Own Latent: A New Approach to Self-Supervised Learning},\n  author={Grill, Jean-Bastien and Strub, Florian and Altch{\\'e}, Florent and Tallec, Corentin and Richemond, Pierre H. and Buchatskaya, Elena and Doersch, Carl and Pires, Bernardo Avila and Guo, Zhaohan Daniel and Azar, Mohammad Gheshlaghi and Piot, Bilal and Kavukcuoglu, Koray and Munos, R{\\'e}mi and Valko, Michal},\n  booktitle={Advances in Neural Information Processing Systems (NeurIPS)},\n  year={2020},\n}\n\n% ============================================================\n% New citations (Round 10 fixes)\n% ============================================================\n\n@article{zhang2021understanding,\n  title={Understanding Deep Learning (Still) Requires Rethinking Generalization},\n  author={Zhang, Chiyuan and Bengio, Samy and Hardt, Moritz and Recht, Benjamin and Vinyals, Oriol},\n  journal={Communications of the ACM},\n  volume={64},\n  number={3},\n  pages={107--115},\n  year={2021},\n  doi={10.1145/3446776},\n}\n\n@inproceedings{maennel2020random,\n  title={What Do Neural Networks Learn When Trained With Random Labels?},\n  author={Maennel, Hartmut and Alabdulmohsin, Ibrahim M. and Tolstikhin, Ilya O. and Baldock, Robert J. N. and Bousquet, Olivier and Gelly, Sylvain and Keysers, Daniel},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2020},\n}\n",
    "structuredPatch": [
      {
        "oldStart": 289,
        "oldLines": 6,
        "newStart": 289,
        "newLines": 7,
        "lines": [
          "   archivePrefix={arXiv},",
          " }",
          " ",
          "+% Note: key retains \"2024\" for citation compatibility; paper published at ICLR 2025",
          " @inproceedings{andriushchenko2024adaptive,",
          "   title={Jailbreaking Leading Safety-Aligned LLMs with Simple Adaptive Attacks},",
          "   author={Andriushchenko, Maksym and Croce, Francesco and Flammarion, Nicolas},"
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

_source line 30_

<details open><summary>🔧 Tool call — Edit · `toolu_01EBcQThHxwBfoB7yvVHjFUK`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/references.bib",
  "old_string": "@inproceedings{ren2024actorattack,",
  "new_string": "% Note: key retains \"2024\" for citation compatibility; paper published at ICLR 2025\n@inproceedings{ren2024actorattack,"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "c3f4d3c3-1a3f-469a-adba-1e6795091178",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01L4fc4TonuQGduT45Y6fVh2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 3097,
      "cache_read_input_tokens": 40902,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 3097
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

_source line 31 · 2026-05-21T23:10:40.782Z_

<details><summary>↩ Tool result · `toolu_01EBcQThHxwBfoB7yvVHjFUK`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/references.bib has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "acc6f54f-b7a2-48fb-8407-f84f7fdbcc2c",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0514_2/projects/persuasion_turn_jailbreak_detect/docs/paper/references.bib",
    "oldString": "@inproceedings{ren2024actorattack,",
    "newString": "% Note: key retains \"2024\" for citation compatibility; paper published at ICLR 2025\n@inproceedings{ren2024actorattack,",
    "originalFile": "% References for persuasion_turn_jailbreak_detect\n% Auto-generated from literature_map.yaml (2026-05-18)\n% Total entries: 31\n\n% ============================================================\n% Category 1: Production Multi-Turn Safety Systems\n% ============================================================\n\n@article{inan2023llamaguard,\n  title={Llama Guard: LLM-based Input-Output Safeguard for Human-AI Conversations},\n  author={Inan, Hakan and Upasani, Kartikeya and Chi, Jianfeng and Rungta, Rashi and Iyer, Krithika and Mao, Yuning and Tontchev, Michael and Hu, Qing and Fuller, Brian and Testuggine, Davide and Khabsa, Madian},\n  journal={arXiv preprint},\n  year={2023},\n  eprint={2312.06674},\n  archivePrefix={arXiv},\n}\n\n@misc{metallamaguard3_2024,\n  title={Llama Guard 3},\n  author={{Meta AI}},\n  year={2024},\n  howpublished={Meta AI (released with Llama 3.1)},\n}\n\n@article{zeng2024shieldgemma,\n  title={ShieldGemma: Generative AI Content Moderation Based on Gemma},\n  author={Zeng, Wenjun and Liu, Yuchi and Mullins, Ryan and Peran, Ludovic and Fernandez, Joe and Harkous, Hamza and Narasimhan, Karthik and Proud, Drew and Kumar, Piyush and Radharapu, Bhaktipriya and Sturman, Olivia and Wahltinez, Oscar},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2407.21772},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{han2024wildguard,\n  title={WildGuard: Open One-Stop Moderation Tools for Safety Risks, Jailbreaks, and Refusals of LLMs},\n  author={Han, Seungju and Rao, Kavel and Ettinger, Allyson and Jiang, Liwei and Lin, Bill Yuchen and Lambert, Nathan and Choi, Yejin and Dziri, Nouha},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2024},\n}\n\n@techreport{anthropic2025constitutional,\n  title={Constitutional Classifiers: Defending against Universal Jailbreaks across Thousands of Hours of Red Teaming},\n  author={Sharma, Mrinank and Tong, Meg and Mu, Jesse and Korbak, Tomek and others},\n  institution={Anthropic},\n  year={2025},\n  eprint={2501.18837},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 2: Multi-Turn Jailbreak Defenses\n% ============================================================\n\n@article{deepcontext2026,\n  title={DeepContext: Stateful Real-Time Detection of Multi-Turn Adversarial Intent Drift in LLMs},\n  author={Albrethsen, Justin and Datta, Yash and Kumar, Kunal and Rajasekar, Sharath},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2602.16935},\n  archivePrefix={arXiv},\n}\n\n@article{tong2025biid,\n  title={Bidirectional Intention Inference Enhances LLMs' Defense Against Multi-Turn Jailbreak Attacks},\n  author={Tong, Haibo and Zhao, Dongcheng and Shen, Guobin and He, Xiang and Lin, Dachuan and Zhao, Feifei and Zeng, Yi},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2509.22732},\n  archivePrefix={arXiv},\n}\n\n@article{gguard2025,\n  title={An Attention-Aware GNN-Based Input Defender Against Multi-Turn Jailbreak on LLMs},\n  author={Huang, Zixuan and Huang, Kecheng and Yin, Lihao and He, Bowei and Zhen, Huiling and Yuan, Mingxuan and Shao, Zili},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2507.07146},\n  archivePrefix={arXiv},\n}\n\n@article{safedream2026,\n  title={SafeDream: Safety World Model for Proactive Early Jailbreak Detection},\n  author={Yan, Bo and Lin, Weikai and Zhu, Yada and Wang, Song},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2604.16824},\n  archivePrefix={arXiv},\n}\n\n@article{bullwinkel2025repeng,\n  title={A Representation Engineering Perspective on the Effectiveness of Multi-Turn Jailbreaks},\n  author={Bullwinkel, Blake and Russinovich, Mark and Salem, Ahmed and Zanella-Beguelin, Santiago and Jones, Daniel and Severi, Giorgio and Kim, Eugenia and Hines, Keegan and Minnich, Amanda and Zunger, Yonatan and Kumar, Ram Shankar Siva},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2507.02956},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 3: Discourse Analysis in NLP\n% ============================================================\n\n@article{mann1988rst,\n  title={Rhetorical Structure Theory: Toward a Functional Theory of Text Organization},\n  author={Mann, William C. and Thompson, Sandra A.},\n  journal={Text \\& Talk},\n  year={1988},\n  volume={8},\n  number={3},\n  pages={243--281},\n}\n\n@inproceedings{prasad2008pdtb,\n  title={The Penn Discourse TreeBank 2.0},\n  author={Prasad, Rashmi and Dinesh, Nikhil and Lee, Alan and Miltsakaki, Eleni and Robaldo, Livio and Joshi, Aravind and Webber, Bonnie},\n  booktitle={Proceedings of the International Conference on Language Resources and Evaluation},\n  year={2008},\n}\n\n@article{stolcke2000dialogueact,\n  title={Dialogue Act Modeling for Automatic Tagging and Recognition of Conversational Speech},\n  author={Stolcke, Andreas and Ries, Klaus and Coccaro, Noah and Shriberg, Elizabeth and Bates, Rebecca and Jurafsky, Daniel and Taylor, Paul and Martin, Rachel and Van Ess-Dykema, Carol and Meteer, Marie},\n  journal={Computational Linguistics},\n  year={2000},\n  volume={26},\n  number={3},\n  pages={339--374},\n}\n\n@book{austin1962speechacts,\n  title={How to Do Things with Words},\n  author={Austin, J. L.},\n  publisher={Harvard University Press},\n  year={1962},\n}\n\n@book{searle1969speechacts,\n  title={Speech Acts: An Essay in the Philosophy of Language},\n  author={Searle, J. R.},\n  publisher={Cambridge University Press},\n  year={1969},\n}\n\n% ============================================================\n% Category 4: Computational Persuasion Detection\n% ============================================================\n\n@book{cialdini2001influence,\n  title={Influence: Science and Practice},\n  author={Cialdini, Robert B.},\n  publisher={Allyn \\& Bacon},\n  year={2001},\n  edition={4th},\n}\n\n% ============================================================\n% Category 5: Jailbreak Attacks & Taxonomies\n% ============================================================\n\n@inproceedings{zeng2024pap,\n  title={How Johnny Can Persuade LLMs to Jailbreak Them: Rethinking Persuasion to Challenge AI Safety by Humanizing LLMs},\n  author={Zeng, Yi and Lin, Hongpeng and Zhang, Jingwen and Yang, Diyi and Jia, Ruoxi and Shi, Weiyan},\n  booktitle={Proceedings of the Association for Computational Linguistics},\n  year={2024},\n}\n\n% Note: key retains \"2024\" for citation compatibility; paper published at USENIX Security 2025\n@inproceedings{russinovich2024crescendo,\n  title={Great, Now Write an Article About That: The Crescendo Multi-Turn LLM Jailbreak Attack},\n  author={Russinovich, Mark and Salem, Ahmed and Eldan, Ronen},\n  booktitle={USENIX Security Symposium},\n  year={2025},\n  eprint={2404.01833},\n  archivePrefix={arXiv},\n}\n\n% Note: key retains \"2023\" for citation compatibility; paper published at SaTML 2025\n@inproceedings{chao2023pair,\n  title={Jailbreaking Black Box Large Language Models in Twenty Queries},\n  author={Chao, Patrick and Robey, Alexander and Dobriban, Edgar and Hassani, Hamed and Pappas, George J. and Wong, Eric},\n  booktitle={IEEE Conference on Secure and Trustworthy Machine Learning},\n  year={2025},\n  eprint={2310.08419},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{wei2023jailbroken,\n  title={Jailbroken: How Does LLM Safety Training Fail?},\n  author={Wei, Alexander and Haghtalab, Nika and Steinhardt, Jacob},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2023},\n}\n\n@article{hagendorff2026reasoning,\n  title={Large Reasoning Models Are Autonomous Jailbreak Agents},\n  author={Hagendorff, Thilo and Derner, Erik and Oliver, Nuria},\n  journal={Nature Communications},\n  volume={17},\n  pages={1435},\n  year={2026},\n  doi={10.1038/s41467-026-69010-1},\n}\n\n@article{fitd2024,\n  title={Foot In The Door: Understanding Large Language Model Jailbreaking via Cognitive Psychology},\n  author={Wang, Zhenhua and Xie, Wei and Wang, Baosheng and Wang, Enze and Gui, Zhiwen and Ma, Shuoyoucheng and Chen, Kai},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2402.15690},\n  archivePrefix={arXiv},\n}\n\n@techreport{deceptivedelight2024,\n  title={Deceptive Delight: Jailbreak LLMs Through Camouflage and Distraction},\n  author={{Palo Alto Networks Unit 42}},\n  institution={Palo Alto Networks},\n  year={2024},\n}\n\n@inproceedings{ren2024actorattack,\n  title={ActorAttack: Red-Teaming Large Language Models via Multi-Turn Actor Network Theory},\n  author={Ren, Qibing and Li, Hao and Liu, Dongrui and Xie, Zhanxu and Lu, Xiaoya and Qiao, Yu and Sha, Lei and Yan, Junchi and Ma, Lizhuang and Shao, Jing},\n  booktitle={International Conference on Learning Representations},\n  year={2025},\n}\n\n@article{zou2023gcg,\n  title={Universal and Transferable Adversarial Attacks on Aligned Language Models},\n  author={Zou, Andy and Wang, Zifan and Carlini, Nicholas and Nasr, Milad and Kolter, J. Zico and Fredrikson, Matt},\n  journal={arXiv preprint},\n  year={2023},\n  eprint={2307.15043},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 5b: Human Jailbreak Datasets\n% ============================================================\n\n@inproceedings{lin2023toxicchat,\n  title={ToxicChat: Unveiling Hidden Challenges of Toxicity Detection in Real-World User-{AI} Conversation},\n  author={Lin, Zi and Wang, Zihan and Tong, Yongqi and Wang, Yangkun and Guo, Yuxin and Wang, Yujia and Shang, Jingbo},\n  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2023},\n  pages={4694--4702},\n  year={2023},\n}\n\n% ============================================================\n% Category 6: Red-Teaming\n% ============================================================\n\n@article{li2024mhj,\n  title={LLM Defenses Are Not Robust to Multi-Turn Human Jailbreaks Yet},\n  author={Li, Nathaniel and Han, Ziwen and Steneker, Ian and Primack, Willow and Goodside, Riley and Zhang, Hugh and Wang, Zifan and Menghini, Cristina and Yue, Summer},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2408.15221},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Category 7: Annotation Artifacts & Dataset Biases\n% ============================================================\n\n@inproceedings{gururangan2018artifacts,\n  title={Annotation Artifacts in Natural Language Inference Data},\n  author={Gururangan, Suchin and Swayamdipta, Swabha and Levy, Omer and Schwartz, Roy and Bowman, Samuel and Smith, Noah A.},\n  booktitle={Proceedings of the Conference of the North American Chapter of the Association for Computational Linguistics},\n  year={2018},\n}\n\n@inproceedings{niven2019probing,\n  title={Probing Neural Network Comprehension of Natural Language Arguments},\n  author={Niven, Timothy and Kao, Hung-Yu},\n  booktitle={Proceedings of the Association for Computational Linguistics},\n  year={2019},\n}\n\n% ============================================================\n% Category 8: Adaptive Attacks on Classifiers\n% ============================================================\n\n@article{nasr2025attackermovessecond,\n  title={The Attacker Moves Second: Stronger Adaptive Attacks Bypass Defenses Against LLM Jailbreaks and Prompt Injections},\n  author={Nasr, Milad and Carlini, Nicholas and Sitawarin, Chawin and Schulhoff, Sander V. and Hayes, Jamie and Ilie, Michael and Pluto, Juliette and Song, Shuang and Chaudhari, Harsh and Shumailov, Ilia and Thakurta, Abhradeep and Xiao, Kai Yuanqing and Terzis, Andreas and Tram{\\`e}r, Florian},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2510.09023},\n  archivePrefix={arXiv},\n}\n\n% Note: key retains \"2024\" for citation compatibility; paper published at ICLR 2025\n@inproceedings{andriushchenko2024adaptive,\n  title={Jailbreaking Leading Safety-Aligned LLMs with Simple Adaptive Attacks},\n  author={Andriushchenko, Maksym and Croce, Francesco and Flammarion, Nicolas},\n  booktitle={International Conference on Learning Representations},\n  year={2025},\n}\n\n% ============================================================\n% Technical Foundation\n% ============================================================\n\n@inproceedings{he2021deberta,\n  title={DeBERTa: Decoding-enhanced BERT with Disentangled Attention},\n  author={He, Pengcheng and Liu, Xiaodong and Gao, Jianfeng and Chen, Weizhu},\n  booktitle={International Conference on Learning Representations},\n  year={2021},\n}\n\n@inproceedings{he2023debertav3,\n  title={{DeBERTaV3}: Improving {DeBERTa} using {ELECTRA}-Style Pre-Training with Gradient-Disentangled Embedding Sharing},\n  author={He, Pengcheng and Gao, Jianfeng and Chen, Weizhu},\n  booktitle={International Conference on Learning Representations},\n  year={2023},\n}\n\n\n@inproceedings{kornblith2019cka,\n  title={Similarity of Neural Network Representations Revisited},\n  author={Kornblith, Simon and Norouzi, Mohammad and Lee, Honglak and Hinton, Geoffrey},\n  booktitle={International Conference on Machine Learning},\n  pages={3519--3529},\n  year={2019},\n}\n\n@article{qwen3_2025,\n  title={Qwen3 Technical Report},\n  author={Yang, An and Yang, Baosong and Zhang, Beichen and Wang, Binyuan and Li, Bo and Lin, Bowen and others},\n  journal={arXiv preprint},\n  year={2025},\n  eprint={2505.09388},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% Domain-Adaptive Pretraining & Multi-Task Learning\n% ============================================================\n\n@inproceedings{gururangan2020dontstop,\n  title={Don't Stop Pretraining: Adapt Language Models to Domains and Tasks},\n  author={Gururangan, Suchin and Marasovi{\\'c}, Ana and Swayamdipta, Swabha and Lo, Kyle and Beltagy, Iz and Downey, Doug and Smith, Noah A.},\n  booktitle={Proceedings of the 58th Annual Meeting of the Association for Computational Linguistics},\n  pages={8342--8360},\n  year={2020},\n}\n\n@article{caruana1997multitask,\n  title={Multitask Learning},\n  author={Caruana, Rich},\n  journal={Machine Learning},\n  volume={28},\n  number={1},\n  pages={41--75},\n  year={1997},\n}\n\n@article{phang2018stilts,\n  title={Sentence Encoders on {STILTs}: Supplementary Training on Intermediate Labeled-data Tasks},\n  author={Phang, Jason and F{\\'e}vry, Thibault and Bowman, Samuel R.},\n  journal={arXiv preprint arXiv:1811.01088},\n  year={2018},\n}\n\n@inproceedings{liu2019mtdnn,\n  title={Multi-Task Deep Neural Networks for Natural Language Understanding},\n  author={Liu, Xiaodong and He, Pengcheng and Chen, Weizhu and Gao, Jianfeng},\n  booktitle={Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics},\n  pages={4487--4496},\n  year={2019},\n}\n\n@inproceedings{howard2018ulmfit,\n  title={Universal Language Model Fine-tuning for Text Classification},\n  author={Howard, Jeremy and Ruder, Sebastian},\n  booktitle={Proceedings of the 56th Annual Meeting of the Association for Computational Linguistics},\n  pages={328--339},\n  year={2018},\n}\n\n% ============================================================\n% Propaganda Detection\n% ============================================================\n\n@inproceedings{dasanmartino2020semeval,\n  title={{SemEval-2020 Task 11}: Detection of Propaganda Techniques in News Articles},\n  author={Da San Martino, Giovanni and Barr\\'{o}n-Cede\\~{n}o, Alberto and Wachsmuth, Henning and Petrov, Rostislav and Nakov, Preslav},\n  booktitle={Proceedings of the Fourteenth Workshop on Semantic Evaluation},\n  pages={1377--1414},\n  year={2020},\n}\n\n@inproceedings{dasanmartino2019fine,\n  title={Fine-Grained Analysis of Propaganda in News Articles},\n  author={Da San Martino, Giovanni and Yu, Seunghak and Barr\\'{o}n-Cede\\~{n}o, Alberto and Petrov, Rostislav and Nakov, Preslav},\n  booktitle={Proceedings of the 2019 Conference on Empirical Methods in Natural Language Processing},\n  pages={5636--5646},\n  year={2019},\n}\n\n% ============================================================\n% Adversarial NLP\n% ============================================================\n\n@inproceedings{jin2020textfooler,\n  title={Is {BERT} Really Robust? A Strong Baseline for Natural Language Attack on Text Classification and Entailment},\n  author={Jin, Di and Jin, Zhijing and Zhou, Joey Tianyi and Szolovits, Peter},\n  booktitle={Proceedings of the AAAI Conference on Artificial Intelligence},\n  volume={34},\n  pages={8018--8025},\n  year={2020},\n}\n\n@inproceedings{li2020bertattack,\n  title={{BERT-ATTACK}: Adversarial Attack Against {BERT} Using {BERT}},\n  author={Li, Linyang and Ma, Ruotian and Guo, Qipeng and Xue, Xiangyang and Qiu, Xipeng},\n  booktitle={Proceedings of the 2020 Conference on Empirical Methods in Natural Language Processing},\n  pages={6193--6202},\n  year={2020},\n}\n\n% ============================================================\n% Probing Classifiers\n% ============================================================\n\n@inproceedings{devlin2019bert,\n  title={{BERT}: Pre-training of Deep Bidirectional Transformers for Language Understanding},\n  author={Devlin, Jacob and Chang, Ming-Wei and Lee, Kenton and Toutanova, Kristina},\n  booktitle={Proceedings of the 2019 Conference of the North American Chapter of the Association for Computational Linguistics: Human Language Technologies},\n  pages={4171--4186},\n  year={2019},\n}\n\n@inproceedings{conneau2018probing,\n  title={What you can cram into a single \\$\\&!\\#* vector: Probing sentence embeddings for linguistic properties},\n  author={Conneau, Alexis and Kruszewski, German and Lample, Guillaume and Barrault, Lo\\\"{i}c and Baroni, Marco},\n  booktitle={Proceedings of the 56th Annual Meeting of the Association for Computational Linguistics},\n  pages={2126--2136},\n  year={2018},\n}\n\n@inproceedings{hewitt2019structural,\n  title={A Structural Probe for Finding Syntax in Word Representations},\n  author={Hewitt, John and Manning, Christopher D.},\n  booktitle={Proceedings of the 2019 Conference of the North American Chapter of the Association for Computational Linguistics},\n  pages={4129--4138},\n  year={2019},\n}\n\n@article{liu2019roberta,\n  title={RoBERTa: A Robustly Optimized BERT Pretraining Approach},\n  author={Liu, Yinhan and Ott, Myle and Goyal, Naman and Du, Jingfei and Joshi, Mandar and Chen, Danqi and Levy, Omer and Lewis, Mike and Zettlemoyer, Luke and Stoyanov, Veselin},\n  journal={arXiv preprint arXiv:1907.11692},\n  year={2019},\n}\n\n@inproceedings{wang2019persuasion,\n  title={Persuasion for Good: Towards a Personalized Persuasive Dialogue System for Social Good},\n  author={Wang, Xuewei and Shi, Weiyan and Kim, Richard and Oh, Yoojung and Yang, Sijia and Zhang, Jingwen and Yu, Zhou},\n  booktitle={Proceedings of the 57th Annual Meeting of the Association for Computational Linguistics},\n  pages={5635--5649},\n  year={2019},\n}\n\n@inproceedings{robey2024smoothllm,\n  title={SmoothLLM: Defending Large Language Models Against Jailbreaking Attacks},\n  author={Robey, Alexander and Wong, Eric and Hassani, Hamed and Pappas, George J.},\n  booktitle={Proceedings of the 41st International Conference on Machine Learning},\n  year={2024},\n}\n\n@inproceedings{mehrotra2024tap,\n  title={Tree of Attacks: Jailbreaking Black-Box LLMs with the Pruning of Candidate Outputs},\n  author={Mehrotra, Anay and Zampetakis, Manolis and Kassianik, Paul and Nelson, Blaine and Anderson, Hyrum and Singer, Yaron and Karbasi, Amin},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2024},\n}\n\n@article{chao2024jailbreakbench,\n  title={JailbreakBench: An Open Robustness Benchmark for Jailbreaking Large Language Models},\n  author={Chao, Patrick and Robey, Alexander and Dobriban, Edgar and Hassani, Hamed and Pappas, George J. and Wong, Eric},\n  journal={arXiv preprint arXiv:2404.01318},\n  year={2024},\n}\n\n@inproceedings{mazeika2024harmbench,\n  title={HarmBench: A Standardized Evaluation Framework for Automated Red Teaming and Robust Refusal},\n  author={Mazeika, Mantas and Phan, Long and Yin, Xuwang and Zou, Andy and Wang, Zifan and Mu, Norman and Sakhaee, Elham and Li, Nathaniel and Basart, Steven and Li, Bo and Forsyth, David and Hendrycks, Dan},\n  booktitle={Proceedings of the 41st International Conference on Machine Learning},\n  year={2024},\n}\n\n@inproceedings{lu2025xboundary,\n  title={X-Boundary: Establishing Exact Safety Boundary to Shield {LLMs} from Multi-Turn Jailbreaks without Compromising Usability},\n  author={Lu, Xiaoya and Liu, Dongrui and Yu, Yi and Xu, Luxin and Shao, Jing},\n  booktitle={Findings of the Association for Computational Linguistics: EMNLP 2025},\n  year={2025},\n  eprint={2502.09990},\n  archivePrefix={arXiv},\n}\n\n@article{kadali2026trace,\n  title={Jailbreaking Leaves a Trace: Understanding and Detecting Jailbreak Attacks from Internal Representations of Large Language Models},\n  author={Kadali, Sri Durga Sai Sowmya and Papalexakis, Evangelos E.},\n  journal={arXiv preprint arXiv:2602.11495},\n  year={2026},\n  eprint={2602.11495},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{hua2026rcs,\n  title={Rethinking Jailbreak Detection of Large Vision Language Models with Representational Contrastive Scoring},\n  author={Hua, Peichun and Li, Hao and Shi, Shanghao and Yu, Zhiyuan and Zhang, Ning},\n  booktitle={Proceedings of the 64th Annual Meeting of the Association for Computational Linguistics},\n  year={2026},\n  eprint={2512.12069},\n  archivePrefix={arXiv},\n}\n\n@article{jiang2024redqueen,\n  title={{RED QUEEN}: Safeguarding Large Language Models against Concealed Multi-Turn Jailbreaking},\n  author={Jiang, Yifan and Aggarwal, Kriti and Laud, Tanmay and Munir, Kashif and Pujara, Jay and Mukherjee, Subhabrata},\n  journal={arXiv preprint},\n  year={2024},\n  eprint={2409.17458},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{song2026multibreak,\n  title={{MultiBreak}: A Scalable and Diverse Multi-turn Jailbreak Benchmark for Evaluating {LLM} Safety},\n  author={Song, Jialin and Liu, Xiaodong and Yang, Weiwei and Chen, Wuyang and Feng, Mingqian and Zhu, Xuekai and Gao, Jianfeng},\n  booktitle={International Conference on Machine Learning},\n  year={2026},\n  eprint={2605.01687},\n  archivePrefix={arXiv},\n}\n\n% ============================================================\n% New citations (added 2026-05-21)\n% ============================================================\n\n@inproceedings{xie2024gradsafe,\n  title={{GradSafe}: Detecting Jailbreak Prompts for {LLMs} via Safety-Critical Gradient Analysis},\n  author={Xie, Yueqi and Fang, Minghong and Pi, Renjie and Gong, Neil},\n  booktitle={Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics},\n  pages={507--518},\n  year={2024},\n}\n\n@inproceedings{xu2024safedecoding,\n  title={{SafeDecoding}: Defending against Jailbreak Attacks via Safety-Aware Decoding},\n  author={Xu, Zhangchen and Jiang, Fengqing and Niu, Luyao and Jia, Jinyuan and Lin, Bill Yuchen and Poovendran, Radha},\n  booktitle={Proceedings of the 62nd Annual Meeting of the Association for Computational Linguistics},\n  year={2024},\n}\n\n@inproceedings{zou2024circuitbreakers,\n  title={Improving Alignment and Robustness with Circuit Breakers},\n  author={Zou, Andy and Phan, Long and Wang, Justin and Duenas, Derek and Lin, Maxwell and Andriushchenko, Maksym and Wang, Rowan and Kolter, Zico and Fredrikson, Matt and Hendrycks, Dan},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2024},\n}\n\n% ============================================================\n% New citations (added 2026-05-20)\n% ============================================================\n\n@inproceedings{zhang2025jbshield,\n  title={{JBShield}: Defending Large Language Models from Jailbreak Attacks through Activated Concept Analysis and Manipulation},\n  author={Zhang, Shenyi and Zhai, Yuchen and Guo, Keyan and Hu, Hongxin and Guo, Shengnan and Fang, Zheng and Zhao, Lingchen and Shen, Chao and Wang, Cong and Wang, Qian},\n  booktitle={USENIX Security Symposium},\n  year={2025},\n  eprint={2502.07557},\n  archivePrefix={arXiv},\n}\n\n@inproceedings{perez2022redteaming,\n  title={Red Teaming Language Models with Language Models},\n  author={Perez, Ethan and Huang, Saffron and Song, Francis and Cai, Trevor and Ring, Roman and Aslanides, John and Glaese, Amelia and McAleese, Nat and Irving, Geoffrey},\n  booktitle={Proceedings of the 2022 Conference on Empirical Methods in Natural Language Processing},\n  pages={3419--3448},\n  year={2022},\n}\n\n@article{kulkarni2026latentadversarial,\n  title={Latent Adversarial Detection: Adaptive Probing of {LLM} Activations for Multi-Turn Attack Detection},\n  author={Kulkarni, Prashant},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2604.28129},\n  archivePrefix={arXiv},\n}\n\n@article{derya2026revisitingjbshield,\n  title={Revisiting {JBShield}: Breaking and Rebuilding Representation-Level Jailbreak Defenses},\n  author={Derya, Kemal and Sunar, Berk},\n  journal={arXiv preprint},\n  year={2026},\n  eprint={2605.03095},\n  archivePrefix={arXiv},\n}\n\n@article{lee2020biobert,\n  title={{BioBERT}: A Pre-trained Biomedical Language Representation Model for Biomedical Text Mining},\n  author={Lee, Jinhyuk and Yoon, Wonjin and Kim, Sungdong and Kim, Donghyeon and Kim, Sunkyu and So, Chan Ho and Kang, Jaewoo},\n  journal={Bioinformatics},\n  volume={36},\n  number={4},\n  pages={1234--1240},\n  year={2020},\n  publisher={Oxford University Press},\n}\n\n@inproceedings{beltagy2019scibert,\n  title={{SciBERT}: A Pretrained Language Model for Scientific Text},\n  author={Beltagy, Iz and Lo, Kyle and Cohan, Arman},\n  booktitle={Proceedings of the 2019 Conference on Empirical Methods in Natural Language Processing (EMNLP)},\n  pages={3615--3620},\n  year={2019},\n}\n\n@inproceedings{chen2020simclr,\n  title={A Simple Framework for Contrastive Learning of Visual Representations},\n  author={Chen, Ting and Kornblith, Simon and Norouzi, Mohammad and Hinton, Geoffrey},\n  booktitle={International Conference on Machine Learning (ICML)},\n  pages={1597--1607},\n  year={2020},\n}\n\n@inproceedings{grill2020byol,\n  title={Bootstrap Your Own Latent: A New Approach to Self-Supervised Learning},\n  author={Grill, Jean-Bastien and Strub, Florian and Altch{\\'e}, Florent and Tallec, Corentin and Richemond, Pierre H. and Buchatskaya, Elena and Doersch, Carl and Pires, Bernardo Avila and Guo, Zhaohan Daniel and Azar, Mohammad Gheshlaghi and Piot, Bilal and Kavukcuoglu, Koray and Munos, R{\\'e}mi and Valko, Michal},\n  booktitle={Advances in Neural Information Processing Systems (NeurIPS)},\n  year={2020},\n}\n\n% ============================================================\n% New citations (Round 10 fixes)\n% ============================================================\n\n@article{zhang2021understanding,\n  title={Understanding Deep Learning (Still) Requires Rethinking Generalization},\n  author={Zhang, Chiyuan and Bengio, Samy and Hardt, Moritz and Recht, Benjamin and Vinyals, Oriol},\n  journal={Communications of the ACM},\n  volume={64},\n  number={3},\n  pages={107--115},\n  year={2021},\n  doi={10.1145/3446776},\n}\n\n@inproceedings{maennel2020random,\n  title={What Do Neural Networks Learn When Trained With Random Labels?},\n  author={Maennel, Hartmut and Alabdulmohsin, Ibrahim M. and Tolstikhin, Ilya O. and Baldock, Robert J. N. and Bousquet, Olivier and Gelly, Sylvain and Keysers, Daniel},\n  booktitle={Advances in Neural Information Processing Systems},\n  year={2020},\n}\n",
    "structuredPatch": [
      {
        "oldStart": 217,
        "oldLines": 6,
        "newStart": 217,
        "newLines": 7,
        "lines": [
          "   year={2024},",
          " }",
          " ",
          "+% Note: key retains \"2024\" for citation compatibility; paper published at ICLR 2025",
          " @inproceedings{ren2024actorattack,",
          "   title={ActorAttack: Red-Teaming Large Language Models via Multi-Turn Actor Network Theory},",
          "   author={Ren, Qibing and Li, Hao and Liu, Dongrui and Xie, Zhanxu and Lu, Xiaoya and Qiao, Yu and Sha, Lei and Yan, Junchi and Ma, Lizhuang and Shao, Jing},"
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

_source line 32_

```
## Austin/Cialdini: 确认正确
- austin1962speechacts: Harvard UP, 1962 — 正确
- cialdini2001influence: Allyn & Bacon, 4th ed, 2001 — 正确

## maennel2020random: 未引用 → 已添加引用
- conclusion.tex L19: `\citep{zhang2021understanding}` → `\citep{zhang2021understanding,maennel2020random}`

## 孤立 entries: 1 条
- **devlin2019bert** — BERT 原文，bib 中有定义但未被任何 .tex 文件 \cite

## Bib mismatch: 3 处已修复
1. **grill2020byol**: 作者名 "Buchatber, Elena" → "Buchatskaya, Elena"（拼写错误）
2. **andriushchenko2024adaptive**: key=2024 / year=2025，缺注释 → 已添加说明
3. **ren2024actorattack**: key=2024 / year=2025，缺注释 → 已添加说明

其余条目格式统一，无重复，重音符号正确。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "uuid": "9ab9fd5b-602b-4b09-8918-b9d2346dfad5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018LtwfLiTJYJsLt5QXC29K2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 564,
      "cache_read_input_tokens": 43999,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 564
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

_source line 33_

```
## Austin/Cialdini: 确认正确
- austin1962speechacts: Harvard UP, 1962 — 正确
- cialdini2001influence: Allyn & Bacon, 4th ed, 2001 — 正确

## maennel2020random: 未引用 → 已添加引用
- conclusion.tex L19: `\citep{zhang2021understanding}` → `\citep{zhang2021understanding,maennel2020random}`

## 孤立 entries: 1 条
- **devlin2019bert** — BERT 原文，bib 中有定义但未被任何 .tex 文件 \cite

## Bib mismatch: 3 处已修复
1. **grill2020byol**: 作者名 "Buchatber, Elena" → "Buchatskaya, Elena"（拼写错误）
2. **andriushchenko2024adaptive**: key=2024 / year=2025，缺注释 → 已添加说明
3. **ren2024actorattack**: key=2024 / year=2025，缺注释 → 已添加说明

其余条目格式统一，无重复，重音符号正确。

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 90480,
  "duration_api_ms": 91419,
  "num_turns": 11,
  "stop_reason": "end_turn",
  "session_id": "1996ceff-d3d2-4190-b3fd-e49e0bfc7024",
  "total_cost_usd": 0.43588449999999995,
  "usage": {
    "input_tokens": 113,
    "cache_creation_input_tokens": 32722,
    "cache_read_input_tokens": 194580,
    "output_tokens": 5267,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 32722,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 324,
        "cache_read_input_tokens": 43999,
        "cache_creation_input_tokens": 564,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 564
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1762,
      "outputTokens": 16,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.0018419999999999999,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 113,
      "outputTokens": 5267,
      "cacheReadInputTokens": 194580,
      "cacheCreationInputTokens": 32722,
      "webSearchRequests": 0,
      "costUSD": 0.4340425,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "788a7168-a445-4a2b-9b70-f376c513eb0d"
}
```

</details>

---
