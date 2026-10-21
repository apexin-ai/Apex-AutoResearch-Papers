# paper writing limitations

**When Debiasing Hurts: An Exact Bias Identity for LLM-Annotated Treatment Effects** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 26
- **Recorded user turns:** 0
- **Tool calls:** 8
- **Original source:** `logs/workers/worker_paper_writing_limitations_20260521T054219.log`
- **Structured JSON:** [`97e9df0f801a943dc2a1.json`](../../sessions/97/97e9df0f801a943dc2a1.json)

## Before a recorded user message

26 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation",
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
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
    "mcp__agent-ml-research__auto_build_provenance",
    "mcp__agent-ml-research__bootstrap_provenance",
    "mcp__agent-ml-research__check_figures_and_layout",
    "mcp__agent-ml-research__check_paper_consistency",
    "mcp__agent-ml-research__check_provenance_completeness",
    "mcp__agent-ml-research__cleanup_pdf_images",
    "mcp__agent-ml-research__compute_coverage_matrix",
    "mcp__agent-ml-research__edit_paper_section",
    "mcp__agent-ml-research__get_image_info",
    "mcp__agent-ml-research__get_worker_status",
    "mcp__agent-ml-research__list_artifacts",
    "mcp__agent-ml-research__list_workers",
    "mcp__agent-ml-research__load_project_config",
    "mcp__agent-ml-research__overleaf_init",
    "mcp__agent-ml-research__overleaf_pull",
    "mcp__agent-ml-research__overleaf_push",
    "mcp__agent-ml-research__overleaf_status",
    "mcp__agent-ml-research__overleaf_sync",
    "mcp__agent-ml-research__paper_agent_post_to_director",
    "mcp__agent-ml-research__paper_agent_request_review",
    "mcp__agent-ml-research__paper_compile_and_check",
    "mcp__agent-ml-research__pdf_to_images",
    "mcp__agent-ml-research__read_experiment_plan_with_status",
    "mcp__agent-ml-research__read_project_file",
    "mcp__agent-ml-research__read_registry",
    "mcp__agent-ml-research__read_roadmap",
    "mcp__agent-ml-research__register_artifact",
    "mcp__agent-ml-research__save_project_file",
    "mcp__agent-ml-research__send_progress",
    "mcp__agent-ml-research__spawn_worker",
    "mcp__agent-ml-research__verify_references",
    "mcp__agent-ml-research__write_paper_section"
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
  "uuid": "eb90fa43-e58a-4085-93b3-beeed39fe286",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude/projects/-home-ubuntu--agent-ml-research-idea-gen-0520-projects-ec-hte-llm-annotation/memory/"
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
    "resetsAt": 1779360000,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "fa3cd9f3-72fd-4dcc-9e3f-e4923910abaa",
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735"
}
```

---

### Assistant

_source line 4_

I'll start by reading the required skill files and reference files in parallel.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "4cf84399-61ac-4d03-abb0-0edc73911531",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014RWY3wTcTogP8McSwAfMCh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12604,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12604
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

<details open><summary>🔧 Tool call — Read · `toolu_01L4AqQkKnFVqdM99EDuGbGb`</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "e312977a-7889-47af-b8fa-418a0d0edecf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014RWY3wTcTogP8McSwAfMCh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12604,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12604
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

_source line 6 · 2026-05-21T05:42:30.009Z_

<details><summary>↩ Tool result · `toolu_01L4AqQkKnFVqdM99EDuGbGb`</summary>

````text
1	---
2	name: paper-writing-norms
3	description: 顶会级别论文写作风格规范——章节写法（Abstract/Intro/Related Work）、去 AI 风格、视觉密度、叙事哲学。Paper Agent 和 Worker 写论文章节时必须加载。
4	allowed-tools: [Read, Write, Edit, Glob, Grep]
5	scope: global
6	version: 2
7	priority: 9
8	tags:
9	  - writing
10	  - paper
11	  - style
12	  - norms
13	roles:
14	  - agent
15	  - worker
16	  - paper_agent
17	---
18	
19	# 论文写作风格规范
20	
21	> 核心哲学：**论文是一个有说服力的故事，不是实验报告。** 审稿人在几十秒内判断论文价值——如果 Abstract 和 Introduction 读起来像实验日志，论文就已经失败了。
22	
23	---
24	
25	## 一、总体写作哲学
26	
27	### 1.1 故事驱动，不是数据堆砌
28	
29	- 论文必须以"故事线"为核心展开：问题 → 洞察 → 方法 → 验证
30	- 禁止大量实验数据堆砌——每个数字出现必须服务于叙事推进
31	- 附录内容必须在正文中有明确引用且融入叙事，禁止简单堆砌
32	- 如果附录数据对核心叙事有重大影响，根据附录数据调整论文 framing
33	
34	### 1.2 主线统一性
35	
36	- 当 idea 在研究过程中发生变化后，**必须重审全文逻辑**
37	- 常见问题：Introduction 讲的故事 A，Method 做的是故事 B，Results 又在讲故事 C
38	- 修复方式：从最终实验结论反推，重写 Introduction 的问题定义和动机
39	- 每次 idea 调整后检查：Abstract → Introduction → Method → Results → Discussion → Conclusion 是否形成一条连贯主线
40	
41	### 1.3 专有名词必须有定义
42	
43	- 首次出现的专有名词/缩写必须给出完整定义和解释
44	- Abstract 中使用的缩写也必须在 Abstract 内定义（如 LLM = Large Language Model）
45	- 不能假设读者知道你自己定义的术语——论文从来没解释过的概念不能直接使用
46	- 通用规则：如果一个非标准术语第一次出现时没有括号定义，就是写作 bug
47	
48	### 1.4 写作前必读同类优秀论文
49	
50	- 每个章节动笔前，找 **2-3 篇目标会议近 1-2 年的高分论文**作为风格参考——同类问题或同类方法皆可
51	- 重点学：
52	  - Abstract 怎么用最少篇幅讲完故事
53	  - Introduction 怎么从大问题切入到具体贡献
54	  - Related Work 怎么 positioning 自己（不是 survey）
55	  - Table/Figure 怎么压缩信息密度
56	- **不是抄袭**，是学习同行的故事节奏和审美——不同子领域叙事节奏差异很大
57	- 实操：Paper Agent 可以从 `literature_map.yaml` 中挑 `role=foundation` 或 `role=direct-competitor` 的论文，把 `{title, venue, year, abstract}` 附在 Worker 的 task_prompt 中作为概念参考；如需学习写作风格本身，让 Worker 通过 WebSearch 取得论文链接并 fetch 全文
58	
59	---
60	
61	## 二、Abstract 写作规范
62	
63	### 2.1 四个必答问题（150-250 words）
64	
65	Abstract 必须在很短的篇幅内清楚回答：
66	1. **研究什么问题** — 1-2 句话交代背景和痛点
67	2. **为什么重要** — 现有方法的不足（不用写太多）
68	3. **本文提出什么** — 核心贡献的关键机制（简要，不堆砌细节）
69	4. **结果说明什么** — 用具体实验结论支撑贡献
70	
71	### 2.2 禁忌
72	
73	- **禁止堆砌数据**：Abstract 不是 Results 的缩写。最多引用 2-3 个关键数字，要服务于 claim
74	- **禁止过度宣传**：不说 "revolutionary"、"groundbreaking"
75	- **禁止写成 Introduction 的缩写**：Abstract 是独立阅读单元
76	- **禁止术语堆积**：如果审稿人几十秒内判断不出价值，就失败了
77	- **缩写必须定义**：Abstract 中首次出现的缩写必须展开
78	
79	### 2.3 审稿人视角检验
80	
81	写完后用这个标准自检：审稿人能否在 30 秒内判断——
82	- 问题是否重要？
83	- 方法是否清楚？
84	- 贡献是否可信？
85	- 结果是否有说服力？
86	
87	---
88	
89	## 三、Introduction 写作规范
90	
91	### 3.1 完整叙事线（5 段结构）
92	
93	Introduction 需要从一个清晰、重要的问题切入，逐步把读者带到核心贡献：
94	
95	1. **研究背景**（1-2 段）：大模型在某类能力/应用中已取得进展，但仍存在一个关键瓶颈
96	2. **问题重要性**（1 段）：结合真实应用、已有方法局限或当前趋势，说明这不是小问题
97	3. **现有方法不足**（1 段）：系统梳理为什么不够（依赖更大模型/更多数据/更复杂推理/更高成本，或只在特定 benchmark 有效）
98	4. **本文核心想法**（1 段）：我们观察到什么、提出了什么方法、为什么能解决上述问题
99	5. **贡献总结**（列表）：清楚列出方法贡献、实验贡献和分析贡献
100	
101	### 3.2 整体叙事结构
102	
103	```
104	现有进展 → 关键缺口 → 本文洞察 → 方法概述 → 实验证据 → 贡献总结
105	```
106	
107	### 3.3 禁忌
108	
109	- **禁止泛泛介绍**：不要开头就写 "LLMs have shown remarkable capabilities..."，要从具体问题切入
110	- **禁止缺少过渡**：每段之间必须有逻辑连接
111	- **禁止实验报告风格**：Introduction 不是 "我们做了 X 实验得到了 Y 结果" 的罗列
112	- 每条 Contribution 必须有对应的 section/table 支撑
113	- Contribution 列表中不能出现未在前文铺垫过的概念
114	
115	---
116	
117	## 四、Related Work 写作规范
118	
119	### 4.1 目标
120	
121	让审稿人相信：作者理解这个领域，知道自己的方法站在什么位置，清楚相对已有工作的真实增量在哪里。
122	
123	### 4.2 结构要求
124	
125	- 把已有工作分成几个清晰的主题（如模型训练、推理增强、工具调用、数据构建、评测等）
126	- 每类简要说明：已有方法做了什么、解决了哪些问题、和本文的关系
127	- 帮助读者理解：哪些是本文直接继承的，哪些方法不同但解决相似问题，哪些留下了本文要解决的缺口
128	
129	### 4.3 禁忌
130	
131	- **禁止论文堆砌**：不要写成 "A proposed X. B proposed Y. C proposed Z." 的列表
132	- **目标不是展示读了多少论文**，而是做归纳和比较
133	- Contribution claim（"To our knowledge, no prior work..."）应放在 Introduction，不在 Related Work
134	
135	### 4.4 引用充足度
136	
137	- 引用必须覆盖：**直接相关方法、baseline 论文、评测 benchmark 论文、理论基础**
138	- 任何一类缺失，审稿人会立刻看出来调研不充分
139	- 引用密度参照目标会议近年录用论文的量级——明显偏少意味着 Related Work 调研不足
140	
141	---
142	
143	## 五、去 AI 写作风格（硬规则）
144	
145	以下模式是 AI 生成文本的典型标志，审稿人一眼能看出。**必须全部消除。**
146	
147	### 5.1 严禁破折号（最显著的 AI 痕迹）
148	
149	**这是 AI 写作最容易被识别的标志，审稿人最敏感。单列为最高优先级硬规则。**
150	
151	- 解释性 em-dash（—，U+2014）和 en-dash（–，U+2013）必须**全部删除**
152	- 替代方式：用逗号、括号或拆分为两个句子
153	- 强制检查命令：
154	  ```bash
155	  grep -n "—" paper/*.tex     # em-dash，每处人工判断是否必要
156	  grep -n " – " paper/*.tex   # 解释性 en-dash，几乎都应删除
157	  ```
158	- 例外（允许保留）：表格分隔符、数字范围（`2020–2024`、`pp. 12–18`）、专有名词（`Newton–Raphson`）
159	
160	### 5.2 段落与句式
161	
162	- **禁止过度分段**：不需要每 2-3 句就换段，自然段 5-8 句是正常的
163	- **减少关系从句**（which, that, who）：能用简洁直接的句子就不用从句
164	- **禁止 -ing 短语结尾**：如 "..., highlighting the applicability of..." / "..., demonstrating the effectiveness of..."。这是 AI 写作最典型的标志之一
165	- **禁止连续使用 "Furthermore" / "Moreover" / "Additionally"**：一段内最多用一个过渡词
166	- **避免 "It is worth noting that..." / "Notably, ..."**：直接写要说的内容
167	
168	### 5.3 用词黑名单
169	
170	- 避免 "delve into" / "leverage" / "utilize" / "facilitate" — 用 "explore" / "use" / "enable"
171	- 避免 "a myriad of" / "a plethora of" — 用 "many" / "various"
172	- 避免 "in the realm of" / "in the context of" — 直接说
173	- 避免 "paradigm shift" / "novel" 过度使用
174	
175	### 5.4 校对清单（4 步）
176	
177	1. 全文 proofread 语法和拼写
178	2. 检查所有代词/指示词（this, that, it）是否指代明确
179	3. **`grep "—"` + `grep " – "` 全文清零**（删除所有解释性 dash，§5.1）
180	4. `grep "ing,"` 模式——大部分 -ing 分词短语需要改写
181	
182	---
183	
184	## 六、图表与视觉规范
185	
186	### 6.1 知识密度原则
187	
188	- **图表的信息必须紧凑**——不能为了美观而留大量白空间
189	- 一张图如果只传达一个简单信息，要么缩小要么合并到其他图中
190	- 能用 inline text 说清的不要占一整个 Figure
191	
192	### 6.2 表格规范
193	
194	- 表格和正文文字不能视觉重叠（检查 column 宽度和 alignment）
195	- 小数精度全表统一
196	- 最优加粗、次优下划线
197	- Caption 必须自包含
198	
199	### 6.3 图片规范
200	
201	- 数值标签不能被线、bar、点遮住——用白色背景或偏移标签
202	- 图中字体 >= 7pt（打印后仍可读）
203	- 栏宽约束需匹配目标 venue 模板要求
204	- 概念图/流程图要有信息量，不要画一个 trivial 的 pipeline 然后占半页
205	
206	### 6.4 空间效率
207	
208	- 顶会正文页数严格受限（具体页数查目标会议官网），每 cm² 都是宝贵资源
209	- 优先使用 `\subfigure` 合并相关图
210	- Table 能 inline 就不要单独浮动
211	- 图表占比与其对叙事的贡献成正比
212	
213	### 6.5 页面节奏
214	
215	好论文的页面有节奏感——text、equation、figure 交替出现，读者视觉不疲劳：
216	
217	- **text-equation-figure 三重奏**：重要概念用"文字解释 → 公式定义 → 图表直觉"三步展开
218	- 连续 2 页纯文本（无 figure/equation/table）→ 穿插一个 display item 打破节奏
219	- 连续 2 个 figure 页（整页被 float 占满）→ 至少隔 1 段文字再放下一个 float
220	- Section heading 不孤悬页底（heading 后至少跟 2 行正文，否则强制分页）
221	- 最后一页内容 ≥ 2/3 页面高度（太空显得凑数，太满放不下 references）
222	
223	### 6.6 表格 LaTeX 规范
224	
225	**Booktabs 标准（硬规则）**：
226	- 用 `\toprule` / `\midrule` / `\bottomrule`，禁止 `\hline`，禁止竖线 `|`
227	- 用 `\centering` 不用 `\begin{center}`（后者多加垂直空白）
228	- 最优结果加粗（`\textbf{}`），次优下划线（`\underline{}`）+ 方向箭头 `↑`/`↓` 标明指标方向
229	- 小数精度全表统一（如全部保留 1 位或 2 位）
230	- Caption 在表格上方（`\caption` 在 `\begin{tabular}` 之前）
231	
232	**宽度决策树**：
233	- ≤5 列 → 单栏宽度（`\columnwidth`）
234	- 6–8 列 → 全文宽度（`\textwidth`，双栏模板用 `table*`）
235	- >8 列 → 拆成两张表或移入 appendix
236	
237	---
238	
239	## 七、投稿前通用准备
240	
241	### 7.1 模板必须官方（硬规则）
242	
243	- LaTeX 模板**必须从目标会议官网下载**（CallForPapers / Author Instructions 页面）
244	- **不要用**：
245	  - 网上他人转载的复制版本（可能被改过 margin / 行号设置）
246	  - 上一年的模板（参数可能变：字体、margin、行号、anonymous 选项等）
247	  - 组里学长留的旧版本（来源不明、无法追溯）
248	- 风险：
249	  - 样式不符合 → desk reject
250	  - margin 不对 → 被审稿人质疑诚信
251	  - reference 格式错 → 被认为不规范
252	- 流程：先查会议官网 templates → 找不到再 `WebSearch "{venue} {year} latex template official"` → 仍找不到汇报 Director（不要用就近年版本顶替）
253	- `\documentclass[]{}` 选项必须与目标 venue + 阶段（review / camera-ready）一致
254	
255	### 7.2 投稿要求逐项核对
256	
257	- 目标会议如要求 Checklist / Ethical Statement / Broader Impact Statement / Reproducibility Statement，必须**认真填每一项**，不要全写 N/A
258	- 页数限制：查目标会议官网
259	- 匿名化要求：review 版 vs camera-ready 版本设置不同
260	- 行号开启（review 版常需）
261	- 字体大小、margin 不得修改 sty 文件
262	
263	### 7.3 最终修改 10 项检查流程
264	
265	提交前必须逐一检查：
266	1. 所有最新实验结果已全部录入
267	2. 根据实验结果将叙事调至最优状态
268	3. 附录所有内容在正文中被引用且融入叙事
269	4. 无数据堆砌（每个数字服务于叙事推进）
270	5. Abstract 和 Introduction 具有吸引力（不是实验报告风格）
271	6. 全文主线统一（idea 变化后各章节逻辑一致）
272	7. 所有专有名词有定义
273	8. 无 AI 风格标志（dash、-ing phrases、过度分段）
274	9. 图表知识密度高、无视觉遮挡
275	10. Reference 覆盖直接相关方法、baseline、benchmark、理论基础
276	
````

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "4b80e60d-19a6-4ff8-94f2-392c11f16547",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/agent-ml-research/skills/global/paper-writing-norms.skill.md",
      "content": "---\nname: paper-writing-norms\ndescription: 顶会级别论文写作风格规范——章节写法（Abstract/Intro/Related Work）、去 AI 风格、视觉密度、叙事哲学。Paper Agent 和 Worker 写论文章节时必须加载。\nallowed-tools: [Read, Write, Edit, Glob, Grep]\nscope: global\nversion: 2\npriority: 9\ntags:\n  - writing\n  - paper\n  - style\n  - norms\nroles:\n  - agent\n  - worker\n  - paper_agent\n---\n\n# 论文写作风格规范\n\n> 核心哲学：**论文是一个有说服力的故事，不是实验报告。** 审稿人在几十秒内判断论文价值——如果 Abstract 和 Introduction 读起来像实验日志，论文就已经失败了。\n\n---\n\n## 一、总体写作哲学\n\n### 1.1 故事驱动，不是数据堆砌\n\n- 论文必须以\"故事线\"为核心展开：问题 → 洞察 → 方法 → 验证\n- 禁止大量实验数据堆砌——每个数字出现必须服务于叙事推进\n- 附录内容必须在正文中有明确引用且融入叙事，禁止简单堆砌\n- 如果附录数据对核心叙事有重大影响，根据附录数据调整论文 framing\n\n### 1.2 主线统一性\n\n- 当 idea 在研究过程中发生变化后，**必须重审全文逻辑**\n- 常见问题：Introduction 讲的故事 A，Method 做的是故事 B，Results 又在讲故事 C\n- 修复方式：从最终实验结论反推，重写 Introduction 的问题定义和动机\n- 每次 idea 调整后检查：Abstract → Introduction → Method → Results → Discussion → Conclusion 是否形成一条连贯主线\n\n### 1.3 专有名词必须有定义\n\n- 首次出现的专有名词/缩写必须给出完整定义和解释\n- Abstract 中使用的缩写也必须在 Abstract 内定义（如 LLM = Large Language Model）\n- 不能假设读者知道你自己定义的术语——论文从来没解释过的概念不能直接使用\n- 通用规则：如果一个非标准术语第一次出现时没有括号定义，就是写作 bug\n\n### 1.4 写作前必读同类优秀论文\n\n- 每个章节动笔前，找 **2-3 篇目标会议近 1-2 年的高分论文**作为风格参考——同类问题或同类方法皆可\n- 重点学：\n  - Abstract 怎么用最少篇幅讲完故事\n  - Introduction 怎么从大问题切入到具体贡献\n  - Related Work 怎么 positioning 自己（不是 survey）\n  - Table/Figure 怎么压缩信息密度\n- **不是抄袭**，是学习同行的故事节奏和审美——不同子领域叙事节奏差异很大\n- 实操：Paper Agent 可以从 `literature_map.yaml` 中挑 `role=foundation` 或 `role=direct-competitor` 的论文，把 `{title, venue, year, abstract}` 附在 Worker 的 task_prompt 中作为概念参考；如需学习写作风格本身，让 Worker 通过 WebSearch 取得论文链接并 fetch 全文\n\n---\n\n## 二、Abstract 写作规范\n\n### 2.1 四个必答问题（150-250 words）\n\nAbstract 必须在很短的篇幅内清楚回答：\n1. **研究什么问题** — 1-2 句话交代背景和痛点\n2. **为什么重要** — 现有方法的不足（不用写太多）\n3. **本文提出什么** — 核心贡献的关键机制（简要，不堆砌细节）\n4. **结果说明什么** — 用具体实验结论支撑贡献\n\n### 2.2 禁忌\n\n- **禁止堆砌数据**：Abstract 不是 Results 的缩写。最多引用 2-3 个关键数字，要服务于 claim\n- **禁止过度宣传**：不说 \"revolutionary\"、\"groundbreaking\"\n- **禁止写成 Introduction 的缩写**：Abstract 是独立阅读单元\n- **禁止术语堆积**：如果审稿人几十秒内判断不出价值，就失败了\n- **缩写必须定义**：Abstract 中首次出现的缩写必须展开\n\n### 2.3 审稿人视角检验\n\n写完后用这个标准自检：审稿人能否在 30 秒内判断——\n- 问题是否重要？\n- 方法是否清楚？\n- 贡献是否可信？\n- 结果是否有说服力？\n\n---\n\n## 三、Introduction 写作规范\n\n### 3.1 完整叙事线（5 段结构）\n\nIntroduction 需要从一个清晰、重要的问题切入，逐步把读者带到核心贡献：\n\n1. **研究背景**（1-2 段）：大模型在某类能力/应用中已取得进展，但仍存在一个关键瓶颈\n2. **问题重要性**（1 段）：结合真实应用、已有方法局限或当前趋势，说明这不是小问题\n3. **现有方法不足**（1 段）：系统梳理为什么不够（依赖更大模型/更多数据/更复杂推理/更高成本，或只在特定 benchmark 有效）\n4. **本文核心想法**（1 段）：我们观察到什么、提出了什么方法、为什么能解决上述问题\n5. **贡献总结**（列表）：清楚列出方法贡献、实验贡献和分析贡献\n\n### 3.2 整体叙事结构\n\n```\n现有进展 → 关键缺口 → 本文洞察 → 方法概述 → 实验证据 → 贡献总结\n```\n\n### 3.3 禁忌\n\n- **禁止泛泛介绍**：不要开头就写 \"LLMs have shown remarkable capabilities...\"，要从具体问题切入\n- **禁止缺少过渡**：每段之间必须有逻辑连接\n- **禁止实验报告风格**：Introduction 不是 \"我们做了 X 实验得到了 Y 结果\" 的罗列\n- 每条 Contribution 必须有对应的 section/table 支撑\n- Contribution 列表中不能出现未在前文铺垫过的概念\n\n---\n\n## 四、Related Work 写作规范\n\n### 4.1 目标\n\n让审稿人相信：作者理解这个领域，知道自己的方法站在什么位置，清楚相对已有工作的真实增量在哪里。\n\n### 4.2 结构要求\n\n- 把已有工作分成几个清晰的主题（如模型训练、推理增强、工具调用、数据构建、评测等）\n- 每类简要说明：已有方法做了什么、解决了哪些问题、和本文的关系\n- 帮助读者理解：哪些是本文直接继承的，哪些方法不同但解决相似问题，哪些留下了本文要解决的缺口\n\n### 4.3 禁忌\n\n- **禁止论文堆砌**：不要写成 \"A proposed X. B proposed Y. C proposed Z.\" 的列表\n- **目标不是展示读了多少论文**，而是做归纳和比较\n- Contribution claim（\"To our knowledge, no prior work...\"）应放在 Introduction，不在 Related Work\n\n### 4.4 引用充足度\n\n- 引用必须覆盖：**直接相关方法、baseline 论文、评测 benchmark 论文、理论基础**\n- 任何一类缺失，审稿人会立刻看出来调研不充分\n- 引用密度参照目标会议近年录用论文的量级——明显偏少意味着 Related Work 调研不足\n\n---\n\n## 五、去 AI 写作风格（硬规则）\n\n以下模式是 AI 生成文本的典型标志，审稿人一眼能看出。**必须全部消除。**\n\n### 5.1 严禁破折号（最显著的 AI 痕迹）\n\n**这是 AI 写作最容易被识别的标志，审稿人最敏感。单列为最高优先级硬规则。**\n\n- 解释性 em-dash（—，U+2014）和 en-dash（–，U+2013）必须**全部删除**\n- 替代方式：用逗号、括号或拆分为两个句子\n- 强制检查命令：\n  ```bash\n  grep -n \"—\" paper/*.tex     # em-dash，每处人工判断是否必要\n  grep -n \" – \" paper/*.tex   # 解释性 en-dash，几乎都应删除\n  ```\n- 例外（允许保留）：表格分隔符、数字范围（`2020–2024`、`pp. 12–18`）、专有名词（`Newton–Raphson`）\n\n### 5.2 段落与句式\n\n- **禁止过度分段**：不需要每 2-3 句就换段，自然段 5-8 句是正常的\n- **减少关系从句**（which, that, who）：能用简洁直接的句子就不用从句\n- **禁止 -ing 短语结尾**：如 \"..., highlighting the applicability of...\" / \"..., demonstrating the effectiveness of...\"。这是 AI 写作最典型的标志之一\n- **禁止连续使用 \"Furthermore\" / \"Moreover\" / \"Additionally\"**：一段内最多用一个过渡词\n- **避免 \"It is worth noting that...\" / \"Notably, ...\"**：直接写要说的内容\n\n### 5.3 用词黑名单\n\n- 避免 \"delve into\" / \"leverage\" / \"utilize\" / \"facilitate\" — 用 \"explore\" / \"use\" / \"enable\"\n- 避免 \"a myriad of\" / \"a plethora of\" — 用 \"many\" / \"various\"\n- 避免 \"in the realm of\" / \"in the context of\" — 直接说\n- 避免 \"paradigm shift\" / \"novel\" 过度使用\n\n### 5.4 校对清单（4 步）\n\n1. 全文 proofread 语法和拼写\n2. 检查所有代词/指示词（this, that, it）是否指代明确\n3. **`grep \"—\"` + `grep \" – \"` 全文清零**（删除所有解释性 dash，§5.1）\n4. `grep \"ing,\"` 模式——大部分 -ing 分词短语需要改写\n\n---\n\n## 六、图表与视觉规范\n\n### 6.1 知识密度原则\n\n- **图表的信息必须紧凑**——不能为了美观而留大量白空间\n- 一张图如果只传达一个简单信息，要么缩小要么合并到其他图中\n- 能用 inline text 说清的不要占一整个 Figure\n\n### 6.2 表格规范\n\n- 表格和正文文字不能视觉重叠（检查 column 宽度和 alignment）\n- 小数精度全表统一\n- 最优加粗、次优下划线\n- Caption 必须自包含\n\n### 6.3 图片规范\n\n- 数值标签不能被线、bar、点遮住——用白色背景或偏移标签\n- 图中字体 >= 7pt（打印后仍可读）\n- 栏宽约束需匹配目标 venue 模板要求\n- 概念图/流程图要有信息量，不要画一个 trivial 的 pipeline 然后占半页\n\n### 6.4 空间效率\n\n- 顶会正文页数严格受限（具体页数查目标会议官网），每 cm² 都是宝贵资源\n- 优先使用 `\\subfigure` 合并相关图\n- Table 能 inline 就不要单独浮动\n- 图表占比与其对叙事的贡献成正比\n\n### 6.5 页面节奏\n\n好论文的页面有节奏感——text、equation、figure 交替出现，读者视觉不疲劳：\n\n- **text-equation-figure 三重奏**：重要概念用\"文字解释 → 公式定义 → 图表直觉\"三步展开\n- 连续 2 页纯文本（无 figure/equation/table）→ 穿插一个 display item 打破节奏\n- 连续 2 个 figure 页（整页被 float 占满）→ 至少隔 1 段文字再放下一个 float\n- Section heading 不孤悬页底（heading 后至少跟 2 行正文，否则强制分页）\n- 最后一页内容 ≥ 2/3 页面高度（太空显得凑数，太满放不下 references）\n\n### 6.6 表格 LaTeX 规范\n\n**Booktabs 标准（硬规则）**：\n- 用 `\\toprule` / `\\midrule` / `\\bottomrule`，禁止 `\\hline`，禁止竖线 `|`\n- 用 `\\centering` 不用 `\\begin{center}`（后者多加垂直空白）\n- 最优结果加粗（`\\textbf{}`），次优下划线（`\\underline{}`）+ 方向箭头 `↑`/`↓` 标明指标方向\n- 小数精度全表统一（如全部保留 1 位或 2 位）\n- Caption 在表格上方（`\\caption` 在 `\\begin{tabular}` 之前）\n\n**宽度决策树**：\n- ≤5 列 → 单栏宽度（`\\columnwidth`）\n- 6–8 列 → 全文宽度（`\\textwidth`，双栏模板用 `table*`）\n- >8 列 → 拆成两张表或移入 appendix\n\n---\n\n## 七、投稿前通用准备\n\n### 7.1 模板必须官方（硬规则）\n\n- LaTeX 模板**必须从目标会议官网下载**（CallForPapers / Author Instructions 页面）\n- **不要用**：\n  - 网上他人转载的复制版本（可能被改过 margin / 行号设置）\n  - 上一年的模板（参数可能变：字体、margin、行号、anonymous 选项等）\n  - 组里学长留的旧版本（来源不明、无法追溯）\n- 风险：\n  - 样式不符合 → desk reject\n  - margin 不对 → 被审稿人质疑诚信\n  - reference 格式错 → 被认为不规范\n- 流程：先查会议官网 templates → 找不到再 `WebSearch \"{venue} {year} latex template official\"` → 仍找不到汇报 Director（不要用就近年版本顶替）\n- `\\documentclass[]{}` 选项必须与目标 venue + 阶段（review / camera-ready）一致\n\n### 7.2 投稿要求逐项核对\n\n- 目标会议如要求 Checklist / Ethical Statement / Broader Impact Statement / Reproducibility Statement，必须**认真填每一项**，不要全写 N/A\n- 页数限制：查目标会议官网\n- 匿名化要求：review 版 vs camera-ready 版本设置不同\n- 行号开启（review 版常需）\n- 字体大小、margin 不得修改 sty 文件\n\n### 7.3 最终修改 10 项检查流程\n\n提交前必须逐一检查：\n1. 所有最新实验结果已全部录入\n2. 根据实验结果将叙事调至最优状态\n3. 附录所有内容在正文中被引用且融入叙事\n4. 无数据堆砌（每个数字服务于叙事推进）\n5. Abstract 和 Introduction 具有吸引力（不是实验报告风格）\n6. 全文主线统一（idea 变化后各章节逻辑一致）\n7. 所有专有名词有定义\n8. 无 AI 风格标志（dash、-ing phrases、过度分段）\n9. 图表知识密度高、无视觉遮挡\n10. Reference 覆盖直接相关方法、baseline、benchmark、理论基础\n",
      "numLines": 276,
      "startLine": 1,
      "totalLines": 276
    }
  }
}
````

</details>

---

### Tool call

_source line 7_

<details open><summary>🔧 Tool call — Read · `toolu_01Kgcgt8mbcQkBZjEsz5nyJK`</summary>

```json
{
  "file_path": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "115b9cfa-1a92-4c48-9277-bd187c1dc1b4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014RWY3wTcTogP8McSwAfMCh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12604,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12604
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

_source line 8 · 2026-05-21T05:42:30.476Z_

<details><summary>↩ Tool result · `toolu_01Kgcgt8mbcQkBZjEsz5nyJK`</summary>

````text
1	---
2	name: latex-paper
3	description: ML 顶会论文 LaTeX 写作全流程——Claim-Evidence 方法论、引用防幻觉、顶会模板速查、投稿工程链、会议转投。写论文/投稿时参考。
4	scope: global
5	tags:
6	- latex
7	- paper-writing
8	- academic
9	- citation
10	- submission
11	version: 1
12	roles:
13	- agent
14	- worker
15	---
16	
17	# LaTeX 论文写作全流程
18	
19	ML/AI 顶会论文从草稿到投稿的完整指南。整合 Orchestra Research、VibeSkills、claim2evidence 三方最佳实践。
20	
21	---
22	
23	## 1. 工作模式
24	
25	开始前选择模式：
26	
27	| 模式 | 说明 | 适用 |
28	|------|------|------|
29	| **Build** | 从实验笔记/结果/代码生成论文 | 新稿 |
30	| **Improve** | 改写已有章节，强化论证 | 修改稿 |
31	| **Audit** | 输出风险列表 + 缺失证据 + 修复建议 | 投前检查 |
32	
33	---
34	
35	## 2. Claim-Evidence 方法论
36	
37	**核心原则：论文是一个有中心贡献的故事，不是实验的堆砌。**
38	
39	### 2.1 一句话贡献
40	
41	在写任何内容之前，必须能用一句话说清贡献。如果不能，说明还没准备好写论文。
42	
43	### 2.2 Claim-Evidence Map
44	
45	为每个 contribution 建立 claim→evidence 映射表：
46	
47	| Contribution | Claim | Evidence | Table/Figure |
48	|-------------|-------|----------|-------------|
49	| C1: 方法 X 在 Y 上 SOTA | 比所有 baseline 高 ≥2% | 5-seed 平均，p<0.05 | Table 1 |
50	| C2: 消融证明 Z 是关键 | 去掉 Z 后掉 >5% | 消融实验 | Table 2 |
51	| C3: 计算效率 | 比 baseline 快 3× | FLOPs + wall-clock | Figure 3 |
52	
53	**没有直接证据支撑的 claim 必须删除或降级为 discussion。**
54	
55	### 2.3 章节起草顺序
56	
57	```
58	1. Introduction + Experiments（先确定 claim 和 evidence）
59	2. Method（评估问题稳定后再写细节）
60	3. Related Work
61	4. Abstract + Title（核心 claim 定型后最后写）
62	```
63	
64	### 2.4 Quality Gates
65	
66	投稿前必须通过：
67	- [ ] 前两段出现显式 novelty 声明
68	- [ ] 每个 contribution 有可验证的 evidence
69	- [ ] Abstract / Intro / Conclusion 的 claim 一致
70	- [ ] Limitations 真实且技术性诚实
71	- [ ] 审稿人两分钟内能识别 delta
72	
73	---
74	
75	## 3. 引用防幻觉（CRITICAL）
76	
77	**AI 生成引用有 ~40% 错误率。绝对禁止凭记忆写 BibTeX。**
78	
79	### 3.1 黄金法则
80	
81	```
82	IF 无法程序化获取引用:
83	    → 标记 [CITATION NEEDED] 或 \cite{PLACEHOLDER_verify}
84	    → 明确告知用户
85	    → 绝不编造看似合理的引用
86	```
87	
88	### 3.2 五步验证流程
89	
90	```
91	1. SEARCH  → Semantic Scholar API 搜索关键词
92	2. VERIFY  → 至少 2 个来源确认论文存在（S2 + arXiv/CrossRef）
93	3. RETRIEVE → 通过 DOI 获取 BibTeX（程序化，非记忆）
94	4. CHECK   → 确认你引用的 claim 确实出自该论文
95	5. ADD     → 加入 .bib 文件
96	```
97	
98	### 3.3 API 速查
99	
100	| API | 用途 | 限制 |
101	|-----|------|------|
102	| **Semantic Scholar** | ML/AI 论文搜索 | 1 RPS (免费) |
103	| **CrossRef** | DOI → BibTeX | 需 mailto 头 |
104	| **arXiv** | 预印本搜索 | 3s 间隔 |
105	
106	```python
107	# DOI → BibTeX（最可靠的方式）
108	import requests
109	def doi_to_bibtex(doi: str) -> str:
110	    r = requests.get(f"https://doi.org/{doi}",
111	                     headers={"Accept": "application/x-bibtex"})
112	    r.raise_for_status()
113	    return r.text
114	
115	# Semantic Scholar 搜索
116	from semanticscholar import SemanticScholar
117	sch = SemanticScholar()
118	results = sch.search_paper("attention mechanism transformers", limit=5)
119	for p in results:
120	    print(f"{p.title} | DOI: {p.externalIds.get('DOI', 'N/A')}")
121	```
122	
123	### 3.4 引用处理规则
124	
125	| 情况 | 处理 |
126	|------|------|
127	| 找到论文 + DOI + BibTeX | 直接用 |
128	| 找到论文，无 DOI | 用 arXiv BibTeX |
129	| 论文存在但无法获取 BibTeX | 标记 placeholder，告知用户 |
130	| 不确定论文是否存在 | 标记 `[CITATION NEEDED]`，告知用户 |
131	| "我觉得有篇关于 X 的论文" | **绝不引用** — 先搜索或标记 |
132	
133	---
134	
135	## 4. 顶会模板速查
136	
137	### 4.1 ML/AI 会议
138	
139	| 会议 | 页数限制 | 主文件 | 样式文件 | 必须项 |
140	|------|---------|--------|---------|--------|
141	| **NeurIPS** | 9 页 | `main.tex` | `neurips.sty` | Paper Checklist |
142	| **ICML** | 8 页 (+1 camera-ready) | `example_paper.tex` | `icml2026.sty` | Broader Impact |
143	| **ICLR** | 9 页 (+1) | `iclr_conference.tex` | `iclr_conference.sty` | LLM 使用声明 |
144	| **ACL/EMNLP** | 8 页 (long) | `acl_latex.tex` | `acl.sty` | Limitations 必须 |
145	| **AAAI** | 7 页 (+1) | `aaai_template.tex` | `aaai.sty` | 严格样式 |
146	| **COLM** | 9 页 (+1) | `colm_conference.tex` | `colm_conference.sty` | 语言模型聚焦 |
147	
148	### 4.2 系统会议
149	
150	| 会议 | 页数限制 | 模板类型 | 关键要求 |
151	|------|---------|---------|---------|
152	| **OSDI** | 12 页 (+2) | USENIX `usenix.sty` | Research / Operational 双 track |
153	| **NSDI** | 12 页 | USENIX | Introduction 预筛 |
154	| **ASPLOS** | 12 页 | ACM `acmart.cls (sigplan)` | 前 2 页快速评审 |
155	| **SOSP** | 12 页 | ACM `acmart.cls (sigplan)` | 可选 Artifact Evaluation |
156	
157	### 4.3 模板使用原则
158	
159	```bash
160	# 1. 复制整个模板目录（不要只拷 .tex）
161	cp -r templates/neurips2025/ ~/papers/my-paper/
162	
163	# 2. 先编译未修改的模板，确认能跑通
164	latexmk -pdf main.tex
165	
166	# 3. 逐章替换内容，频繁编译
167	```
168	
169	**禁止事项：**
170	- 不要修改 `.sty` 文件
171	- 不要在会议模板间复制 `\usepackage` 行
172	- 不要只复制 `.tex` 而不带 `.sty/.bst`
173	
174	---
175	
176	## 5. 写作规范
177	
178	### 5.1 时间分配（Neel Nanda）
179	
180	花**大致相等**的时间在：
181	1. Abstract
182	2. Introduction
183	3. 图表
184	4. **其余所有内容加起来**
185	
186	审稿人读论文的顺序：标题 → 摘要 → 引言 → 图表 → 也许正文。
187	
188	### 5.2 Abstract 五句法（Sebastian Farquhar）
189	
190	```
191	1. 你做了什么（"We introduce/prove/demonstrate..."）
192	2. 为什么这很难且重要
193	3. 怎么做的（含专业关键词以便检索）
194	4. 有什么证据
195	5. 最惊人的数字/结果
196	```
197	
198	删除一切泛泛的开头：~~"Large language models have achieved remarkable success..."~~
199	
200	### 5.3 句子级清晰度（Gopen & Swan）
201	
202	| 原则 | 规则 |
203	|------|------|
204	| 主谓紧邻 | 不要在主语和动词之间插入长从句 |
205	| 重点在句尾 | 把关键数字/结论放在句末 |
206	| 旧信息在前 | 先放读者已知的内容，再引入新概念 |
207	| 动词表达动作 | "We analyzed" 而非 "We performed an analysis" |
208	
209	### 5.4 常见修改
210	
211	| 问题 | 修复 |
212	|------|------|
213	| Abstract 太泛 | 删第一句（如果它能放在任何 ML 论文前面） |
214	| Introduction 超 1.5 页 | 背景挪到 Related Work |
215	| 实验没有显式 claim | 每个实验前加 "This tests whether..." |
216	| 缺统计显著性 | 加 error bars + 运行次数 + 计算方法 |
217	
218	---
219	
220	## 6. 投稿工程链
221	
222	### 6.1 构建
223	
224	```bash
225	# 推荐：latexmk 一键构建
226	latexmk -pdf -interaction=nonstopmode -halt-on-error main.tex
227	
228	# 手动：需要多次编译
229	pdflatex main.tex && bibtex main && pdflatex main.tex && pdflatex main.tex
230	```
231	
232	### 6.2 Lint + 格式化
233	
234	```bash
235	# Lint: 检查常见 LaTeX 问题
236	chktex main.tex
237	
238	# 格式化: 减少 diff 噪声
239	latexindent -w main.tex
240	```
241	
242	### 6.3 图表格式
243	
244	| 类型 | 格式 | 说明 |
245	|------|------|------|
246	| 矢量图（plot、diagram） | PDF | matplotlib: `plt.savefig('fig.pdf')` |
247	| 照片/heatmap | PNG 600dpi 或 TIFF | 栅格图 |
248	| 表格 | `booktabs` 包 | `\toprule/\midrule/\bottomrule` |
249	
250	```latex
251	\usepackage{booktabs}
252	\begin{tabular}{lcc}
253	\toprule
254	Method & Accuracy $\uparrow$ & Latency $\downarrow$ \\
255	\midrule
256	Baseline & 85.2 & 45ms \\
257	\textbf{Ours} & \textbf{92.1} & 38ms \\
258	\bottomrule
259	\end{tabular}
260	```
261	
262	**图表规范：**
263	- 用色盲友好色板（Okabe-Ito 或 Paul Tol）
264	- 图内不放标题（用 caption）
265	- Caption 独立可理解（不依赖正文）
266	- 最佳值加粗，标注方向符号（↑ 越高越好，↓ 越低越好）
267	
268	### 6.4 投稿打包
269	
270	```bash
271	# 清理辅助文件
272	latexmk -c
273	
274	# 打包投稿
275	zip -r submission.zip main.tex *.sty *.bst *.bib figures/ --exclude='*.aux' --exclude='*.log'
276	```
277	
278	### 6.5 常见失败点
279	
280	| 问题 | 解决 |
281	|------|------|
282	| 图片格式混用导致编译失败 | 统一用 PDF |
283	| 字体未嵌入 | `pdffonts output.pdf` 检查 |
284	| Overfull box 过多 | 关键位置手动调行 |
285	| 引用缺字段 | 检查 DOI/年份/期刊名 |
286	| 超页数 | 用 `\vspace{-Xpt}` 微调，或精简内容 |
287	
288	---
289	
290	## 7. 会议转投
291	
292	当论文被拒或转投其他会议时：
293	
294	### 7.1 ML/AI 会议间转换
295	
296	| 转换 | 页数变化 | 关键调整 |
297	|------|---------|---------|
298	| NeurIPS → ICML | 9→8 | 删 1 页，加 Broader Impact |
299	| ICML → ICLR | 8→9 | 可扩展实验 + LLM 声明 |
300	| NeurIPS → ACL | 9→8 | 按 NLP 惯例重组 + Limitations |
301	| ICLR → AAAI | 9→7 | 大幅精简，严格样式 |
302	
303	### 7.2 转投原则
304	
305	1. **永远用目标模板重新开始** — 复制目标模板，迁移内容，不要合并 preamble
306	2. **只迁移正文内容** — 不复制 `\usepackage`、header/footer 命令
307	3. **根据审稿意见改进** — 但不要在新稿中提及旧投稿（双盲）
308	4. **检查目标会议特殊要求** — checklist、ethics statement、LLM 声明等
309	
310	---
311	
312	## 8. 投前清单
313	
314	### 通用清单
315	
316	- [ ] Abstract/Intro/Conclusion 的 claim 一致
317	- [ ] 每个 contribution 有对应 evidence
318	- [ ] 所有引用已程序化验证（无幻觉引用）
319	- [ ] Error bars + 运行次数 + 统计方法
320	- [ ] Limitations 章节存在且诚实
321	- [ ] 匿名化（双盲审稿）
322	- [ ] 符合页数限制
323	- [ ] 所有图表有自包含 caption
324	- [ ] `.bib` 中无缺失字段
325	- [ ] PDF 编译无 warning
326	
327	### 会议特定
328	
329	| 会议 | 额外要求 |
330	|------|---------|
331	| NeurIPS | 16 项 Paper Checklist（附录，不计页数） |
332	| ICML | Broader Impact Statement |
333	| ICLR | LLM 使用声明 |
334	| ACL/EMNLP | Limitations 章节（必须），Ethics Statement |
335	| AAAI | 严格样式文件合规 |
336	
337	---
338	
339	## 参考资源
340	
341	**写作方法论：**
342	- [Neel Nanda: How to Write ML Papers](https://www.alignmentforum.org/posts/eJGptPbbFPZGLpjsp/) — What/Why/So What 框架
343	- [Farquhar: How to Write ML Papers](https://sebastianfarquhar.com/on-research/2024/11/04/how_to_write_ml_papers/) — 五句法 Abstract
344	- [Gopen & Swan: Science of Scientific Writing](https://cseweb.ucsd.edu/~swanson/papers/science-of-writing.pdf) — 读者预期 7 原则
345	- [Lipton: Heuristics for Scientific Writing](https://www.approximatelycorrect.com/2018/01/29/heuristics-technical-scientific-writing-machine-learning-perspective/) — 用词
346	- [Perez: Easy Paper Writing Tips](https://ethanperez.net/easy-paper-writing-tips/) — 微观清晰度
347	
348	**API：**
349	- [Semantic Scholar](https://api.semanticscholar.org/api-docs/) | [CrossRef](https://www.crossref.org/documentation/) | [arXiv](https://info.arxiv.org/help/api/)
350	
351	**会议官方：**
352	- [NeurIPS](https://neurips.cc/) | [ICML](https://icml.cc/) | [ICLR](https://iclr.cc/) | [ACL](https://www.aclweb.org/) | [AAAI](https://aaai.org/) | [EMNLP](https://2025.emnlp.org/)
353	
````

</details>

<details><summary>Recorded metadata</summary>

````json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "d525a2fc-96e7-4f38-bb43-fbca240321e2",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/agent-ml-research/skills/global/latex-paper.skill.md",
      "content": "---\nname: latex-paper\ndescription: ML 顶会论文 LaTeX 写作全流程——Claim-Evidence 方法论、引用防幻觉、顶会模板速查、投稿工程链、会议转投。写论文/投稿时参考。\nscope: global\ntags:\n- latex\n- paper-writing\n- academic\n- citation\n- submission\nversion: 1\nroles:\n- agent\n- worker\n---\n\n# LaTeX 论文写作全流程\n\nML/AI 顶会论文从草稿到投稿的完整指南。整合 Orchestra Research、VibeSkills、claim2evidence 三方最佳实践。\n\n---\n\n## 1. 工作模式\n\n开始前选择模式：\n\n| 模式 | 说明 | 适用 |\n|------|------|------|\n| **Build** | 从实验笔记/结果/代码生成论文 | 新稿 |\n| **Improve** | 改写已有章节，强化论证 | 修改稿 |\n| **Audit** | 输出风险列表 + 缺失证据 + 修复建议 | 投前检查 |\n\n---\n\n## 2. Claim-Evidence 方法论\n\n**核心原则：论文是一个有中心贡献的故事，不是实验的堆砌。**\n\n### 2.1 一句话贡献\n\n在写任何内容之前，必须能用一句话说清贡献。如果不能，说明还没准备好写论文。\n\n### 2.2 Claim-Evidence Map\n\n为每个 contribution 建立 claim→evidence 映射表：\n\n| Contribution | Claim | Evidence | Table/Figure |\n|-------------|-------|----------|-------------|\n| C1: 方法 X 在 Y 上 SOTA | 比所有 baseline 高 ≥2% | 5-seed 平均，p<0.05 | Table 1 |\n| C2: 消融证明 Z 是关键 | 去掉 Z 后掉 >5% | 消融实验 | Table 2 |\n| C3: 计算效率 | 比 baseline 快 3× | FLOPs + wall-clock | Figure 3 |\n\n**没有直接证据支撑的 claim 必须删除或降级为 discussion。**\n\n### 2.3 章节起草顺序\n\n```\n1. Introduction + Experiments（先确定 claim 和 evidence）\n2. Method（评估问题稳定后再写细节）\n3. Related Work\n4. Abstract + Title（核心 claim 定型后最后写）\n```\n\n### 2.4 Quality Gates\n\n投稿前必须通过：\n- [ ] 前两段出现显式 novelty 声明\n- [ ] 每个 contribution 有可验证的 evidence\n- [ ] Abstract / Intro / Conclusion 的 claim 一致\n- [ ] Limitations 真实且技术性诚实\n- [ ] 审稿人两分钟内能识别 delta\n\n---\n\n## 3. 引用防幻觉（CRITICAL）\n\n**AI 生成引用有 ~40% 错误率。绝对禁止凭记忆写 BibTeX。**\n\n### 3.1 黄金法则\n\n```\nIF 无法程序化获取引用:\n    → 标记 [CITATION NEEDED] 或 \\cite{PLACEHOLDER_verify}\n    → 明确告知用户\n    → 绝不编造看似合理的引用\n```\n\n### 3.2 五步验证流程\n\n```\n1. SEARCH  → Semantic Scholar API 搜索关键词\n2. VERIFY  → 至少 2 个来源确认论文存在（S2 + arXiv/CrossRef）\n3. RETRIEVE → 通过 DOI 获取 BibTeX（程序化，非记忆）\n4. CHECK   → 确认你引用的 claim 确实出自该论文\n5. ADD     → 加入 .bib 文件\n```\n\n### 3.3 API 速查\n\n| API | 用途 | 限制 |\n|-----|------|------|\n| **Semantic Scholar** | ML/AI 论文搜索 | 1 RPS (免费) |\n| **CrossRef** | DOI → BibTeX | 需 mailto 头 |\n| **arXiv** | 预印本搜索 | 3s 间隔 |\n\n```python\n# DOI → BibTeX（最可靠的方式）\nimport requests\ndef doi_to_bibtex(doi: str) -> str:\n    r = requests.get(f\"https://doi.org/{doi}\",\n                     headers={\"Accept\": \"application/x-bibtex\"})\n    r.raise_for_status()\n    return r.text\n\n# Semantic Scholar 搜索\nfrom semanticscholar import SemanticScholar\nsch = SemanticScholar()\nresults = sch.search_paper(\"attention mechanism transformers\", limit=5)\nfor p in results:\n    print(f\"{p.title} | DOI: {p.externalIds.get('DOI', 'N/A')}\")\n```\n\n### 3.4 引用处理规则\n\n| 情况 | 处理 |\n|------|------|\n| 找到论文 + DOI + BibTeX | 直接用 |\n| 找到论文，无 DOI | 用 arXiv BibTeX |\n| 论文存在但无法获取 BibTeX | 标记 placeholder，告知用户 |\n| 不确定论文是否存在 | 标记 `[CITATION NEEDED]`，告知用户 |\n| \"我觉得有篇关于 X 的论文\" | **绝不引用** — 先搜索或标记 |\n\n---\n\n## 4. 顶会模板速查\n\n### 4.1 ML/AI 会议\n\n| 会议 | 页数限制 | 主文件 | 样式文件 | 必须项 |\n|------|---------|--------|---------|--------|\n| **NeurIPS** | 9 页 | `main.tex` | `neurips.sty` | Paper Checklist |\n| **ICML** | 8 页 (+1 camera-ready) | `example_paper.tex` | `icml2026.sty` | Broader Impact |\n| **ICLR** | 9 页 (+1) | `iclr_conference.tex` | `iclr_conference.sty` | LLM 使用声明 |\n| **ACL/EMNLP** | 8 页 (long) | `acl_latex.tex` | `acl.sty` | Limitations 必须 |\n| **AAAI** | 7 页 (+1) | `aaai_template.tex` | `aaai.sty` | 严格样式 |\n| **COLM** | 9 页 (+1) | `colm_conference.tex` | `colm_conference.sty` | 语言模型聚焦 |\n\n### 4.2 系统会议\n\n| 会议 | 页数限制 | 模板类型 | 关键要求 |\n|------|---------|---------|---------|\n| **OSDI** | 12 页 (+2) | USENIX `usenix.sty` | Research / Operational 双 track |\n| **NSDI** | 12 页 | USENIX | Introduction 预筛 |\n| **ASPLOS** | 12 页 | ACM `acmart.cls (sigplan)` | 前 2 页快速评审 |\n| **SOSP** | 12 页 | ACM `acmart.cls (sigplan)` | 可选 Artifact Evaluation |\n\n### 4.3 模板使用原则\n\n```bash\n# 1. 复制整个模板目录（不要只拷 .tex）\ncp -r templates/neurips2025/ ~/papers/my-paper/\n\n# 2. 先编译未修改的模板，确认能跑通\nlatexmk -pdf main.tex\n\n# 3. 逐章替换内容，频繁编译\n```\n\n**禁止事项：**\n- 不要修改 `.sty` 文件\n- 不要在会议模板间复制 `\\usepackage` 行\n- 不要只复制 `.tex` 而不带 `.sty/.bst`\n\n---\n\n## 5. 写作规范\n\n### 5.1 时间分配（Neel Nanda）\n\n花**大致相等**的时间在：\n1. Abstract\n2. Introduction\n3. 图表\n4. **其余所有内容加起来**\n\n审稿人读论文的顺序：标题 → 摘要 → 引言 → 图表 → 也许正文。\n\n### 5.2 Abstract 五句法（Sebastian Farquhar）\n\n```\n1. 你做了什么（\"We introduce/prove/demonstrate...\"）\n2. 为什么这很难且重要\n3. 怎么做的（含专业关键词以便检索）\n4. 有什么证据\n5. 最惊人的数字/结果\n```\n\n删除一切泛泛的开头：~~\"Large language models have achieved remarkable success...\"~~\n\n### 5.3 句子级清晰度（Gopen & Swan）\n\n| 原则 | 规则 |\n|------|------|\n| 主谓紧邻 | 不要在主语和动词之间插入长从句 |\n| 重点在句尾 | 把关键数字/结论放在句末 |\n| 旧信息在前 | 先放读者已知的内容，再引入新概念 |\n| 动词表达动作 | \"We analyzed\" 而非 \"We performed an analysis\" |\n\n### 5.4 常见修改\n\n| 问题 | 修复 |\n|------|------|\n| Abstract 太泛 | 删第一句（如果它能放在任何 ML 论文前面） |\n| Introduction 超 1.5 页 | 背景挪到 Related Work |\n| 实验没有显式 claim | 每个实验前加 \"This tests whether...\" |\n| 缺统计显著性 | 加 error bars + 运行次数 + 计算方法 |\n\n---\n\n## 6. 投稿工程链\n\n### 6.1 构建\n\n```bash\n# 推荐：latexmk 一键构建\nlatexmk -pdf -interaction=nonstopmode -halt-on-error main.tex\n\n# 手动：需要多次编译\npdflatex main.tex && bibtex main && pdflatex main.tex && pdflatex main.tex\n```\n\n### 6.2 Lint + 格式化\n\n```bash\n# Lint: 检查常见 LaTeX 问题\nchktex main.tex\n\n# 格式化: 减少 diff 噪声\nlatexindent -w main.tex\n```\n\n### 6.3 图表格式\n\n| 类型 | 格式 | 说明 |\n|------|------|------|\n| 矢量图（plot、diagram） | PDF | matplotlib: `plt.savefig('fig.pdf')` |\n| 照片/heatmap | PNG 600dpi 或 TIFF | 栅格图 |\n| 表格 | `booktabs` 包 | `\\toprule/\\midrule/\\bottomrule` |\n\n```latex\n\\usepackage{booktabs}\n\\begin{tabular}{lcc}\n\\toprule\nMethod & Accuracy $\\uparrow$ & Latency $\\downarrow$ \\\\\n\\midrule\nBaseline & 85.2 & 45ms \\\\\n\\textbf{Ours} & \\textbf{92.1} & 38ms \\\\\n\\bottomrule\n\\end{tabular}\n```\n\n**图表规范：**\n- 用色盲友好色板（Okabe-Ito 或 Paul Tol）\n- 图内不放标题（用 caption）\n- Caption 独立可理解（不依赖正文）\n- 最佳值加粗，标注方向符号（↑ 越高越好，↓ 越低越好）\n\n### 6.4 投稿打包\n\n```bash\n# 清理辅助文件\nlatexmk -c\n\n# 打包投稿\nzip -r submission.zip main.tex *.sty *.bst *.bib figures/ --exclude='*.aux' --exclude='*.log'\n```\n\n### 6.5 常见失败点\n\n| 问题 | 解决 |\n|------|------|\n| 图片格式混用导致编译失败 | 统一用 PDF |\n| 字体未嵌入 | `pdffonts output.pdf` 检查 |\n| Overfull box 过多 | 关键位置手动调行 |\n| 引用缺字段 | 检查 DOI/年份/期刊名 |\n| 超页数 | 用 `\\vspace{-Xpt}` 微调，或精简内容 |\n\n---\n\n## 7. 会议转投\n\n当论文被拒或转投其他会议时：\n\n### 7.1 ML/AI 会议间转换\n\n| 转换 | 页数变化 | 关键调整 |\n|------|---------|---------|\n| NeurIPS → ICML | 9→8 | 删 1 页，加 Broader Impact |\n| ICML → ICLR | 8→9 | 可扩展实验 + LLM 声明 |\n| NeurIPS → ACL | 9→8 | 按 NLP 惯例重组 + Limitations |\n| ICLR → AAAI | 9→7 | 大幅精简，严格样式 |\n\n### 7.2 转投原则\n\n1. **永远用目标模板重新开始** — 复制目标模板，迁移内容，不要合并 preamble\n2. **只迁移正文内容** — 不复制 `\\usepackage`、header/footer 命令\n3. **根据审稿意见改进** — 但不要在新稿中提及旧投稿（双盲）\n4. **检查目标会议特殊要求** — checklist、ethics statement、LLM 声明等\n\n---\n\n## 8. 投前清单\n\n### 通用清单\n\n- [ ] Abstract/Intro/Conclusion 的 claim 一致\n- [ ] 每个 contribution 有对应 evidence\n- [ ] 所有引用已程序化验证（无幻觉引用）\n- [ ] Error bars + 运行次数 + 统计方法\n- [ ] Limitations 章节存在且诚实\n- [ ] 匿名化（双盲审稿）\n- [ ] 符合页数限制\n- [ ] 所有图表有自包含 caption\n- [ ] `.bib` 中无缺失字段\n- [ ] PDF 编译无 warning\n\n### 会议特定\n\n| 会议 | 额外要求 |\n|------|---------|\n| NeurIPS | 16 项 Paper Checklist（附录，不计页数） |\n| ICML | Broader Impact Statement |\n| ICLR | LLM 使用声明 |\n| ACL/EMNLP | Limitations 章节（必须），Ethics Statement |\n| AAAI | 严格样式文件合规 |\n\n---\n\n## 参考资源\n\n**写作方法论：**\n- [Neel Nanda: How to Write ML Papers](https://www.alignmentforum.org/posts/eJGptPbbFPZGLpjsp/) — What/Why/So What 框架\n- [Farquhar: How to Write ML Papers](https://sebastianfarquhar.com/on-research/2024/11/04/how_to_write_ml_papers/) — 五句法 Abstract\n- [Gopen & Swan: Science of Scientific Writing](https://cseweb.ucsd.edu/~swanson/papers/science-of-writing.pdf) — 读者预期 7 原则\n- [Lipton: Heuristics for Scientific Writing](https://www.approximatelycorrect.com/2018/01/29/heuristics-technical-scientific-writing-machine-learning-perspective/) — 用词\n- [Perez: Easy Paper Writing Tips](https://ethanperez.net/easy-paper-writing-tips/) — 微观清晰度\n\n**API：**\n- [Semantic Scholar](https://api.semanticscholar.org/api-docs/) | [CrossRef](https://www.crossref.org/documentation/) | [arXiv](https://info.arxiv.org/help/api/)\n\n**会议官方：**\n- [NeurIPS](https://neurips.cc/) | [ICML](https://icml.cc/) | [ICLR](https://iclr.cc/) | [ACL](https://www.aclweb.org/) | [AAAI](https://aaai.org/) | [EMNLP](https://2025.emnlp.org/)\n",
      "numLines": 353,
      "startLine": 1,
      "totalLines": 353
    }
  }
}
````

</details>

---

### Tool call

_source line 9_

<details open><summary>🔧 Tool call — Read · `toolu_01BamswReqRpjx3easwr5Sf7`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/method.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "1f949a1c-b74c-4396-86bf-a1741dd4c3c7",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014RWY3wTcTogP8McSwAfMCh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12604,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12604
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

_source line 10 · 2026-05-21T05:42:30.947Z_

<details><summary>↩ Tool result · `toolu_01BamswReqRpjx3easwr5Sf7`</summary>

```text
1	\section{EC-HTE: Error-Corrected Heterogeneous Treatment Effects}
2	\label{sec:method}
3	
4	EC-HTE corrects subgroup-level misclassification bias in three stages: estimate per-subgroup confusion matrices via hierarchical Bayes, invert them to correct observed outcome moments, and propagate correction uncertainty into downstream causal estimators.
5	
6	\subsection{Hierarchical Bayes Confusion Matrix Estimation}
7	
8	We place a Dirichlet-Multinomial hierarchical model over the confusion matrices $\{C_s\}_{s=1}^K$.
9	For each subgroup $s$, row $j$ of $C_s$ has a Dirichlet prior $\text{Dir}(\alpha_0 \cdot \mathbf{e}_j)$, where $\mathbf{e}_j$ is the $j$-th standard basis vector and $\alpha_0 > 0$ is a shared concentration parameter.
10	A $\text{Gamma}(2, 1)$ hyperprior on $\alpha_0$ controls the strength of partial pooling across subgroups: large $\alpha_0$ pulls subgroup estimates toward the identity matrix (low error), while small $\alpha_0$ allows subgroup-specific rates to dominate.
11	This partial pooling implements a James-Stein shrinkage effect, borrowing strength across subgroups to reduce variance for small subgroups while preserving heterogeneity where the data support it.
12	
13	Posterior inference uses a Gibbs sampler with 4 chains, 4000 iterations (2000 warmup).
14	We require convergence diagnostics $\hat{R} < 1.01$ and effective sample size $\text{ESS} > 845$ for all parameters before accepting estimates.
15	In practice, all runs achieve $\hat{R} < 1.0034$ and $\text{ESS} > 1618$, well within these thresholds.
16	HB estimation outperforms stratified MLE in 87.5\% of configurations (21 of 24) across the experimental grid (Section~\ref{sec:ec_hte_eval}), with the largest gains when $n_{\text{expert}} / K < 100$.
17	The advantage requires at least $n_{\text{expert}} / K \geq 25$ per subgroup; below this threshold, stratified MLE is preferred because the hierarchical model lacks sufficient observations for stable shrinkage.
18	At $n_{\text{expert}} \geq 1000$, HB and stratified MLE converge to within 0.5\% on all metrics.
19	Sensitivity analysis shows $<$5\% RMSE variation under 2$\times$ hyperprior perturbation, confirming that results are not driven by prior specification.
20	
21	\subsection{Subgroup-Stratified Correction}
22	
23	Given posterior mean confusion matrices $\hat{C}_s$, we correct observed outcome moments per subgroup by matrix inversion:
24	\begin{equation}
25	\tilde{\boldsymbol{\mu}}_s = \hat{C}_s^{-1} \cdot \hat{\boldsymbol{\mu}}_s,
26	\end{equation}
27	where $\hat{\boldsymbol{\mu}}_s = [\hat{\tau}_{\text{obs}}(0, s),\, \hat{\tau}_{\text{obs}}(1, s)]^\top$ collects the observed conditional outcome moments in subgroup $s$.
28	This requires $\det(\hat{C}_s) \neq 0$ for all $s$, which holds under assumption~(A4) ($\pi_s \neq 0.5$) but may fail in finite samples when error rates approach degeneracy.
29	In practice, Laplace smoothing of the confusion matrix counts ensures finite-sample invertibility.
30	We impose a singularity guard: if the condition number $\kappa(\hat{C}_s) > 100$, subgroup $s$ falls back to global correction $\bar{C}^{-1}$ rather than risk numerical instability from near-singular inversion.
31	
32	The contrast with global correction is direct.
33	Global correction applies $\bar{C}^{-1}$ uniformly to all subgroups, introducing the $\delta_s \cdot \Delta\tau$ bias identified in Theorem~\ref{thm:bias_identity}.
34	Subgroup-stratified correction eliminates this bias by matching each subgroup's correction to its own misclassification structure, at the cost of higher variance from estimating $K$ separate confusion matrices (Section~\ref{sec:budget}).
35	
36	\subsection{Variance-Adjusted CausalForest}
37	
38	For heterogeneous treatment effect estimation, we feed corrected covariates into CausalForestDML~\cite{wager2018causal} with honest splitting.
39	The forest produces per-observation standard error estimates $\text{se}_i$.
40	To account for confusion matrix correction, we propagate uncertainty through the inverse mapping:
41	\begin{equation}
42	\text{se}_{\text{corrected},i} = \sqrt{\text{diag}\!\left(\hat{C}_{S_i}^{-1}\, \text{diag}(\text{se}_i^2)\, \hat{C}_{S_i}^{-\top}\right)}.
43	\end{equation}
44	This is a plug-in approach: the standard errors reflect outcome variance conditional on $\hat{C}_s$ but do not propagate uncertainty from the confusion matrix estimation itself.
45	At $n_{\text{expert}} \geq 100$, the plug-in approximation is reasonable because confusion matrix estimation variance is small relative to outcome variance.
46	Below this threshold, the standard errors may understate total uncertainty; this limitation is discussed further in the Limitations section.
47	
48	\paragraph{Diagnostic criterion.}
49	As a practical corollary of Theorem~\ref{thm:bias_identity}, the product $|\Delta\pi \times \Delta\tau|$ serves as a computable diagnostic for whether global correction will harm specific subgroups.
50	The bias decomposition identity predicts that bias is proportional to this product, and both quantities can be estimated from a small pilot sample ($n_{\text{expert}} \geq 50$ suffices).
51	A threshold calibrated via leave-one-out cross-validation achieves AUC~=~0.833 at the subgroup level (Section~\ref{sec:diagnostic}).
52	The recommended workflow is: compute the diagnostic from pilot data; if any subgroup shows a large product, apply EC-HTE; if the product is uniformly small, global correction suffices.
53	
54	\paragraph{Composition with PPCI.}
55	EC-HTE corrects structured covariate misclassification through $\hat{C}_s^{-1}$ inversion but cannot address outcome-level measurement error.
56	PPCI~\cite{sui2026ppci} corrects residual outcome bias using a debiasing estimator but assumes correct covariate labels.
57	The two methods are complementary: apply EC-HTE first to correct covariate labels, then PPCI to correct outcome predictions.
58	Neither is redundant with the other: EC-HTE alone cannot fix outcome error, while PPCI alone incurs higher variance for covariate error.
59	Under both error types simultaneously, the composition reduces $|\text{bias}|$ from 0.179 to below 0.01 (Section~\ref{sec:ppci}).
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "25c77501-b190-4fe7-ad4e-6e8e9c963c29",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/method.tex",
      "content": "\\section{EC-HTE: Error-Corrected Heterogeneous Treatment Effects}\n\\label{sec:method}\n\nEC-HTE corrects subgroup-level misclassification bias in three stages: estimate per-subgroup confusion matrices via hierarchical Bayes, invert them to correct observed outcome moments, and propagate correction uncertainty into downstream causal estimators.\n\n\\subsection{Hierarchical Bayes Confusion Matrix Estimation}\n\nWe place a Dirichlet-Multinomial hierarchical model over the confusion matrices $\\{C_s\\}_{s=1}^K$.\nFor each subgroup $s$, row $j$ of $C_s$ has a Dirichlet prior $\\text{Dir}(\\alpha_0 \\cdot \\mathbf{e}_j)$, where $\\mathbf{e}_j$ is the $j$-th standard basis vector and $\\alpha_0 > 0$ is a shared concentration parameter.\nA $\\text{Gamma}(2, 1)$ hyperprior on $\\alpha_0$ controls the strength of partial pooling across subgroups: large $\\alpha_0$ pulls subgroup estimates toward the identity matrix (low error), while small $\\alpha_0$ allows subgroup-specific rates to dominate.\nThis partial pooling implements a James-Stein shrinkage effect, borrowing strength across subgroups to reduce variance for small subgroups while preserving heterogeneity where the data support it.\n\nPosterior inference uses a Gibbs sampler with 4 chains, 4000 iterations (2000 warmup).\nWe require convergence diagnostics $\\hat{R} < 1.01$ and effective sample size $\\text{ESS} > 845$ for all parameters before accepting estimates.\nIn practice, all runs achieve $\\hat{R} < 1.0034$ and $\\text{ESS} > 1618$, well within these thresholds.\nHB estimation outperforms stratified MLE in 87.5\\% of configurations (21 of 24) across the experimental grid (Section~\\ref{sec:ec_hte_eval}), with the largest gains when $n_{\\text{expert}} / K < 100$.\nThe advantage requires at least $n_{\\text{expert}} / K \\geq 25$ per subgroup; below this threshold, stratified MLE is preferred because the hierarchical model lacks sufficient observations for stable shrinkage.\nAt $n_{\\text{expert}} \\geq 1000$, HB and stratified MLE converge to within 0.5\\% on all metrics.\nSensitivity analysis shows $<$5\\% RMSE variation under 2$\\times$ hyperprior perturbation, confirming that results are not driven by prior specification.\n\n\\subsection{Subgroup-Stratified Correction}\n\nGiven posterior mean confusion matrices $\\hat{C}_s$, we correct observed outcome moments per subgroup by matrix inversion:\n\\begin{equation}\n\\tilde{\\boldsymbol{\\mu}}_s = \\hat{C}_s^{-1} \\cdot \\hat{\\boldsymbol{\\mu}}_s,\n\\end{equation}\nwhere $\\hat{\\boldsymbol{\\mu}}_s = [\\hat{\\tau}_{\\text{obs}}(0, s),\\, \\hat{\\tau}_{\\text{obs}}(1, s)]^\\top$ collects the observed conditional outcome moments in subgroup $s$.\nThis requires $\\det(\\hat{C}_s) \\neq 0$ for all $s$, which holds under assumption~(A4) ($\\pi_s \\neq 0.5$) but may fail in finite samples when error rates approach degeneracy.\nIn practice, Laplace smoothing of the confusion matrix counts ensures finite-sample invertibility.\nWe impose a singularity guard: if the condition number $\\kappa(\\hat{C}_s) > 100$, subgroup $s$ falls back to global correction $\\bar{C}^{-1}$ rather than risk numerical instability from near-singular inversion.\n\nThe contrast with global correction is direct.\nGlobal correction applies $\\bar{C}^{-1}$ uniformly to all subgroups, introducing the $\\delta_s \\cdot \\Delta\\tau$ bias identified in Theorem~\\ref{thm:bias_identity}.\nSubgroup-stratified correction eliminates this bias by matching each subgroup's correction to its own misclassification structure, at the cost of higher variance from estimating $K$ separate confusion matrices (Section~\\ref{sec:budget}).\n\n\\subsection{Variance-Adjusted CausalForest}\n\nFor heterogeneous treatment effect estimation, we feed corrected covariates into CausalForestDML~\\cite{wager2018causal} with honest splitting.\nThe forest produces per-observation standard error estimates $\\text{se}_i$.\nTo account for confusion matrix correction, we propagate uncertainty through the inverse mapping:\n\\begin{equation}\n\\text{se}_{\\text{corrected},i} = \\sqrt{\\text{diag}\\!\\left(\\hat{C}_{S_i}^{-1}\\, \\text{diag}(\\text{se}_i^2)\\, \\hat{C}_{S_i}^{-\\top}\\right)}.\n\\end{equation}\nThis is a plug-in approach: the standard errors reflect outcome variance conditional on $\\hat{C}_s$ but do not propagate uncertainty from the confusion matrix estimation itself.\nAt $n_{\\text{expert}} \\geq 100$, the plug-in approximation is reasonable because confusion matrix estimation variance is small relative to outcome variance.\nBelow this threshold, the standard errors may understate total uncertainty; this limitation is discussed further in the Limitations section.\n\n\\paragraph{Diagnostic criterion.}\nAs a practical corollary of Theorem~\\ref{thm:bias_identity}, the product $|\\Delta\\pi \\times \\Delta\\tau|$ serves as a computable diagnostic for whether global correction will harm specific subgroups.\nThe bias decomposition identity predicts that bias is proportional to this product, and both quantities can be estimated from a small pilot sample ($n_{\\text{expert}} \\geq 50$ suffices).\nA threshold calibrated via leave-one-out cross-validation achieves AUC~=~0.833 at the subgroup level (Section~\\ref{sec:diagnostic}).\nThe recommended workflow is: compute the diagnostic from pilot data; if any subgroup shows a large product, apply EC-HTE; if the product is uniformly small, global correction suffices.\n\n\\paragraph{Composition with PPCI.}\nEC-HTE corrects structured covariate misclassification through $\\hat{C}_s^{-1}$ inversion but cannot address outcome-level measurement error.\nPPCI~\\cite{sui2026ppci} corrects residual outcome bias using a debiasing estimator but assumes correct covariate labels.\nThe two methods are complementary: apply EC-HTE first to correct covariate labels, then PPCI to correct outcome predictions.\nNeither is redundant with the other: EC-HTE alone cannot fix outcome error, while PPCI alone incurs higher variance for covariate error.\nUnder both error types simultaneously, the composition reduces $|\\text{bias}|$ from 0.179 to below 0.01 (Section~\\ref{sec:ppci}).",
      "numLines": 59,
      "startLine": 1,
      "totalLines": 59
    }
  }
}
```

</details>

---

### Tool call

_source line 11_

<details open><summary>🔧 Tool call — Read · `toolu_01VUJ3571iVy1fKEJNmVPgod`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "6cdb453e-fdff-4ecc-98ce-b8546f48224d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_014RWY3wTcTogP8McSwAfMCh",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12604,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12604
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

_source line 12 · 2026-05-21T05:42:31.367Z_

<details><summary>↩ Tool result · `toolu_01VUJ3571iVy1fKEJNmVPgod`</summary>

```text
1	\section{Experiments}
2	
3	\subsection{Experimental Setup and Data Generation}
4	
5	\subsubsection{Synthetic DGP}
6	
7	We generate data from a controlled data-generating process (DGP) that separates the effect of subgroup-level misclassification heterogeneity from other confounders.
8	For each observation $i$, the potential outcome under treatment $t$ is
9	\begin{equation}
10	Y_i(t) = \alpha + \tau(Z_i) \cdot t + \beta X_i + \varepsilon_i, \quad \varepsilon_i \sim \mathcal{N}(0,1),
11	\end{equation}
12	where $T_i \sim \text{Bernoulli}(0.5)$ simulates a randomized controlled trial, and $Z_i \in \{0, \ldots, K{-}1\}$ is the true effect modifier with $K \in \{2, 4\}$ subgroups.
13	The conditional average treatment effect (CATE) $\tau(Z{=}z)$ varies across subgroups with controlled heterogeneity $\Delta\tau = \max_z \tau(z) - \min_z \tau(z)$.
14	Misclassification is injected through subgroup-specific symmetric confusion matrices $C_s$: the observed label $\hat{Z}_i$ is drawn as $\hat{Z}_i \sim \text{Multinomial}(C_{S_i})$, where each subgroup $s$ has error rate $\pi_s$ and $\Delta\pi = \max_s \pi_s - \min_s \pi_s$ controls heterogeneity.
15	We fix $N{=}5000$ observations and vary $n_{\text{expert}} \in \{50, 100, 250, 500, 1000, 2000\}$ (the number of expert-labeled observations used to estimate confusion matrices).
16	Each configuration is repeated for 100 Monte Carlo runs.
17	
18	\subsubsection{Semi-synthetic DGP (TweetEval)}
19	
20	To test EC-HTE under realistic conditions, we construct a semi-synthetic DGP from the TweetEval sentiment corpus~\cite{barbieri2020tweeteval}, sampling $N{=}5000$ tweets per run from a pool of 57{,}899.
21	Four subgroups are defined by crossing two binary text features: presence of hashtags (\texttt{has\_hashtag}) and text length relative to the median (\texttt{text\_length\_bin}).
22	This yields unbalanced subgroup proportions (S0: 39\%, S1: 38\%, S2: 12\%, S3: 11\%).
23	The effect modifier is $Z{=}1$ if the true sentiment is positive ($P(Z{=}1) \approx 35\%$), and $Z{=}0$ otherwise.
24	We set subgroup-specific misclassification rates $\pi_{S0}{=}0.05$, $\pi_{S1}{=}0.10$, $\pi_{S2}{=}0.15$, $\pi_{S3}{=}0.25$ in the extreme regime, reflecting empirical evidence that hashtag-heavy text degrades LLM classifier accuracy~\cite{ashwin2025bias}.
25	The outcome model is
26	\begin{equation}
27	Y_i = 1.0 + \tau(Z_i, S_i) \cdot T_i + 0.3 \cdot \text{len}_i + 0.2 \cdot \text{mention}_i + \varepsilon_i,
28	\end{equation}
29	where $\tau(Z{=}1, S) \in \{0.5, 0.4, 0.3, 0.2\}$ for S0--S3 and $\tau(Z{=}0) = 0.1$ is the baseline effect.
30	
31	\paragraph{Baselines and metrics.}
32	We compare: (1) \textit{Naive} (no correction), (2) \textit{Global} (pooled confusion matrix), (3) \textit{Stratified MLE} (per-subgroup MLE without pooling), (4) \textit{HB EC-HTE} (our hierarchical Bayes estimator), (5) \textit{PPCI}~\cite{sui2026ppci}, and (6) \textit{EC-HTE+PPCI} (our combined method).
33	For the CausalForest estimator~\cite{wager2018causal}, we also compare naive, global, and EC-HTE variants.
34	Primary metrics are absolute bias $|\text{bias}|$, root mean squared error (RMSE), and 95\% confidence interval coverage, all averaged across subgroups and 100 MC runs.
35	
36	\subsection{Bias Mechanism Verification}
37	\label{sec:bias_mechanism}
38	
39	The bias decomposition identity (Theorem~\ref{thm:bias_identity}) predicts that global correction introduces bias proportional to $\Delta\pi \times \Delta\tau$ at the subgroup level.
40	We verify this identity empirically across 520 configurations spanning $K \in \{2,4\}$, two misclassification regimes, and six expert budget levels.
41	Regressing observed subgroup bias on the predicted $\Delta\pi \times \Delta\tau$ product yields $R^2 = 0.994$ for $K{=}2$ and $R^2 = 0.974$ for $K{=}4$; the residual variance reflects MC sampling noise rather than model misspecification, since Theorem~\ref{thm:bias_identity} is an exact identity at the population level.
42	In 50\% of configurations (260/520, excluding $\Delta_c{=}0$ rows where bias is zero by construction), global correction produces larger absolute bias than the naive estimator.
43	The damage concentrates in low-$\pi$ subgroups: among subgroups where $\pi_s < \bar{\pi}$, global correction increases bias in 84.6\% of cases.
44	Maximum observed amplification reaches 2.86$\times$ (K=2) and 2.41$\times$ (K=4) relative to the naive estimator.
45	Figure~\ref{fig:heatmap} visualizes the $\Delta\pi \times \Delta\tau$ amplification surface across the parameter grid.
46	
47	\subsection{EC-HTE Evaluation}
48	\label{sec:ec_hte_eval}
49	
50	Table~\ref{tab:main_results} presents the main results across representative configurations.
51	In the synthetic DGP with $K{=}2$ subgroups and extreme misclassification heterogeneity, HB EC-HTE reduces $|\text{bias}|$ from 0.059 (global) to 0.011 (a 5.4$\times$ reduction) while maintaining nominal coverage (0.95) and comparable RMSE (0.093 vs.\ 0.099).
52	The advantage persists at $K{=}4$: EC-HTE achieves $|\text{bias}|{=}0.009$ versus 0.056 for global (6.2$\times$ reduction), though with a small RMSE penalty (0.127 vs.\ 0.125).
53	Under moderate heterogeneity ($K{=}2$), global correction already achieves low bias (0.009), and EC-HTE provides negligible improvement (0.005) at the cost of slightly higher RMSE (0.075 vs.\ 0.074).
54	This illustrates the conditional nature of EC-HTE's advantage: when $\Delta\pi$ is small, the variance cost of stratification is not offset by bias reduction.
55	
56	In the semi-synthetic TweetEval experiment, the pattern shifts.
57	Global correction achieves the lowest $|\text{bias}|$ (0.023) among non-oracle methods, while HB EC-HTE attains 0.027 with substantially higher RMSE (0.225 vs.\ 0.124).
58	This is consistent with moderate $\Delta\pi{=}0.20$ and the high-error subgroups (S2, S3) comprising only 23\% of data: the bias reduction from stratification is marginal while the variance cost of four per-subgroup confusion matrices is substantial.
59	HB EC-HTE does improve over stratified MLE (RMSE 0.225 vs.\ 0.248), confirming that partial pooling helps, but the improvement is insufficient to overcome the structural variance from unbalanced subgroup sizes.
60	At $n_{\text{expert}} \geq 250$, HB and MLE converge to within 5\% on all metrics.
61	
62	\paragraph{CausalForest K-dependence.}
63	When the downstream estimator is a CausalForest~\cite{wager2018causal} rather than difference-in-means, the bias mechanism operates with amplified magnitude.
64	At $K{=}4$/extreme/$n{=}500$, EC-HTE Forest reduces $|\text{bias}|$ from 0.191 (global) to 0.040, a 4.8$\times$ improvement with lower RMSE (0.224 vs.\ 0.244) and dramatically better coverage (0.91 vs.\ 0.58).
65	The debiasing-hurts phenomenon intensifies: global correction amplifies naive bias by up to 5.9$\times$ in the worst subgroup (compared to 2.41$\times$ for difference-in-means), because the forest's sensitivity to covariate noise magnifies the effect of label errors.
66	At $K{=}2$/$n{=}500$, EC-HTE Forest achieves near-zero bias (0.004--0.013 across subgroups) versus 0.033--0.109 for global, with coverage of 0.91 compared to 0.58 for the global variant.
67	At $K{=}4$, the per-subgroup range widens to 0.002--0.068 while coverage remains above 0.80.
68	However, this comes at a variance cost: at $K{=}4$/$n{=}100$, EC-HTE Forest RMSE reaches 1.43 (3.5$\times$ naive), underscoring the budget guidelines in Section~\ref{sec:budget}.
69	
70	\begin{table*}[t]
71	\centering
72	\caption{Main results across synthetic (difference-in-means and CausalForest) and semi-synthetic configurations. $|\text{Bias}|$ and RMSE are averaged over subgroups, $z$-levels, and 100 MC runs. Bold marks lowest $|\text{bias}|$ per block. $^\dagger$RMSE exceeds Global in this configuration, reflecting the variance cost of stratification.}
73	\label{tab:main_results}
74	\small
75	\begin{tabular}{ll ccc}
76	\toprule
77	Configuration & Method & $|\text{Bias}| \downarrow$ & RMSE $\downarrow$ & Coverage \\
78	\midrule
79	\multirow{4}{*}{\shortstack[l]{Synthetic DIM\\$K{=}2$, extreme, $n{=}250$}}
80	 & Naive & 0.058 & 0.090 & 0.82 \\
81	 & Global & 0.059 & 0.099 & 0.87 \\
82	 & Strat.\ MLE & 0.012 & 0.094 & 0.95 \\
83	 & HB EC-HTE & \textbf{0.011} & 0.093 & 0.95 \\
84	\midrule
85	\multirow{4}{*}{\shortstack[l]{Synthetic DIM\\$K{=}2$, moderate, $n{=}250$}}
86	 & Naive & 0.018 & 0.064 & 0.95 \\
87	 & Global & 0.009 & 0.074 & 0.96 \\
88	 & Strat.\ MLE & \textbf{0.005} & 0.075$^\dagger$ & 0.97 \\
89	 & HB EC-HTE & \textbf{0.005} & 0.075$^\dagger$ & 0.97 \\
90	\midrule
91	\multirow{4}{*}{\shortstack[l]{Synthetic DIM\\$K{=}4$, extreme, $n{=}500$}}
92	 & Naive & 0.062 & 0.113 & 0.88 \\
93	 & Global & 0.056 & 0.125 & 0.91 \\
94	 & Strat.\ MLE & 0.010 & 0.127$^\dagger$ & 0.95 \\
95	 & HB EC-HTE & \textbf{0.009} & 0.127$^\dagger$ & 0.95 \\
96	\midrule
97	\multirow{3}{*}{\shortstack[l]{Synthetic CausalForest\\$K{=}4$, extreme, $n{=}500$}}
98	 & Naive & 0.208 & 0.231 & 0.44 \\
99	 & Global & 0.191 & 0.244 & 0.58 \\
100	 & EC-HTE Forest & \textbf{0.040} & 0.224 & 0.91 \\
101	\midrule
102	\multirow{4}{*}{\shortstack[l]{Semi-synthetic\\TweetEval, extreme, $n{=}250$}}
103	 & Naive & 0.027 & 0.103 & 0.93 \\
104	 & Global & \textbf{0.023} & 0.124 & 0.92 \\
105	 & Strat.\ MLE & 0.032 & 0.248$^\dagger$ & 0.91 \\
106	 & HB EC-HTE & 0.027 & 0.225$^\dagger$ & 0.91 \\
107	\bottomrule
108	\end{tabular}
109	\end{table*}
110	
111	\subsection{Diagnostic Criterion}
112	\label{sec:diagnostic}
113	
114	As a practical corollary of Theorem~\ref{thm:bias_identity}, the $\Delta\pi \times \Delta\tau$ product provides a computable diagnostic for predicting when global correction will fail.
115	Using leave-one-out cross-validation at the subgroup level, a threshold classifier on $|\Delta\pi \times \Delta\tau|$ achieves AUC = 0.833 for predicting whether global correction increases bias relative to the naive estimator.
116	The Pearson correlation between the signed product and the observed bias ratio is $r = 0.86$.
117	At the setting level (averaging across subgroups within a configuration), the diagnostic has AUC = 0.49, which is no better than random.
118	This asymmetry arises because global correction redistributes bias across subgroups (benefiting high-$\pi$ subgroups at the expense of low-$\pi$ ones) rather than increasing total bias uniformly.
119	In practice, the diagnostic enables researchers to identify vulnerable subgroups before committing to a correction strategy: if any subgroup has $\pi_s \ll \bar{\pi}$ and $\tau(z)$ varies across $z$-levels, global correction should be avoided.
120	Figure~\ref{fig:roc} shows the ROC curve and the correlation scatter plot.
121	
122	\subsection{Expert Budget Analysis}
123	\label{sec:budget}
124	
125	The crossover point at which EC-HTE achieves lower RMSE than global correction depends on $K$ and $\Delta\pi$.
126	For $K{=}2$/extreme, the crossover occurs at $n_{\text{expert}} = 250$: below this threshold, the variance cost of estimating per-subgroup confusion matrices exceeds the bias reduction.
127	For $K{=}4$/extreme, the crossover shifts to $n_{\text{expert}} = 1000$ because four subgroups require more expert labels to achieve precise confusion matrix estimates.
128	Under moderate heterogeneity ($K{=}2$), EC-HTE never achieves lower RMSE than global at any budget, because global correction already produces low bias ($|\text{bias}|{<}0.01$) in this regime.
129	Within the EC-HTE family, HB partial pooling improves over stratified MLE in 21 of 24 budget-regime configurations overall, with the largest gains at small $n_{\text{expert}}$ in $K{=}4$ settings (+42.4\% RMSE improvement for the hardest subgroup).
130	The two estimators converge by $n_{\text{expert}} \geq 1000$ ($<$0.5\% difference).
131	Figure~\ref{fig:budget} shows the crossover curves across the full budget range.
132	
133	\subsection{PPCI Complementarity}
134	\label{sec:ppci}
135	
136	EC-HTE corrects structured covariate misclassification by inverting estimated confusion matrices, but cannot address treatment-differential outcome measurement error.
137	Prediction-Powered Conditional Inference~\cite{sui2026ppci} (PPCI) correct outcome-level prediction error using a small gold-standard sample but assume correct covariate labels.
138	We test their combination across four DGP variants: (A) covariate error only ($\sigma_{\text{outcome}}{=}0$), (B) outcome error only ($\sigma_{\text{outcome}}{=}0.5$), (C) both errors ($\sigma_{\text{outcome}}{=}0.5$), and (D) no error ($\sigma_{\text{outcome}}{=}0$).
139	Table~\ref{tab:ppci} reports results for $K{=}2$, $n_{\text{expert}}{=}250$, extreme misclassification.
140	
141	Under DGP~C (both errors), EC-HTE+PPCI reduces $|\text{bias}|$ to 0.007/0.008 (z=0/z=1), compared to 0.179/0.216 for EC-HTE alone, representing a 25--27$\times$ improvement.
142	PPCI alone achieves comparable bias (0.017/0.007) but at higher RMSE (0.241 vs.\ 0.209 for z=0).
143	Under DGP~A (covariate error only), EC-HTE+PPCI produces identical results to EC-HTE, confirming that PPCI adds no correction when outcome labels are unbiased.
144	Under DGP~D (no error), all methods perform similarly, with naive and PPCI equivalent as expected.
145	The two corrections are complementary rather than redundant: EC-HTE handles the structured $M^{-1}$ inversion for covariate error, while PPCI handles residual outcome-level bias through its debiasing estimator~\cite{sui2026ppci}.
146	
147	\begin{table*}[t]
148	\centering
149	\caption{PPCI complementarity experiment ($K{=}2$, extreme, $n_{\text{expert}}{=}250$). DGP~A: covariate error only; B: outcome error only ($\sigma{=}0.5$); C: both errors; D: no error. Values are $|\text{bias}|$ and RMSE averaged over two subgroups. $^\star$EC-HTE+PPCI achieves near-zero bias when both error types are present.}
150	\label{tab:ppci}
151	\small
152	\begin{tabular}{ll cccc}
153	\toprule
154	DGP & Method & $|\text{Bias}|_{z=0}$ & $|\text{Bias}|_{z=1}$ & RMSE$_{z=0}$ & RMSE$_{z=1}$ \\
155	\midrule
156	\multirow{5}{*}{A: Covariate}
157	 & Naive & 0.053 & 0.063 & 0.087 & 0.093 \\
158	 & Global & 0.063 & 0.055 & 0.101 & 0.102 \\
159	 & EC-HTE & 0.017 & \textbf{0.013} & 0.097 & 0.108 \\
160	 & PPCI & \textbf{0.015} & 0.020 & 0.162 & 0.168 \\
161	 & EC-HTE+PPCI & 0.017 & \textbf{0.013} & 0.097 & 0.108 \\
162	\midrule
163	\multirow{5}{*}{B: Outcome}
164	 & Naive & 0.189 & 0.197 & 0.206 & 0.212 \\
165	 & Global & 0.185 & 0.208 & 0.204 & 0.228 \\
166	 & EC-HTE & 0.181 & 0.215 & 0.202 & 0.237 \\
167	 & PPCI & 0.015 & \textbf{0.020} & 0.171 & 0.176 \\
168	 & EC-HTE+PPCI & \textbf{0.012} & 0.023 & 0.171 & 0.186 \\
169	\midrule
170	\multirow{5}{*}{C: Both}
171	 & Naive & 0.251 & 0.135 & 0.267 & 0.155 \\
172	 & Global & 0.182 & 0.209 & 0.233 & 0.235 \\
173	 & EC-HTE & 0.179 & 0.216 & 0.224 & 0.262 \\
174	 & PPCI & 0.017 & 0.007 & 0.241 & 0.232 \\
175	 & EC-HTE+PPCI$^\star$ & \textbf{0.007} & \textbf{0.008} & 0.209 & 0.223 \\
176	\midrule
177	\multirow{5}{*}{D: None}
178	 & Naive & \textbf{0.007} & 0.003 & 0.060 & 0.065 \\
179	 & Global & 0.010 & \textbf{0.002} & 0.061 & 0.071 \\
180	 & EC-HTE & 0.013 & 0.007 & 0.062 & 0.079 \\
181	 & PPCI & \textbf{0.007} & \textbf{0.003} & 0.060 & 0.065 \\
182	 & EC-HTE+PPCI & 0.013 & 0.007 & 0.062 & 0.079 \\
183	\bottomrule
184	\end{tabular}
185	\end{table*}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "2340b4e2-05f2-4bff-a138-dd08c0a08429",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/experiments.tex",
      "content": "\\section{Experiments}\n\n\\subsection{Experimental Setup and Data Generation}\n\n\\subsubsection{Synthetic DGP}\n\nWe generate data from a controlled data-generating process (DGP) that separates the effect of subgroup-level misclassification heterogeneity from other confounders.\nFor each observation $i$, the potential outcome under treatment $t$ is\n\\begin{equation}\nY_i(t) = \\alpha + \\tau(Z_i) \\cdot t + \\beta X_i + \\varepsilon_i, \\quad \\varepsilon_i \\sim \\mathcal{N}(0,1),\n\\end{equation}\nwhere $T_i \\sim \\text{Bernoulli}(0.5)$ simulates a randomized controlled trial, and $Z_i \\in \\{0, \\ldots, K{-}1\\}$ is the true effect modifier with $K \\in \\{2, 4\\}$ subgroups.\nThe conditional average treatment effect (CATE) $\\tau(Z{=}z)$ varies across subgroups with controlled heterogeneity $\\Delta\\tau = \\max_z \\tau(z) - \\min_z \\tau(z)$.\nMisclassification is injected through subgroup-specific symmetric confusion matrices $C_s$: the observed label $\\hat{Z}_i$ is drawn as $\\hat{Z}_i \\sim \\text{Multinomial}(C_{S_i})$, where each subgroup $s$ has error rate $\\pi_s$ and $\\Delta\\pi = \\max_s \\pi_s - \\min_s \\pi_s$ controls heterogeneity.\nWe fix $N{=}5000$ observations and vary $n_{\\text{expert}} \\in \\{50, 100, 250, 500, 1000, 2000\\}$ (the number of expert-labeled observations used to estimate confusion matrices).\nEach configuration is repeated for 100 Monte Carlo runs.\n\n\\subsubsection{Semi-synthetic DGP (TweetEval)}\n\nTo test EC-HTE under realistic conditions, we construct a semi-synthetic DGP from the TweetEval sentiment corpus~\\cite{barbieri2020tweeteval}, sampling $N{=}5000$ tweets per run from a pool of 57{,}899.\nFour subgroups are defined by crossing two binary text features: presence of hashtags (\\texttt{has\\_hashtag}) and text length relative to the median (\\texttt{text\\_length\\_bin}).\nThis yields unbalanced subgroup proportions (S0: 39\\%, S1: 38\\%, S2: 12\\%, S3: 11\\%).\nThe effect modifier is $Z{=}1$ if the true sentiment is positive ($P(Z{=}1) \\approx 35\\%$), and $Z{=}0$ otherwise.\nWe set subgroup-specific misclassification rates $\\pi_{S0}{=}0.05$, $\\pi_{S1}{=}0.10$, $\\pi_{S2}{=}0.15$, $\\pi_{S3}{=}0.25$ in the extreme regime, reflecting empirical evidence that hashtag-heavy text degrades LLM classifier accuracy~\\cite{ashwin2025bias}.\nThe outcome model is\n\\begin{equation}\nY_i = 1.0 + \\tau(Z_i, S_i) \\cdot T_i + 0.3 \\cdot \\text{len}_i + 0.2 \\cdot \\text{mention}_i + \\varepsilon_i,\n\\end{equation}\nwhere $\\tau(Z{=}1, S) \\in \\{0.5, 0.4, 0.3, 0.2\\}$ for S0--S3 and $\\tau(Z{=}0) = 0.1$ is the baseline effect.\n\n\\paragraph{Baselines and metrics.}\nWe compare: (1) \\textit{Naive} (no correction), (2) \\textit{Global} (pooled confusion matrix), (3) \\textit{Stratified MLE} (per-subgroup MLE without pooling), (4) \\textit{HB EC-HTE} (our hierarchical Bayes estimator), (5) \\textit{PPCI}~\\cite{sui2026ppci}, and (6) \\textit{EC-HTE+PPCI} (our combined method).\nFor the CausalForest estimator~\\cite{wager2018causal}, we also compare naive, global, and EC-HTE variants.\nPrimary metrics are absolute bias $|\\text{bias}|$, root mean squared error (RMSE), and 95\\% confidence interval coverage, all averaged across subgroups and 100 MC runs.\n\n\\subsection{Bias Mechanism Verification}\n\\label{sec:bias_mechanism}\n\nThe bias decomposition identity (Theorem~\\ref{thm:bias_identity}) predicts that global correction introduces bias proportional to $\\Delta\\pi \\times \\Delta\\tau$ at the subgroup level.\nWe verify this identity empirically across 520 configurations spanning $K \\in \\{2,4\\}$, two misclassification regimes, and six expert budget levels.\nRegressing observed subgroup bias on the predicted $\\Delta\\pi \\times \\Delta\\tau$ product yields $R^2 = 0.994$ for $K{=}2$ and $R^2 = 0.974$ for $K{=}4$; the residual variance reflects MC sampling noise rather than model misspecification, since Theorem~\\ref{thm:bias_identity} is an exact identity at the population level.\nIn 50\\% of configurations (260/520, excluding $\\Delta_c{=}0$ rows where bias is zero by construction), global correction produces larger absolute bias than the naive estimator.\nThe damage concentrates in low-$\\pi$ subgroups: among subgroups where $\\pi_s < \\bar{\\pi}$, global correction increases bias in 84.6\\% of cases.\nMaximum observed amplification reaches 2.86$\\times$ (K=2) and 2.41$\\times$ (K=4) relative to the naive estimator.\nFigure~\\ref{fig:heatmap} visualizes the $\\Delta\\pi \\times \\Delta\\tau$ amplification surface across the parameter grid.\n\n\\subsection{EC-HTE Evaluation}\n\\label{sec:ec_hte_eval}\n\nTable~\\ref{tab:main_results} presents the main results across representative configurations.\nIn the synthetic DGP with $K{=}2$ subgroups and extreme misclassification heterogeneity, HB EC-HTE reduces $|\\text{bias}|$ from 0.059 (global) to 0.011 (a 5.4$\\times$ reduction) while maintaining nominal coverage (0.95) and comparable RMSE (0.093 vs.\\ 0.099).\nThe advantage persists at $K{=}4$: EC-HTE achieves $|\\text{bias}|{=}0.009$ versus 0.056 for global (6.2$\\times$ reduction), though with a small RMSE penalty (0.127 vs.\\ 0.125).\nUnder moderate heterogeneity ($K{=}2$), global correction already achieves low bias (0.009), and EC-HTE provides negligible improvement (0.005) at the cost of slightly higher RMSE (0.075 vs.\\ 0.074).\nThis illustrates the conditional nature of EC-HTE's advantage: when $\\Delta\\pi$ is small, the variance cost of stratification is not offset by bias reduction.\n\nIn the semi-synthetic TweetEval experiment, the pattern shifts.\nGlobal correction achieves the lowest $|\\text{bias}|$ (0.023) among non-oracle methods, while HB EC-HTE attains 0.027 with substantially higher RMSE (0.225 vs.\\ 0.124).\nThis is consistent with moderate $\\Delta\\pi{=}0.20$ and the high-error subgroups (S2, S3) comprising only 23\\% of data: the bias reduction from stratification is marginal while the variance cost of four per-subgroup confusion matrices is substantial.\nHB EC-HTE does improve over stratified MLE (RMSE 0.225 vs.\\ 0.248), confirming that partial pooling helps, but the improvement is insufficient to overcome the structural variance from unbalanced subgroup sizes.\nAt $n_{\\text{expert}} \\geq 250$, HB and MLE converge to within 5\\% on all metrics.\n\n\\paragraph{CausalForest K-dependence.}\nWhen the downstream estimator is a CausalForest~\\cite{wager2018causal} rather than difference-in-means, the bias mechanism operates with amplified magnitude.\nAt $K{=}4$/extreme/$n{=}500$, EC-HTE Forest reduces $|\\text{bias}|$ from 0.191 (global) to 0.040, a 4.8$\\times$ improvement with lower RMSE (0.224 vs.\\ 0.244) and dramatically better coverage (0.91 vs.\\ 0.58).\nThe debiasing-hurts phenomenon intensifies: global correction amplifies naive bias by up to 5.9$\\times$ in the worst subgroup (compared to 2.41$\\times$ for difference-in-means), because the forest's sensitivity to covariate noise magnifies the effect of label errors.\nAt $K{=}2$/$n{=}500$, EC-HTE Forest achieves near-zero bias (0.004--0.013 across subgroups) versus 0.033--0.109 for global, with coverage of 0.91 compared to 0.58 for the global variant.\nAt $K{=}4$, the per-subgroup range widens to 0.002--0.068 while coverage remains above 0.80.\nHowever, this comes at a variance cost: at $K{=}4$/$n{=}100$, EC-HTE Forest RMSE reaches 1.43 (3.5$\\times$ naive), underscoring the budget guidelines in Section~\\ref{sec:budget}.\n\n\\begin{table*}[t]\n\\centering\n\\caption{Main results across synthetic (difference-in-means and CausalForest) and semi-synthetic configurations. $|\\text{Bias}|$ and RMSE are averaged over subgroups, $z$-levels, and 100 MC runs. Bold marks lowest $|\\text{bias}|$ per block. $^\\dagger$RMSE exceeds Global in this configuration, reflecting the variance cost of stratification.}\n\\label{tab:main_results}\n\\small\n\\begin{tabular}{ll ccc}\n\\toprule\nConfiguration & Method & $|\\text{Bias}| \\downarrow$ & RMSE $\\downarrow$ & Coverage \\\\\n\\midrule\n\\multirow{4}{*}{\\shortstack[l]{Synthetic DIM\\\\$K{=}2$, extreme, $n{=}250$}}\n & Naive & 0.058 & 0.090 & 0.82 \\\\\n & Global & 0.059 & 0.099 & 0.87 \\\\\n & Strat.\\ MLE & 0.012 & 0.094 & 0.95 \\\\\n & HB EC-HTE & \\textbf{0.011} & 0.093 & 0.95 \\\\\n\\midrule\n\\multirow{4}{*}{\\shortstack[l]{Synthetic DIM\\\\$K{=}2$, moderate, $n{=}250$}}\n & Naive & 0.018 & 0.064 & 0.95 \\\\\n & Global & 0.009 & 0.074 & 0.96 \\\\\n & Strat.\\ MLE & \\textbf{0.005} & 0.075$^\\dagger$ & 0.97 \\\\\n & HB EC-HTE & \\textbf{0.005} & 0.075$^\\dagger$ & 0.97 \\\\\n\\midrule\n\\multirow{4}{*}{\\shortstack[l]{Synthetic DIM\\\\$K{=}4$, extreme, $n{=}500$}}\n & Naive & 0.062 & 0.113 & 0.88 \\\\\n & Global & 0.056 & 0.125 & 0.91 \\\\\n & Strat.\\ MLE & 0.010 & 0.127$^\\dagger$ & 0.95 \\\\\n & HB EC-HTE & \\textbf{0.009} & 0.127$^\\dagger$ & 0.95 \\\\\n\\midrule\n\\multirow{3}{*}{\\shortstack[l]{Synthetic CausalForest\\\\$K{=}4$, extreme, $n{=}500$}}\n & Naive & 0.208 & 0.231 & 0.44 \\\\\n & Global & 0.191 & 0.244 & 0.58 \\\\\n & EC-HTE Forest & \\textbf{0.040} & 0.224 & 0.91 \\\\\n\\midrule\n\\multirow{4}{*}{\\shortstack[l]{Semi-synthetic\\\\TweetEval, extreme, $n{=}250$}}\n & Naive & 0.027 & 0.103 & 0.93 \\\\\n & Global & \\textbf{0.023} & 0.124 & 0.92 \\\\\n & Strat.\\ MLE & 0.032 & 0.248$^\\dagger$ & 0.91 \\\\\n & HB EC-HTE & 0.027 & 0.225$^\\dagger$ & 0.91 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\subsection{Diagnostic Criterion}\n\\label{sec:diagnostic}\n\nAs a practical corollary of Theorem~\\ref{thm:bias_identity}, the $\\Delta\\pi \\times \\Delta\\tau$ product provides a computable diagnostic for predicting when global correction will fail.\nUsing leave-one-out cross-validation at the subgroup level, a threshold classifier on $|\\Delta\\pi \\times \\Delta\\tau|$ achieves AUC = 0.833 for predicting whether global correction increases bias relative to the naive estimator.\nThe Pearson correlation between the signed product and the observed bias ratio is $r = 0.86$.\nAt the setting level (averaging across subgroups within a configuration), the diagnostic has AUC = 0.49, which is no better than random.\nThis asymmetry arises because global correction redistributes bias across subgroups (benefiting high-$\\pi$ subgroups at the expense of low-$\\pi$ ones) rather than increasing total bias uniformly.\nIn practice, the diagnostic enables researchers to identify vulnerable subgroups before committing to a correction strategy: if any subgroup has $\\pi_s \\ll \\bar{\\pi}$ and $\\tau(z)$ varies across $z$-levels, global correction should be avoided.\nFigure~\\ref{fig:roc} shows the ROC curve and the correlation scatter plot.\n\n\\subsection{Expert Budget Analysis}\n\\label{sec:budget}\n\nThe crossover point at which EC-HTE achieves lower RMSE than global correction depends on $K$ and $\\Delta\\pi$.\nFor $K{=}2$/extreme, the crossover occurs at $n_{\\text{expert}} = 250$: below this threshold, the variance cost of estimating per-subgroup confusion matrices exceeds the bias reduction.\nFor $K{=}4$/extreme, the crossover shifts to $n_{\\text{expert}} = 1000$ because four subgroups require more expert labels to achieve precise confusion matrix estimates.\nUnder moderate heterogeneity ($K{=}2$), EC-HTE never achieves lower RMSE than global at any budget, because global correction already produces low bias ($|\\text{bias}|{<}0.01$) in this regime.\nWithin the EC-HTE family, HB partial pooling improves over stratified MLE in 21 of 24 budget-regime configurations overall, with the largest gains at small $n_{\\text{expert}}$ in $K{=}4$ settings (+42.4\\% RMSE improvement for the hardest subgroup).\nThe two estimators converge by $n_{\\text{expert}} \\geq 1000$ ($<$0.5\\% difference).\nFigure~\\ref{fig:budget} shows the crossover curves across the full budget range.\n\n\\subsection{PPCI Complementarity}\n\\label{sec:ppci}\n\nEC-HTE corrects structured covariate misclassification by inverting estimated confusion matrices, but cannot address treatment-differential outcome measurement error.\nPrediction-Powered Conditional Inference~\\cite{sui2026ppci} (PPCI) correct outcome-level prediction error using a small gold-standard sample but assume correct covariate labels.\nWe test their combination across four DGP variants: (A) covariate error only ($\\sigma_{\\text{outcome}}{=}0$), (B) outcome error only ($\\sigma_{\\text{outcome}}{=}0.5$), (C) both errors ($\\sigma_{\\text{outcome}}{=}0.5$), and (D) no error ($\\sigma_{\\text{outcome}}{=}0$).\nTable~\\ref{tab:ppci} reports results for $K{=}2$, $n_{\\text{expert}}{=}250$, extreme misclassification.\n\nUnder DGP~C (both errors), EC-HTE+PPCI reduces $|\\text{bias}|$ to 0.007/0.008 (z=0/z=1), compared to 0.179/0.216 for EC-HTE alone, representing a 25--27$\\times$ improvement.\nPPCI alone achieves comparable bias (0.017/0.007) but at higher RMSE (0.241 vs.\\ 0.209 for z=0).\nUnder DGP~A (covariate error only), EC-HTE+PPCI produces identical results to EC-HTE, confirming that PPCI adds no correction when outcome labels are unbiased.\nUnder DGP~D (no error), all methods perform similarly, with naive and PPCI equivalent as expected.\nThe two corrections are complementary rather than redundant: EC-HTE handles the structured $M^{-1}$ inversion for covariate error, while PPCI handles residual outcome-level bias through its debiasing estimator~\\cite{sui2026ppci}.\n\n\\begin{table*}[t]\n\\centering\n\\caption{PPCI complementarity experiment ($K{=}2$, extreme, $n_{\\text{expert}}{=}250$). DGP~A: covariate error only; B: outcome error only ($\\sigma{=}0.5$); C: both errors; D: no error. Values are $|\\text{bias}|$ and RMSE averaged over two subgroups. $^\\star$EC-HTE+PPCI achieves near-zero bias when both error types are present.}\n\\label{tab:ppci}\n\\small\n\\begin{tabular}{ll cccc}\n\\toprule\nDGP & Method & $|\\text{Bias}|_{z=0}$ & $|\\text{Bias}|_{z=1}$ & RMSE$_{z=0}$ & RMSE$_{z=1}$ \\\\\n\\midrule\n\\multirow{5}{*}{A: Covariate}\n & Naive & 0.053 & 0.063 & 0.087 & 0.093 \\\\\n & Global & 0.063 & 0.055 & 0.101 & 0.102 \\\\\n & EC-HTE & 0.017 & \\textbf{0.013} & 0.097 & 0.108 \\\\\n & PPCI & \\textbf{0.015} & 0.020 & 0.162 & 0.168 \\\\\n & EC-HTE+PPCI & 0.017 & \\textbf{0.013} & 0.097 & 0.108 \\\\\n\\midrule\n\\multirow{5}{*}{B: Outcome}\n & Naive & 0.189 & 0.197 & 0.206 & 0.212 \\\\\n & Global & 0.185 & 0.208 & 0.204 & 0.228 \\\\\n & EC-HTE & 0.181 & 0.215 & 0.202 & 0.237 \\\\\n & PPCI & 0.015 & \\textbf{0.020} & 0.171 & 0.176 \\\\\n & EC-HTE+PPCI & \\textbf{0.012} & 0.023 & 0.171 & 0.186 \\\\\n\\midrule\n\\multirow{5}{*}{C: Both}\n & Naive & 0.251 & 0.135 & 0.267 & 0.155 \\\\\n & Global & 0.182 & 0.209 & 0.233 & 0.235 \\\\\n & EC-HTE & 0.179 & 0.216 & 0.224 & 0.262 \\\\\n & PPCI & 0.017 & 0.007 & 0.241 & 0.232 \\\\\n & EC-HTE+PPCI$^\\star$ & \\textbf{0.007} & \\textbf{0.008} & 0.209 & 0.223 \\\\\n\\midrule\n\\multirow{5}{*}{D: None}\n & Naive & \\textbf{0.007} & 0.003 & 0.060 & 0.065 \\\\\n & Global & 0.010 & \\textbf{0.002} & 0.061 & 0.071 \\\\\n & EC-HTE & 0.013 & 0.007 & 0.062 & 0.079 \\\\\n & PPCI & \\textbf{0.007} & \\textbf{0.003} & 0.060 & 0.065 \\\\\n & EC-HTE+PPCI & 0.013 & 0.007 & 0.062 & 0.079 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}",
      "numLines": 185,
      "startLine": 1,
      "totalLines": 185
    }
  }
}
```

</details>

---

### Assistant

_source line 13_

<details><summary>Logged reasoning block</summary>

```text
I've read all the required files. Now I need to write the limitations section based on the task requirements. Let me also check if the file already exists.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "9685aba2-23ae-4b6c-8bdb-7424f28e6f2b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017nAJMz3qvT3mQpa3z3mvyZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19177,
      "cache_read_input_tokens": 24445,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19177
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

_source line 14_

Now let me check if the target file already exists.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "ef6f3170-9deb-45b0-b88f-b8145d5c58d4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017nAJMz3qvT3mQpa3z3mvyZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19177,
      "cache_read_input_tokens": 24445,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19177
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

_source line 15_

<details open><summary>🔧 Tool call — Bash · `toolu_012n4aa45FQD9QyjRvenhedF`</summary>

```json
{
  "command": "ls -la /home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/limitations.tex 2>/dev/null; echo \"EXIT:$?\"",
  "description": "Check if limitations.tex exists"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "afdd3174-d67b-4872-857f-ac8d6cf5f2cf",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017nAJMz3qvT3mQpa3z3mvyZ",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19177,
      "cache_read_input_tokens": 24445,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19177
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

_source line 16 · 2026-05-21T05:42:39.713Z_

<details><summary>↩ Tool result · `toolu_012n4aa45FQD9QyjRvenhedF`</summary>

```text
EXIT:2
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "4ffaa4ea-976c-4800-8f1a-83e2b9d35133",
  "tool_use_result": {
    "stdout": "EXIT:2",
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

_source line 17_

File doesn't exist. Writing it now.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "36f357d9-74ec-4758-86a4-2257049ac569",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01N9Ly3wJbGM5NGb2XqKMZwn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 200,
      "cache_read_input_tokens": 43622,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 200
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

_source line 18_

<details open><summary>🔧 Tool call — Write · `toolu_01B5QLKgHY65W2Dhxo8YM7GK`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/limitations.tex",
  "content": "\\section*{Limitations}\n\n\\paragraph{Expert budget threshold.}\nEC-HTE requires at least $n_{\\text{expert}} / K \\geq 25$ per subgroup for the hierarchical Bayesian shrinkage estimates to stabilize.\nBelow this threshold, per-subgroup confusion matrix estimates are too noisy for reliable inversion, and stratified MLE is preferred.\nAt $n_{\\text{expert}} \\geq 1000$, HB and stratified MLE converge to within 0.5\\% on all metrics, making the hierarchical model unnecessary at large expert budgets.\n\n\\paragraph{RMSE tradeoff at small $n$.}\nEC-HTE achieves lower bias than global correction but incurs higher variance when the expert budget is small relative to the number of subgroups.\nIn the most unfavorable configuration ($K{=}4$, extreme, $n_{\\text{expert}} \\leq 100$), EC-HTE CausalForest RMSE reaches 3.5$\\times$ that of the naive estimator.\nPractitioners should weigh whether bias or variance is more consequential for their application before adopting subgroup-stratified correction at small sample sizes.\n\n\\paragraph{Plug-in standard errors.}\nThe variance-adjusted CausalForest propagates outcome uncertainty through the inverse confusion matrix $\\hat{C}_s^{-1}$ but does not propagate uncertainty from the confusion matrix estimation itself.\nThis plug-in approximation is reasonable at $n_{\\text{expert}} \\geq 100$, where confusion matrix estimation variance is small relative to outcome variance, but may understate total uncertainty below this threshold.\nFull Bayesian propagation of confusion matrix posterior uncertainty through the causal forest splitting procedure is computationally prohibitive and left to future work.\n\n\\paragraph{Symmetric misclassification assumption.}\nAll experiments use symmetric error rates ($P(\\hat{Z}{=}1 \\mid Z{=}0) = P(\\hat{Z}{=}0 \\mid Z{=}1)$).\nReal LLM annotators may exhibit asymmetric confusion patterns, such as higher false positive than false negative rates for certain label categories.\nThe bias decomposition identity (Theorem~\\ref{thm:bias_identity}) generalizes to asymmetric matrices, but empirical validation under asymmetric misclassification is left to future work.\n\n\\paragraph{Subgroup structure assumed known.}\nEC-HTE requires discrete, pre-defined subgroups as input.\nContinuous effect modifiers or latent subgroup discovery settings require fundamentally different approaches.\nThe hierarchical prior provides partial robustness to noisy subgroup definitions through automatic shrinkage toward the global mean, but intersectional subgroups with many levels may exceed the $n_{\\text{expert}} / K \\geq 25$ budget threshold, limiting practical applicability to settings with moderate $K$.\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "0ef22073-8e25-4019-9cae-773195425e9e",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01N9Ly3wJbGM5NGb2XqKMZwn",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 200,
      "cache_read_input_tokens": 43622,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 200
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

_source line 19 · 2026-05-21T05:42:59.578Z_

<details><summary>↩ Tool result · `toolu_01B5QLKgHY65W2Dhxo8YM7GK`</summary>

```text
File created successfully at: /home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/limitations.tex
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "3ca83214-9ba5-4a84-9ceb-e2996961a5a3",
  "tool_use_result": {
    "type": "create",
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/limitations.tex",
    "content": "\\section*{Limitations}\n\n\\paragraph{Expert budget threshold.}\nEC-HTE requires at least $n_{\\text{expert}} / K \\geq 25$ per subgroup for the hierarchical Bayesian shrinkage estimates to stabilize.\nBelow this threshold, per-subgroup confusion matrix estimates are too noisy for reliable inversion, and stratified MLE is preferred.\nAt $n_{\\text{expert}} \\geq 1000$, HB and stratified MLE converge to within 0.5\\% on all metrics, making the hierarchical model unnecessary at large expert budgets.\n\n\\paragraph{RMSE tradeoff at small $n$.}\nEC-HTE achieves lower bias than global correction but incurs higher variance when the expert budget is small relative to the number of subgroups.\nIn the most unfavorable configuration ($K{=}4$, extreme, $n_{\\text{expert}} \\leq 100$), EC-HTE CausalForest RMSE reaches 3.5$\\times$ that of the naive estimator.\nPractitioners should weigh whether bias or variance is more consequential for their application before adopting subgroup-stratified correction at small sample sizes.\n\n\\paragraph{Plug-in standard errors.}\nThe variance-adjusted CausalForest propagates outcome uncertainty through the inverse confusion matrix $\\hat{C}_s^{-1}$ but does not propagate uncertainty from the confusion matrix estimation itself.\nThis plug-in approximation is reasonable at $n_{\\text{expert}} \\geq 100$, where confusion matrix estimation variance is small relative to outcome variance, but may understate total uncertainty below this threshold.\nFull Bayesian propagation of confusion matrix posterior uncertainty through the causal forest splitting procedure is computationally prohibitive and left to future work.\n\n\\paragraph{Symmetric misclassification assumption.}\nAll experiments use symmetric error rates ($P(\\hat{Z}{=}1 \\mid Z{=}0) = P(\\hat{Z}{=}0 \\mid Z{=}1)$).\nReal LLM annotators may exhibit asymmetric confusion patterns, such as higher false positive than false negative rates for certain label categories.\nThe bias decomposition identity (Theorem~\\ref{thm:bias_identity}) generalizes to asymmetric matrices, but empirical validation under asymmetric misclassification is left to future work.\n\n\\paragraph{Subgroup structure assumed known.}\nEC-HTE requires discrete, pre-defined subgroups as input.\nContinuous effect modifiers or latent subgroup discovery settings require fundamentally different approaches.\nThe hierarchical prior provides partial robustness to noisy subgroup definitions through automatic shrinkage toward the global mean, but intersectional subgroups with many levels may exceed the $n_{\\text{expert}} / K \\geq 25$ budget threshold, limiting practical applicability to settings with moderate $K$.\n",
    "structuredPatch": [],
    "originalFile": null,
    "userModified": false
  }
}
```

</details>

---

### Assistant

_source line 20_

Now let me register the artifact.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "b6836ea0-9a74-4d70-8e08-48490a422bd2",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LteVV5z5WxR8ScWSei1p3M",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 835,
      "cache_read_input_tokens": 43822,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 835
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

_source line 21_

<details open><summary>🔧 Tool call — ToolSearch · `toolu_0147zCagi1DThCHDai1qGecS`</summary>

```json
{
  "query": "select:mcp__agent-ml-research__register_artifact",
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
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "7ba2e3c2-59a9-41de-84e0-f531fd186470",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01LteVV5z5WxR8ScWSei1p3M",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 835,
      "cache_read_input_tokens": 43822,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 835
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

_source line 22 · 2026-05-21T05:43:02.356Z_

<details><summary>↩ Tool result · `toolu_0147zCagi1DThCHDai1qGecS`</summary>

````text
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
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "9d789679-4875-41bc-b06f-53adb53c262f",
  "tool_use_result": {
    "matches": [
      "mcp__agent-ml-research__register_artifact"
    ],
    "query": "select:mcp__agent-ml-research__register_artifact",
    "total_deferred_tools": 51
  }
}
```

</details>

---

### Tool call

_source line 23_

<details open><summary>🔧 Tool call — mcp__agent-ml-research__register_artifact · `toolu_01CtvuhjcELLvsLAkMm9J7Ve`</summary>

```json
{
  "name": "limitations-section",
  "type": "paper",
  "description": "Limitations section for EC-HTE EMNLP 2026 paper: 5 limitations covering expert budget threshold, RMSE tradeoff, plug-in SEs, symmetric misclassification assumption, and subgroup structure assumption.",
  "project": "ec_hte_llm_annotation",
  "source_path": "/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/docs/paper/limitations.tex",
  "tags": [
    "paper",
    "limitations",
    "emnlp2026"
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
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "b7722106-32bf-49a7-bcda-934d35cb4a8b",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_018h8ECM8gpNV1gBhbKHSdz2",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 822,
      "cache_read_input_tokens": 44657,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 822
      },
      "output_tokens": 59,
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

_source line 24 · 2026-05-21T05:43:07.469Z_

<details><summary>↩ Tool result · `toolu_01CtvuhjcELLvsLAkMm9J7Ve`</summary>

```text
{"result":"{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260521_3de53d\", \"name\": \"limitations-section\", \"type\": \"paper\", \"description\": \"Limitations section for EC-HTE EMNLP 2026 paper: 5 limitations covering expert budget threshold, RMSE tradeoff, plug-in SEs, symmetric misclassification assumption, and subgroup structure assumption.\", \"path\": \"projects/ec_hte_llm_annotation/artifacts/_project/paper/limitations.tex\", \"url\": null, \"project\": \"ec_hte_llm_annotation\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-21T05:43:07.396123+00:00\", \"tags\": [\"paper\", \"limitations\", \"emnlp2026\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "9e87bae0-9473-4e45-bf05-f1003661b220",
  "tool_use_result": {
    "content": "{\"result\":\"{\\\"success\\\": true, \\\"data\\\": {\\\"artifact\\\": {\\\"id\\\": \\\"art_20260521_3de53d\\\", \\\"name\\\": \\\"limitations-section\\\", \\\"type\\\": \\\"paper\\\", \\\"description\\\": \\\"Limitations section for EC-HTE EMNLP 2026 paper: 5 limitations covering expert budget threshold, RMSE tradeoff, plug-in SEs, symmetric misclassification assumption, and subgroup structure assumption.\\\", \\\"path\\\": \\\"projects/ec_hte_llm_annotation/artifacts/_project/paper/limitations.tex\\\", \\\"url\\\": null, \\\"project\\\": \\\"ec_hte_llm_annotation\\\", \\\"exp_id\\\": null, \\\"skill\\\": \\\"\\\", \\\"created_at\\\": \\\"2026-05-21T05:43:07.396123+00:00\\\", \\\"tags\\\": [\\\"paper\\\", \\\"limitations\\\", \\\"emnlp2026\\\"]}, \\\"manifest\\\": \\\"/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/artifacts/manifest.yaml\\\"}, \\\"error\\\": null, \\\"metadata\\\": {}}\"}",
    "structuredContent": {
      "result": "{\"success\": true, \"data\": {\"artifact\": {\"id\": \"art_20260521_3de53d\", \"name\": \"limitations-section\", \"type\": \"paper\", \"description\": \"Limitations section for EC-HTE EMNLP 2026 paper: 5 limitations covering expert budget threshold, RMSE tradeoff, plug-in SEs, symmetric misclassification assumption, and subgroup structure assumption.\", \"path\": \"projects/ec_hte_llm_annotation/artifacts/_project/paper/limitations.tex\", \"url\": null, \"project\": \"ec_hte_llm_annotation\", \"exp_id\": null, \"skill\": \"\", \"created_at\": \"2026-05-21T05:43:07.396123+00:00\", \"tags\": [\"paper\", \"limitations\", \"emnlp2026\"]}, \"manifest\": \"/home/ubuntu/.agent-ml-research-idea_gen_0520/projects/ec_hte_llm_annotation/artifacts/manifest.yaml\"}, \"error\": null, \"metadata\": {}}"
    }
  }
}
```

</details>

---

### Assistant

_source line 25_

Written to `docs/paper/limitations.tex` (~250 words). Five limitations with specific experimental numbers:

1. **Expert budget threshold** — $n_{\text{expert}}/K \geq 25$ required; HB/MLE converge at $n \geq 1000$
2. **RMSE tradeoff** — up to 3.5× worse RMSE at $K{=}4$, small $n$
3. **Plug-in SEs** — no confusion matrix uncertainty propagation (D010 requirement met)
4. **Symmetric misclassification** — asymmetric case not empirically validated
5. **Subgroup structure assumed known** — discrete pre-defined subgroups only; intersectional settings may exceed budget threshold

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "uuid": "9d2425bc-3655-4588-88ba-93964df27a67",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01KwPnFrXxfcDUMF4PxTnQQE",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 560,
      "cache_read_input_tokens": 45479,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 560
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

_source line 26_

Written to `docs/paper/limitations.tex` (~250 words). Five limitations with specific experimental numbers:

1. **Expert budget threshold** — $n_{\text{expert}}/K \geq 25$ required; HB/MLE converge at $n \geq 1000$
2. **RMSE tradeoff** — up to 3.5× worse RMSE at $K{=}4$, small $n$
3. **Plug-in SEs** — no confusion matrix uncertainty propagation (D010 requirement met)
4. **Symmetric misclassification** — asymmetric case not empirically validated
5. **Subgroup structure assumed known** — discrete pre-defined subgroups only; intersectional settings may exceed budget threshold

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 46343,
  "duration_api_ms": 47327,
  "num_turns": 9,
  "stop_reason": "end_turn",
  "session_id": "626c2f0d-9004-45c6-be44-aff40c395735",
  "total_cost_usd": 0.3672435,
  "usage": {
    "input_tokens": 10,
    "cache_creation_input_tokens": 34198,
    "cache_read_input_tokens": 213866,
    "output_tokens": 1795,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 34198,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 180,
        "cache_read_input_tokens": 45479,
        "cache_creation_input_tokens": 560,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 560
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1568,
      "outputTokens": 16,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.001648,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 10,
      "outputTokens": 1795,
      "cacheReadInputTokens": 213866,
      "cacheCreationInputTokens": 34198,
      "webSearchRequests": 0,
      "costUSD": 0.36559549999999996,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "e851a7e0-fb60-433d-ab10-67d9ade08f73"
}
```

</details>

---
