// Auto-generated from README.md - DO NOT EDIT MANUALLY
// Run: python3 parse_md.py to regenerate

const tagCategories = {"methods": ["RL-based", "Self-Play", "Memory", "Multi-Agent", "Process Reward", "SFT"], "tasks": ["Agent", "RAG", "Search Agent", "Multi-hop QA", "Deep Research", "Benchmark", "Dataset"], "features": ["Token-Efficient", "Training-free", "Open-Source"]};

const papers = [
  {
    "date": "2025.01",
    "name": "Search-o1",
    "url": "https://arxiv.org/abs/2501.05366",
    "title": "Search-o1",
    "description": "Search-o1: Agentic Search-Enhanced Large Reasoning Models 增强具有类似O1推理模式的LRMs的自主检索能力，使模型在推理过程中能动态检索外部知识，从而提高推理的准确性和可靠性",
    "codeLinks": [
      "https://github.com/sunnynexus/Search-o1"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "Agent"
    ],
    "id": 1
  },
  {
    "date": "2025.02",
    "name": "O1 Embedder",
    "url": "https://arxiv.org/abs/2502.07555",
    "title": "O1 Embedder",
    "description": "O1 Embedder: Let Retrievers Think Before Action 已经有很多训练LLM作为Embedder的工作，如何让Embedder在检索目标文档之前生成对输入查询有用的thoughts，类似于一个推理的过程？",
    "codeLinks": [
      "https://github.com/RuiranYan/o1embedder"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [],
    "id": 2
  },
  {
    "date": "2025.03",
    "name": "DeepRetrieval",
    "url": "https://arxiv.org/abs/2503.00223",
    "title": "DeepRetrieval",
    "description": "DeepRetrieval: Hacking Real Search Engines and Retrievers with Large Language Models via Reinforcement Learning 与前面基于答案匹配度作为奖励信号不同(前面主要是RAG的QA任务)，该工作主要聚焦在检索任务，以检索指标作为奖励信号，LLM通过查询增强的方式，补充原始查询的语义，然后进行检索",
    "codeLinks": [
      "https://github.com/pat-jj/DeepRetrieval"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "RAG",
      "Benchmark"
    ],
    "id": 3
  },
  {
    "date": "2025.03",
    "name": "Search-R1",
    "url": "https://arxiv.org/abs/2503.09516",
    "title": "Search-R1",
    "description": "Search-R1: Training LLMs to Reason and Leverage Search Engines with Reinforcement Learning 收到R1的启发，将强化学习扩展到RAG场景，将搜索引擎建模为强化学习环境的一部分，使LLM能通过试错自主学习；仅用最终答案正确性作为奖励信号，创新检索内容掩码",
    "codeLinks": [
      "https://github.com/PeterGriffinJin/Search-R1"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "RAG"
    ],
    "id": 4
  },
  {
    "date": "2025.03",
    "name": "R1-Searcher",
    "url": "https://arxiv.org/abs/2503.05592",
    "title": "R1-Searcher",
    "description": "R1-Searcher: Incentivizing the Search Capability in LLMs via Reinforcement Learning 与Search-R1类似，不过采用的是基于两阶段RL框架，通过自主调用外部搜索工具增强LLM的回答能力，无过程奖励或蒸馏。仅依赖最终奖励。",
    "codeLinks": [
      "https://github.com/RUCAIBox/R1-Searcher"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Process Reward"
    ],
    "id": 5
  },
  {
    "date": "2025.03",
    "name": "ReSearch",
    "url": "https://arxiv.org/abs/2503.19470",
    "title": "ReSearch",
    "description": "ReSearch: Learning to Reason with Search for LLMs via Reinforcement Learning 基本和Search-R1一样，不同点在于考虑了格式奖励，同时用的是F1 score",
    "codeLinks": [
      "https://github.com/Agent-RL/ReSearch"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based"
    ],
    "id": 6
  },
  {
    "date": "2025.03",
    "name": "ReAgent",
    "url": "https://arxiv.org/abs/2503.06951",
    "title": "ReAgent",
    "description": "ReAgent: Reversible Multi-Agent Reasoning for Knowledge-Enhanced Multi-Hop QA 通过引入多智能体可逆回溯推理机制，解决了多跳问答中错误积累和不可纠正的问题。",
    "codeLinks": [
      "https://github.com/astridesa/ReAgent"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "Multi-Agent",
      "Agent",
      "Multi-hop QA"
    ],
    "id": 7
  },
  {
    "date": "2025.04",
    "name": "DeepResearcher",
    "url": "https://arxiv.org/abs/2504.03160",
    "title": "DeepResearcher",
    "description": "DeepResearcher: Scaling Deep Research via Reinforcement Learning in Real-World Environments 是现有搜索代理在实际环境中扩展困难，通过强化学习在真实环境中扩展深度研究能力，缺少在真实网络环境中，应对环境动态性，不可预测性，噪声、搜索网页质量差异和内容格式问题的强大Agent框架，不仅有Search还有Browse",
    "codeLinks": [
      "https://github.com/GAIR-NLP/DeepResearcher"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent",
      "Deep Research"
    ],
    "id": 8
  },
  {
    "date": "2025.05",
    "name": "AutoRefine",
    "url": "https://arxiv.org/abs/2505.11277",
    "title": "Search and Refine During Think",
    "description": "Search and Refine During Think: Facilitating Knowledge Refinement for Improved Retrieval-Augmented Reasoning Search-R1检索到的文档往往包含无关内容，可能影响到模型有效利用新的知识。可以考虑边检索，边精炼的方式，使模型在检索过程中自我进化。同时精炼过程提供奖励，避免仅结果奖励",
    "codeLinks": [
      "https://github.com/syr-cn/AutoRefine"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Self-Play",
      "RAG",
      "Benchmark"
    ],
    "id": 9
  },
  {
    "date": "2025.05",
    "name": "IKEA",
    "url": "https://arxiv.org/abs/2505.07596",
    "title": "IKEA",
    "description": "IKEA: Reinforced Internal-External Knowledge Synergistic Reasoning for Efficient Adaptive Search Agent 解决现有搜索代理过度依赖外部搜索、未充分利用内部知识的问题，提出强化学习的内外部知识协同推理代理，识别知识边界，优先使用内部知识，减少冗余检索和知识冲突",
    "codeLinks": [
      "https://github.com/hzy312/knowledge-r1"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent"
    ],
    "id": 10
  },
  {
    "date": "2025.05",
    "name": "ZeroSearch",
    "url": "https://arxiv.org/abs/2505.04588",
    "title": "ZeroSearch",
    "description": "ZeroSearch: Incentivize the Search Capability of LLMs without Searching 解决RL训练搜索代理时面临的文档质量不可控和API成本高昂两大挑战，无需真实搜索，直接用LLM模拟搜索引擎，引入课程学习策略，在降低88%成本的同时性能超过依赖真实搜索的方法",
    "codeLinks": [
      "https://github.com/Alibaba-NLP/ZeroSearch"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "Agent",
      "Search Agent"
    ],
    "id": 11
  },
  {
    "date": "2025.05",
    "name": "InForage",
    "url": "https://arxiv.org/abs/2505.09316",
    "title": "Scent of Knowledge",
    "description": "Scent of Knowledge: Optimizing Search-Enhanced Reasoning with Information Foraging 针对传统RAG采用静态预推理检索策略、无法应对模糊多步或动态信息需求的问题，提出了InForage框架。受信息觅食理论启发，作者通过强化学习将检索增强推理形式化为动态信息搜寻过程，显式奖励中间检索质量以鼓励LLM通过自适应搜索行为迭代收集和整合信息。为支持训练，团队构建了人工引导的数据集捕捉复杂真实网络任务的迭代搜索和推理轨迹。",
    "codeLinks": [
      "https://github.com/VectorSpaceLab/Infomatica"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "RAG",
      "Dataset"
    ],
    "id": 12
  },
  {
    "date": "2025.05",
    "name": "s3",
    "url": "https://arxiv.org/abs/2505.14146",
    "title": "s3",
    "description": "s3: You Don't Need That Much Data to Train a Search Agent via RL 解决现有方法要么优化检索指标忽略下游效用，要么端到端训练导致搜索与生成纠缠的问题，提出轻量级框架解耦搜索器和生成器，仅用2.4k训练样本实现强大性能，提出Gain Beyond RAG奖励",
    "codeLinks": [
      "https://github.com/pat-jj/s3"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Agent",
      "RAG",
      "Search Agent"
    ],
    "id": 13
  },
  {
    "date": "2025.05",
    "name": "StepSearch",
    "url": "https://arxiv.org/abs/2505.15107",
    "title": "StepSearch",
    "description": "StepSearch: Igniting LLMs Search Ability via Step-Wise Proximal Policy Optimization 目前Search-R1等现有方法因依赖稀疏全局奖励而缺乏对中间搜索过程细粒度监督的问题，通过引入基于信息增益和冗余惩罚的token级别步骤奖励机制（StePPO），解决了其在复杂多跳问答中缺乏中间查询和多步检索细粒度监督的问题。需要做数据增强得到Golden轨迹",
    "codeLinks": [
      "https://github.com/Zillwang/StepSearch"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Multi-hop QA"
    ],
    "id": 14
  },
  {
    "date": "2025.05",
    "name": "SimpleDeepSearcher",
    "url": "https://arxiv.org/abs/2505.16834",
    "title": "SimpleDeepSearcher",
    "description": "SimpleDeepSearcher: Deep Information Seeking via Web-Powered Reasoning Trajectory Synthesis 动机在于解决现有深度搜索系统面临的核心瓶颈：高质量训练轨迹稀缺、模拟环境与真实部署之间存在分布偏移、以及真实世界部署的计算成本过高。为此，该研究提出了一个轻量且有效的框架，通过在真实网络搜索环境中模拟用户交互来合成高质量训练数据，并辅以多标准筛选策略优化输入输出端的多样性与质量，最终仅用 871 条精选样本进行监督微调，便在五个跨领域基准上取得了优于强化学习基线的显著提升，系统性地突破了数据稀缺困境，为高效深度搜索系统的构建提供了实用路径。",
    "codeLinks": [
      "https://github.com/RUCAIBox/SimpleDeepSearcher"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "SFT",
      "Benchmark"
    ],
    "id": 15
  },
  {
    "date": "2025.05",
    "name": "R1-Searcher++",
    "url": "https://arxiv.org/abs/2505.17005",
    "title": "R1-Searcher++",
    "description": "R1-Searcher++: Incentivizing the Dynamic Knowledge Acquisition of LLMs via Reinforcement Learning 作为R1-Searcher的增强版，解决如何更好地利用内部和外部知识的问题，采用两阶段策略，引入内部知识利用奖励机制和记忆机制，实现动态知识获取",
    "codeLinks": [
      "https://github.com/RUCAIBox/R1-Searcher-plus"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based"
    ],
    "id": 16
  },
  {
    "date": "2025.05",
    "name": "Search Wisely β-GRPO",
    "url": "https://arxiv.org/abs/2505.17281",
    "title": "Search Wisely",
    "description": "Search Wisely: Mitigating Sub-optimal Agentic Searches By Reducing Uncertainty 解决代理搜索中存在的不确定性导致次优搜索行为（搜索不足or冗余搜索）的问题，通过减少不确定性来缓解次优的代理搜索，提高搜索效率和质量",
    "codeLinks": [
      "https://github.com/mianzhang/Search-R1"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "Agent",
      "Token-Efficient"
    ],
    "id": 17
  },
  {
    "date": "2025.05",
    "name": "LeTS",
    "url": "https://arxiv.org/abs/2505.17447",
    "title": "LeTS",
    "description": "LeTS: Learning to Think-and-Search via Process-and-Outcome Reward Hybridization 解决了Search-R1/ReSearch等结果监督RL方法因忽略中间步骤而导致的冗余搜索与无关搜索问题，通过设计基于规则的过程级奖励模块（包括 惩罚同一轨迹内重复检索相同文档的行为 和 利用组内优秀轨迹指导弱轨迹，解决无关搜索问题）并用过程奖励动态调整结果奖励的优势值实现过程-结果奖励混合",
    "codeLinks": [
      "https://github.com/Cheungki/LeTS"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Process Reward"
    ],
    "id": 18
  },
  {
    "date": "2025.05",
    "name": "EvolveSearch",
    "url": "https://arxiv.org/abs/2505.22501",
    "title": "EvolveSearch",
    "description": "EvolveSearch: An Iterative Self-Evolving Search Agent 解决当前搜索代理需要外部人工标注推理轨迹的问题，提出迭代自进化框架，协同结合RL与SFT，无需外部人工标注即可提升网络搜索能力，实现自我进化",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "Self-Play",
      "SFT",
      "Agent",
      "Search Agent"
    ],
    "id": 19
  },
  {
    "date": "2025.06",
    "name": "R-Search",
    "url": "https://arxiv.org/abs/2506.04185",
    "title": "R-Search",
    "description": "R-Search: Empowering LLM Reasoning with Search via Multi-Reward Reinforcement Learning 通过引入多阶段混合奖励机制（答案质量、跨模型证据质量、格式正确性）和证据整合模块，解决了Search-R1中检索时机与真实需求不对齐、推理-搜索交互深度受限的问题，使LLM能够动态决定何时检索并从全局视角提炼关键证据，从而优化整个推理-搜索交互轨迹",
    "codeLinks": [
      "https://github.com/QingFei1/R-Search"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based"
    ],
    "id": 20
  },
  {
    "date": "2025.07",
    "name": "TIRESRAG-R1",
    "url": "https://arxiv.org/abs/2507.22716v1",
    "title": "现有基于强化学习的检索增强生成（RAG）方法仅依赖最终答案奖励、忽视中间推理质量，导致模型常出现信息检索不充分、推理过程存在逻辑缺陷、以及答案与推理链不一致等问题；为此，该论文提出TIRESRAG-R",
    "description": "现有基于强化学习的检索增强生成（RAG）方法仅依赖最终答案奖励、忽视中间推理质量，导致模型常出现信息检索不充分、推理过程存在逻辑缺陷、以及答案与推理链不一致等问题；为此，该论文提出TIRESRAG-R1框架，通过\"思考-检索-反思\"流程结合充分性奖励、推理质量奖励和反思奖励的多维奖励系统，并辅以难度感知重加权和训练样本过滤策略，显著提升了复杂多跳问答任务上的推理质量与稳定性。",
    "codeLinks": [
      "https://github.com/probe2/TIRESRAG-R1"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "RAG",
      "Multi-hop QA"
    ],
    "id": 21
  },
  {
    "date": "2025.08",
    "name": "Self-Search RL",
    "url": "https://arxiv.org/abs/2508.10874",
    "title": "SSRL",
    "description": "SSRL: Self-Search Reinforcement Learning 研究LLM作为RL任务模拟器的潜力，训练LLM直接作为搜索引擎，减少对外部搜索引擎的昂贵交互依赖，通过结构化提示和重复采样量化LLM的内在搜索能力，增强自我搜索能力",
    "codeLinks": [
      "https://github.com/TsinghuaC3I/SSRL"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based"
    ],
    "id": 22
  },
  {
    "date": "2025.08",
    "name": "ASearcher",
    "url": "https://arxiv.org/abs/2508.07976",
    "title": "Beyond Ten Turns",
    "description": "Beyond Ten Turns: Unlocking Long-Horizon Agentic Search with Large-Scale Asynchronous RL 解决长视野搜索任务的挑战，通过大规模异步强化学习解锁长视野代理搜索能力，支持超过十轮以上的复杂搜索交互",
    "codeLinks": [
      "https://github.com/inclusionAI/ASearcher"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Agent",
      "Deep Research"
    ],
    "id": 23
  },
  {
    "date": "2025.08",
    "name": "Atom-Searcher",
    "url": "https://arxiv.org/abs/2508.12800",
    "title": "Atom-Searcher",
    "description": "Atom-Searcher: Enhancing Agentic Deep Research via Fine-Grained Atomic Thought Reward 深度研究依赖结果奖励 RL，存在梯度冲突与奖励稀疏，训练低效且难收敛。提出“原子思维”范式，把推理拆成细粒度功能单元，并设计原子思维奖励 ATR 对其逐段打分；再用课程式聚合策略先重过程 ATR、后重结果奖励，平滑优化路径。Atom-Searcher 框架 = 原子思维分解 + ATR 细粒度引导 + 课程式混合奖励，无需额外标注即可在七项基准上稳定超越 SOTA，推理更可解释、测试算力可伸缩。",
    "codeLinks": [
      "https://github.com/antgroup/Research-Venus"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Process Reward",
      "Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 24
  },
  {
    "date": "2025.09",
    "name": "InfoSeek",
    "url": "https://arxiv.org/abs/2509.00375",
    "title": "Open Data Synthesis For Deep Research 针对现有基准无法捕捉DeepResearch复杂性、而合成数据集常引入捷径推理和知识泄漏的问题，提出了InfoSeek。将具",
    "description": "Open Data Synthesis For Deep Research 针对现有基准无法捕捉DeepResearch复杂性、而合成数据集常引入捷径推理和知识泄漏的问题，提出了InfoSeek。将具有可验证答案的深度研究任务形式化为层次约束满足问题（HCSPs），设计一个双代理系统从大规模网页递归构建研究树，将中间节点模糊化为有效子问题，再转换为需遍历完整层次的自然语言问题。通过拒绝采样生成推理轨迹，快速扩展产出50K+训练样本和精选测试集，保留中间步骤和检索标签等元信息以支持复合奖励设计和轨迹级探索等高级优化策略。",
    "codeLinks": [
      "https://github.com/VectorSpaceLab/Infomatica"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Process Reward",
      "Agent",
      "Deep Research",
      "Benchmark",
      "Dataset"
    ],
    "id": 25
  },
  {
    "date": "2025.09",
    "name": "EviNote-RAG",
    "url": "https://arxiv.org/abs/2509.00877",
    "title": "EviNote-RAG",
    "description": "EviNote-RAG: Enhancing RAG Models via Answer-Supportive Evidence Notes 针对 RAG 信号噪声低、多跳误差累积两大痛点，提出“检索→笔记→回答”新流程：先让模型把原始文档蒸馏成“支持证据笔记”（SEN），显式标记关键与不确定信息，再用基于蕴涵的 Evidence Quality Reward 保证笔记足以推出答案",
    "codeLinks": [
      "https://github.com/Da1yuqin/EviNoteRAG"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "RAG",
      "Multi-hop QA"
    ],
    "id": 26
  },
  {
    "date": "2025.09",
    "name": "AceSearcher",
    "url": "https://arxiv.org/abs/2509.24193",
    "title": "AceSearcher",
    "description": "AceSearcher: Bootstrapping Reasoning and Search for LLMs via Reinforced Self-Play 检索增强 LLM 多跳检索弱、推理差，于是让同一模型“左右互搏”：自演分解者+解题者，用监督微调混合搜索推理任务后，再直接用最终答案准确率做强化学习，无需中间标注，10 数据集平均 EM 提升 7.6%，32B 版仅用 DeepSeek-V3 5% 参数就在金融文档推理上打平，1.5/8B 版也常跑赢参数量大 9 倍的现有模型。",
    "codeLinks": [
      "https://github.com/ritaranx/AceSearcher"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Self-Play",
      "SFT",
      "RAG",
      "Multi-hop QA",
      "Dataset"
    ],
    "id": 27
  },
  {
    "date": "2025.10",
    "name": "DeSA",
    "url": "https://arxiv.org/abs/2510.04695",
    "title": "Beyond Outcome Reward",
    "description": "Beyond Outcome Reward: Decoupling Search and Answering Improves LLM Agents 目前Search-R1主要依赖基于结果的奖励，这隐含了一个关键假设：优化最终答案会自动教会智能体进行有效搜索。作者质疑这一假设，指出结果奖励存在以下根本缺陷：信用分配问题：结果奖励提供的是稀疏、延迟的反馈，无法有效指导中间的搜索行为 行为-结果脱节：没有证据表明好的结果必然来自于有效的搜索过程。导致不搜索，重复搜索，无效搜索。",
    "codeLinks": [
      "https://github.com/yiding-w/DeSA"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Agent"
    ],
    "id": 28
  },
  {
    "date": "2025.10",
    "name": "DecEx-RAG",
    "url": "https://arxiv.org/abs/2510.05691",
    "title": "DecEx-RAG",
    "description": "DecEx-RAG: Boosting Agentic Retrieval-Augmented Generation with Decision and Execution Optimization via Process Supervision 将RAG建模为马尔可夫决策过程，显式解耦决策（终止/检索）与执行（内容质量）两阶段，通过搜索树构建过程监督数据，并利用多轮rollout的聚合奖励动态剪枝冗余分支，将搜索复杂度从指数降为线性。采用SFT+DPO两阶段训练学习最优决策与执行策略",
    "codeLinks": [
      "https://github.com/sdsxdxl/DecEx-RAG"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Process Reward",
      "SFT",
      "Agent",
      "RAG",
      "Benchmark"
    ],
    "id": 29
  },
  {
    "date": "2025.10",
    "name": "HiPRAG",
    "url": "https://arxiv.org/abs/2510.07794",
    "title": "HiPRAG",
    "description": "HiPRAG: Hierarchical Process Rewards for Efficient Agentic Retrieval Augmented Generation 通过分层过程奖励优化RAG智能体搜索决策，将推理轨迹分解为可解析步骤并实时检测冗余/缺失搜索 β-GRPO续作",
    "codeLinks": [
      "https://github.com/qualidea1217/HiPRAG"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Process Reward",
      "Agent",
      "RAG",
      "Benchmark"
    ],
    "id": 30
  },
  {
    "date": "2025.10",
    "name": "QAgent",
    "url": "https://arxiv.org/abs/2510.08383",
    "title": "QAgent",
    "description": "QAgent: A modular Search Agent with Interactive Query Understanding 解决传统RAG难以理解复杂查询、RL训练搜索代理泛化和部署困难的问题，提出模块化搜索代理框架，通过交互式推理和检索优化查询理解，即插即用于复杂系统",
    "codeLinks": [
      "https://github.com/LivingFutureLab/QAgent"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "Agent",
      "RAG",
      "Search Agent"
    ],
    "id": 31
  },
  {
    "date": "2025.10",
    "name": "InfoFlow",
    "url": "https://arxiv.org/abs/2510.26575",
    "title": "InfoFlow",
    "description": "InfoFlow: Reinforcing Search Agent via Reward Density Optimization 解决深度搜索场景中奖励密度低、探索成本高的问题，提出奖励密度优化框架，通过子问题分解、失败引导提示和双代理精炼三方面提高奖励密度和训练效率",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent",
      "Token-Efficient"
    ],
    "id": 32
  },
  {
    "date": "2025.10",
    "name": "Search Self-play",
    "url": "https://arxiv.org/abs/2510.18821",
    "title": "Search Self-play",
    "description": "Search Self-play: Pushing the Frontier of Agent Capability without Supervision 解决无监督情况下如何提升代理能力的问题，通过搜索自我博弈强化学习，让LLM交替提问和解决持续训练自我进化，无需监督即可推动代理能力边界，解决当前训练Agent的RL方法对数据的依赖问题",
    "codeLinks": [
      "https://github.com/Alibaba-Quark/SSP"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Self-Play",
      "Agent"
    ],
    "id": 33
  },
  {
    "date": "2025.10",
    "name": "E-GRPO",
    "url": "https://arxiv.org/abs/2510.24694",
    "title": "Repurposing Synthetic Data for Fine-grained Search Agent Supervision 解决GRPO方法缺乏细粒度监督信号的问题，提出E-GRPO框架",
    "description": "Repurposing Synthetic Data for Fine-grained Search Agent Supervision 解决GRPO方法缺乏细粒度监督信号的问题，提出E-GRPO框架，利用合成数据中的实体信息作为细粒度奖励，解决\"近失\"问题，提升复杂搜索任务性能",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Process Reward",
      "Agent",
      "Search Agent"
    ],
    "id": 34
  },
  {
    "date": "2025.10",
    "name": "GlobalRAG",
    "url": "https://arxiv.org/abs/2510.20548",
    "title": "GlobalRAG",
    "description": "GlobalRAG: Enhancing Global Reasoning in Multi-hop Question Answering via Reinforcement Learning 解决多跳QA中缺乏全局规划和不忠实执行的问题，通过强化学习增强全局推理，分解问题为子目标，协调检索与推理，仅使用8k训练数据就实现显著性能提升。需要做数据增强得到Golden轨迹",
    "codeLinks": [
      "https://github.com/CarnegieBin/GlobalRAG"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "RAG",
      "Multi-hop QA"
    ],
    "id": 35
  },
  {
    "date": "2025.10",
    "name": "Interact-RAG",
    "url": "https://arxiv.org/abs/2510.27566",
    "title": "Interact-RAG",
    "description": "Interact-RAG: Reason and Interact with the Corpus, Beyond Black-Box Retrieval 现有Agentic RAG方法将检索过程视为黑盒，智能体只能被动查询，限制了复杂任务的信息探索能力。Interact-RAG通过语料库交互引擎赋予智能体细粒度检索控制权：多面检索（语义/精确搜索、加权融合）锚定匹配（实体匹配聚焦关键信息）上下文塑造（动态包含/排除文档、调整检索规模）配合推理增强工作流（全局规划器→自适应推理器→执行器）实现零样本执行和轨迹合成，再通过SFT+RL两阶段训练（GRPO算法）内化策略",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "SFT",
      "Agent",
      "RAG",
      "Benchmark"
    ],
    "id": 36
  },
  {
    "date": "2025.10",
    "name": "MARAG-R1",
    "url": "https://arxiv.org/abs/2510.27569",
    "title": "MARAG-R1",
    "description": "MARAG-R1: Beyond Single Retriever via Reinforcement-Learned Multi-Tool Agentic Retrieval 现有RAG系统依赖单一检索器和固定的top-k选择策略，这导致：只能访问语料库的狭窄静态子集；无法获取任务所需的全面外部信息；在需要语料库级推理和跨文档综合的任务上成为主要瓶颈。多工具架构：为LLM配备四种互补的检索工具：语义搜索（广度探索）关键词搜索（精确匹配）文档过滤（基于约束选择）聚合工具（统计综合）两阶段训练：SFT+RL 复合奖励设计：答案奖励 + 文档覆盖率奖励 + 工具探索奖励：平衡探索效率，避免冗余调用",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "SFT",
      "Agent",
      "RAG",
      "Benchmark",
      "Token-Efficient"
    ],
    "id": 37
  },
  {
    "date": "2025.11",
    "name": "TeaRAG",
    "url": "https://arxiv.org/abs/2511.05385",
    "title": "TeaRAG",
    "description": "TeaRAG: A Token-Efficient Agentic Retrieval-Augmented Generation Framework 现有Agentic RAG方法因过度关注答案准确性而忽视token开销，导致模型过度思考和冗余检索，且训练效率低下。TeaRAG通过两个层面提升token效率：1) 检索压缩：构建知识关联图融合语义检索与三元组图检索，用Personalized PageRank筛选关键信息，以高密度知识三元组替代冗余文本块；2) 推理压缩：提出迭代式过程感知DPO（IP-DPO），设计基于知识匹配的过程奖励函数评估每步的知识充分性并惩罚多余步骤，通过迭代优化生成更简洁的推理路径。",
    "codeLinks": [
      "https://github.com/Applied-Machine-Learning-Lab/TeaRAG"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Process Reward",
      "SFT",
      "Agent",
      "RAG",
      "Benchmark",
      "Token-Efficient"
    ],
    "id": 38
  },
  {
    "date": "2025.11",
    "name": "IterResearch",
    "url": "https://arxiv.org/abs/2511.07327",
    "title": "IterResearch",
    "description": "IterResearch: Rethinking Long-Horizon Agents via Markovian State Reconstruction 通过马尔可夫状态重建机制（用演进报告替代完整历史上下文）解决了单上下文范式的上下文窒息与噪声污染问题，使智能体在任意探索深度（实验验证至 2048 轮）保持恒定推理能力。提出EAPO（效率感知策略优化）——引入几何折扣奖励激励高效探索，配合自适应下采样实现稳定分布式训练。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Memory",
      "Agent",
      "Deep Research",
      "Token-Efficient"
    ],
    "id": 39
  },
  {
    "date": "2025.11",
    "name": "Bi-RAR",
    "url": "https://arxiv.org/abs/2511.09109",
    "title": "Thinking Forward and Backward",
    "description": "Thinking Forward and Backward: Multi-Objective Reinforcement Learning for Retrieval-Augmented Reasoning 现有检索增强推理方法因仅依赖最终答案监督，易导致模型生成冗长低效推理链和幻觉。通过Kolmogorov复杂度理论量化每个推理步骤的双向信息距离——既衡量与答案的接近程度（正向），也评估对问题的契合度（反向），并采用多目标强化学习优化这两个目标：设计级联奖励结构鼓励早期建立正确方向，独立训练正向/反向模型后通过权重插值融合，实现细粒度的步骤级监督，生成更精确简洁的推理过程。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "Process Reward",
      "RAG",
      "Benchmark"
    ],
    "id": 40
  },
  {
    "date": "2025.12",
    "name": "LLDS&MA-GRPO4Search-R1",
    "url": "https://arxiv.org/abs/2512.04220",
    "title": "On GRPO Collapse in Search-R1",
    "description": "On GRPO Collapse in Search-R1: The Lazy Likelihood-Displacement Death Spiral 为了解决再用GRPO训练Search-R1出现突然崩溃的现象，作者发现其核心原因是\"懒惰似然位移\"（LLD）——优化过程中正确与错误响应的似然度均出现停滞或下降，进而引发自我强化的\"LLD死亡螺旋\"，导致低置信度响应、梯度膨胀和训练崩溃。提出轻量级似然保持正则化LLDS，通过响应级门控（仅当轨迹总似然下降时激活）和令牌级选择性（仅惩罚导致下降的令牌），精准抑制LLD且最小化对优化的干扰，其变体LLDS-MA掩码答案令牌以鼓励多步推理。!🌟",
    "codeLinks": [
      "https://github.com/vengdeng/LLDS-On-Group-Relative-Policy-Optimization-Collapse-in-Search-R1"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based"
    ],
    "id": 41
  },
  {
    "date": "2025.12",
    "name": "RouteRAG",
    "url": "https://arxiv.org/abs/2512.09487",
    "title": "RouteRAG",
    "description": "RouteRAG: Efficient Retrieval-Augmented Generation from Text and Graph via Reinforcement Learning 解决RAG缺乏自适应能力：图结构或混合检索系统依赖固定流程，无法像文本RAG那样通过强化学习实现多轮动态检索，难以在推理过程中按需补充证据；检索效率问题：图检索虽对多跳推理至关重要，但计算成本远高于文本检索，现有方法无法根据查询需求灵活选择检索方式，导致不必要的开销；通过Search-R1的范式实现，两阶段RL训练",
    "codeLinks": [
      "https://github.com/YucanGuo/RouteRAG"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "RAG",
      "Multi-hop QA",
      "Benchmark",
      "Token-Efficient"
    ],
    "id": 42
  },
  {
    "date": "2025.12",
    "name": "EKA",
    "url": "https://arxiv.org/abs/2512.20144",
    "title": "Multi-hop Reasoning via Early Knowledge Alignment 现有迭代RAG系统因模型在缺乏检索语料上下文的情况下分解问题，导致初始推理缺乏信息基础，易产生错误检",
    "description": "Multi-hop Reasoning via Early Knowledge Alignment 现有迭代RAG系统因模型在缺乏检索语料上下文的情况下分解问题，导致初始推理缺乏信息基础，易产生错误检索和级联错误。为此提出早期知识对齐（EKA），通过在规划阶段前执行首次检索并将结果注入模型，使其后续强化学习优化的迭代过程具备上下文基础",
    "codeLinks": [
      "https://github.com/yxzwang/EarlyKnowledgeAlignment"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "RL-based",
      "RAG",
      "Multi-hop QA"
    ],
    "id": 43
  },
  {
    "date": "2025.12",
    "name": "Laser",
    "url": "https://arxiv.org/abs/2512.20458",
    "title": "Laser",
    "description": "Laser: Governing Long-Horizon Agentic Search via Structured Protocol and Context Register 基于LLM/LRM的智能体搜索系统面临两个核心瓶颈：自然语言推理的脆弱性和上下文窗口污染溢出，Laser通过符号化动作协议+状态寄存器，将智能体搜索从\"自由发挥的自然语言对话\"转变为\"可解析、可回溯、高效率的结构化程序执行\"，从根本上解决了长程推理的稳定性和可扩展性问题。免训练模式：直接通过提示工程驱动（在Qwen3-8b/32b上表现强劲）；RFT微调：使用拒绝采样微调（Rejection Sampling Fine-Tuning），从强模型（DeepSeek-V3.1）收集高质量结构化轨迹进行蒸馏",
    "codeLinks": [
      "https://github.com/ShootingWong/Laser"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "Memory",
      "Agent",
      "Deep Research",
      "Token-Efficient",
      "Training-free"
    ],
    "id": 44
  },
  {
    "date": "2025.12",
    "name": "HGMem",
    "url": "https://arxiv.org/abs/2512.23959",
    "title": "Improving Multi-step RAG with Hypergraph-based Memory for Long-Context Complex Relational Modeling 把",
    "description": "Improving Multi-step RAG with Hypergraph-based Memory for Long-Context Complex Relational Modeling 把多步 RAG 的“工作记忆”从堆叠孤立事实的被动仓库升级为可动态演化的超图：用超边灵活建模 n 阶关系，通过检索-更新-插入-合并循环让记忆不断长出高阶关联骨架，从而给后续推理提供结构化、全局化的知识支撑，显著提升长文本复杂关系与全局理解任务的效果",
    "codeLinks": [
      "https://github.com/Encyclomen/HGMem"
    ],
    "datasetLinks": [],
    "year": 2025,
    "tags": [
      "Memory",
      "RAG"
    ],
    "id": 45
  },
  {
    "date": "2026.01",
    "name": "ARR",
    "url": "https://arxiv.org/abs/2601.04651",
    "title": "Adversarial Yet Cooperative",
    "description": "Adversarial Yet Cooperative: Multi-Perspective Reasoning in Retrieved-Augmented Language Models 对检索增强推理模型单视角局限和训练信号不足的问题，提出“对抗推理RAG”框架：让推理器与验证器互评逻辑，并用过程感知奖励同时优化两者，无需外部打分即可提升多步推理质量",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Process Reward",
      "RAG"
    ],
    "id": 46
  },
  {
    "date": "2026.01",
    "name": "M-ASK",
    "url": "https://arxiv.org/abs/2601.04703",
    "title": "Beyond Monolithic Architectures",
    "description": "Beyond Monolithic Architectures: A Multi-Agent Search and Knowledge Optimization Framework for Agentic Search 针对当前智能体搜索系统中单一架构智能体存在的推理轨迹冗长、信用分配困难和训练不稳定等问题，该论文提出了M-ASK框架，通过将搜索行为与知识管理解耦为两个专门的智能体角色，并引入轮次级奖励机制进行细粒度监督，从而在多跳问答任务上实现了更高的答案准确率和更稳定的训练动态。",
    "codeLinks": [
      "https://github.com/chenyiqun/M-ASK"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Multi-Agent",
      "Agent",
      "Multi-hop QA"
    ],
    "id": 47
  },
  {
    "date": "2026.01",
    "name": "GRACE",
    "url": "https://arxiv.org/abs/2601.04525",
    "title": "GRACE",
    "description": "GRACE: Reinforcement Learning for Grounded Response and Abstention under Contextual Evidence 针对RAG“无证据也答、证据不足就编”的双重幻觉，用异构检索器自动生成训练样本，再以多阶段门控奖励强化学习，让模型同时学会证据接地与主动弃权，用1/10标注成本实现准确率与拒答率的新平衡",
    "codeLinks": [
      "https://github.com/YiboZhao624/Grace"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "RAG"
    ],
    "id": 48
  },
  {
    "date": "2026.01",
    "name": "SmartSearch",
    "url": "https://arxiv.org/abs/2601.04888",
    "title": "SmartSearch",
    "description": "SmartSearch: Process Reward-Guided Query Refinement for Search Agents 发现 LLM 搜索智能体败在中间查询不准，于是用“过程奖励+双层信用评估”实时给每步查询打分，并只重训劣质查询及其后续轮次；配合“模仿-对齐-泛化”三阶段课程学习，让智能体自优化查询质量，在效率与准确率上全面超越现有基线。",
    "codeLinks": [
      "https://github.com/MYVAE/SmartSearch"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Process Reward",
      "Agent",
      "Search Agent",
      "Token-Efficient"
    ],
    "id": 49
  },
  {
    "date": "2026.01",
    "name": "PRISMA",
    "url": "https://arxiv.org/abs/2601.05465",
    "title": "PRISMA",
    "description": "PRISMA: Reinforcement Learning Guided Two-Stage Policy Optimization in Multi-Agent Architecture for Open-Domain Multi-Hop Question Answering 发现端到端 RL 多跳 RAG 会“检索崩溃”找不到桥接证据，又“信用分配弱”易过拟合，于是把系统拆成 Plan-Retrieve-Inspect-Solve-Memoize 五智能体：Inspector提供基于推理的反馈，精炼规划者的分解方案，并强制要求 Solver 进行基于证据的推理，Solver 必须接地；两阶段：GRPO 先分别把 Planner/Solver 训成专家，再用 OARPO(观察感知残差策略优化)让 Inspector 学会验证据、触发修复",
    "codeLinks": [
      "https://github.com/Ameame1/PRISIMA"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Multi-Agent",
      "Agent",
      "RAG",
      "Multi-hop QA"
    ],
    "id": 50
  },
  {
    "date": "2026.01",
    "name": "CaRR & C-GRPO",
    "url": "https://arxiv.org/abs/2601.06021",
    "title": "Chaining the Evidence",
    "description": "Chaining the Evidence: Robust Reinforcement Learning for Deep Search Agents with Citation-Aware Rubric Rewards 指出深度搜索 RL 只用二元结果奖励会走捷径、编幻觉，于是把复杂提问拆成可验证的单跳“评分细则”，要求智能体显式补全隐藏实体、给出正确引文并串成完整证据链；再配 C-GRPO 算法联合细则奖励与结果奖励训练，全面抑制捷径，提升证据完备性与事实准确率",
    "codeLinks": [
      "https://github.com/THUDM/CaRR"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent"
    ],
    "id": 51
  },
  {
    "date": "2026.01",
    "name": "TreePS-RAG",
    "url": "https://arxiv.org/abs/2601.06922",
    "title": "TreePS-RAG",
    "description": "TreePS-RAG: Tree-based Process Supervision for Reinforcement Learning in Agentic RAG 指出仅用最终奖励做 RL 难以对中间推理步骤信用分配，而离线过程监督又易分布漂移；于是把多步检索-推理展开成 rollout 树，节点即步骤，用后代结局的蒙特卡洛估计在线计算每步优势，无需人工中间标签",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Process Reward",
      "Agent",
      "RAG"
    ],
    "id": 52
  },
  {
    "date": "2026.01",
    "name": "Dr. Zero",
    "url": "https://arxiv.org/abs/2601.07055",
    "title": "Dr. Zero",
    "description": "Dr. Zero: Self-Evolving Search Agents without Training Data 高质量训练数据难获且多轮搜索智能体在“无数据自进化”中问题单一、计算爆炸，于是让同一基模型的“命题者”与“解题者”互搏：命题者不断生成更难却可解的新题，解题者用 hop-grouped 相对策略优化（HRPO）按结构聚类批训，省掉逐题难度评估的采样开销；全程零人工数据，自进化出的智能体在多项任务上追平甚至超越全监督方案",
    "codeLinks": [
      "https://github.com/facebookresearch/drzero"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Self-Play",
      "Agent",
      "Search Agent"
    ],
    "id": 53
  },
  {
    "date": "2026.01",
    "name": "RAGShaper",
    "url": "https://arxiv.org/abs/2601.08699v1",
    "title": "RAGShaper",
    "description": "RAGShaper: Eliciting Sophisticated Agentic RAG Skills via Automated Data Synthesis 针对 Agentic RAG 系统缺乏“带噪声”训练数据的痛点，提出 RAGShaper 框架：先用 InfoCurator 围绕种子实体检索并生成感知-认知两级干扰文档，再让教师智能体在“受限导航”下完成多跳问答，自动产出含纠错、抗噪行为的轨迹，无需人工标注即可大规模合成高质量训练数据。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "RAG",
      "Multi-hop QA"
    ],
    "id": 54
  },
  {
    "date": "2026.01",
    "name": "EvoFSM",
    "url": "https://arxiv.org/abs/2601.09465",
    "title": "EvoFSM",
    "description": "EvoFSM: Controllable Self-Evolution for Deep Research with Finite State Machines 把自演化从易失控的“自由改代码”收束到显式有限状态机，将优化空间解耦为宏观 Flow（状态转移）与微观 Skill（状态行为），用批评机制指导少量受控操作迭代 FSM，并配自我演化记忆库，把成功轨迹转为可复用先验、失败模式转为约束",
    "codeLinks": [
      "https://github.com/QuantaAlpha/EvoFSM"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Deep Research"
    ],
    "id": 55
  },
  {
    "date": "2026.01",
    "name": "DR-Arena",
    "url": "https://arxiv.org/abs/2601.10504",
    "title": "DR-Arena",
    "description": "DR-Arena: an Automated Evaluation Framework for Deep Research Agents 该文章针对大型语言模型作为深度研究（DR）智能体的可靠评估难题，提出了DR-Arena框架——通过实时构建动态信息树、自动生成深度推理与广度覆盖任务，并引入自适应演化循环动态提升任务复杂度，实现了与LMSYS Search Arena人类偏好排名0.94的Spearman相关性，为深度研究智能体提供了无需人工干预的可扩展自动化评估方案。",
    "codeLinks": [
      "https://github.com/iNLP-Lab/DR-Arena"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 56
  },
  {
    "date": "2026.01",
    "name": "BAPO",
    "url": "https://arxiv.org/abs/2601.11037",
    "title": "BAPO",
    "description": "BAPO: Boundary-Aware Policy Optimization for Reliable Agentic Search 用 RL 驱动的搜索智能体虽能迭代检索、提升答案准确率，却普遍缺乏“自知之明”——在证据不足或推理到头时仍强行给出看似合理却不可靠的答案，极少主动回答“我不知道”(IDK)，给高风险场景带来隐患。提出 BAPO（Boundary-Aware Policy Optimization）框架，通过两项机制实现“边界感知”：基于组对比的边界奖励——仅当同组内多条轨迹均无法逼近正确答案时才给 IDK 正向信号，避免误奖；自适应奖励调制器——训练初期暂停该奖励，防止 agent 把 IDK 当捷径滥用。",
    "codeLinks": [
      "https://github.com/Liushiyu-0709/BAPO-Reliable-Search"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent"
    ],
    "id": 57
  },
  {
    "date": "2026.01",
    "name": "Agentic-R",
    "url": "https://arxiv.org/abs/2601.11888",
    "title": "Agentic-R",
    "description": "Agentic-R: Learning to Retrieve for Agentic Search 现有“搜索智能体”多轮检索依赖的仍是面向单轮 RAG 的相似度检索器，无法保证中间 passage 既局部相关又最终导向正确答案，亟需专为多轮 agentic search 定制的检索器。把检索器从“单轮相似”升级为“多轮有用”：先用 LLM 打分衡量局部相关，再用“代入该段落能否推得最终正确答案”衡量全局贡献，自动构建正负例做对比学习；同时让搜索 agent 与检索器双向迭代，agent 产出更高质量查询反哺检索器，两轮后得到跨 agent 通用、EM 提升且减少 10–15% 搜索步数的“自我进化”检索器。",
    "codeLinks": [
      "https://github.com/8421BCD/Agentic-R"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Self-Play",
      "Agent",
      "RAG",
      "Search Agent"
    ],
    "id": 58
  },
  {
    "date": "2026.01",
    "name": "SearchGym",
    "url": "https://arxiv.org/abs/2601.14615",
    "title": "SearchGym",
    "description": "SearchGym: Bootstrapping Real-World Search Agents via Cost-Effective and High-Fidelity Environment Simulation 通过构建高保真模拟环境解决搜索智能体训练中的数据不对齐问题，用可验证知识图谱和对齐语料库替代昂贵的真实API交互，在此基础上引入SearchGym-RL，一种课程学习方法，通过纯化反馈逐步优化智能体策略，从基本交互发展到复杂的长远规划。",
    "codeLinks": [
      "https://github.com/JIA-Lab-research/SearchGym"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent"
    ],
    "id": 59
  },
  {
    "date": "2026.01",
    "name": "SAGE",
    "url": "https://arxiv.org/abs/2601.18202v1",
    "title": "SAGE",
    "description": "SAGE: Steerable Agentic Data Generation for Deep Search with Execution Feedback 深度搜索智能体需要跨文档多跳推理，但人工标注长轨迹成本极高，现有合成数据又难控难度与质量，导致训练样本稀缺且分布失衡。提出 SAGE——可转向的 Agentic 数据生成 pipeline：生成器先草拟 QA → 搜索 agent 实跑轨迹给出“能否答对、难度是否匹配”的执行反馈 → 生成器据此多轮精修问题与答案，直至满足预设难度。 intrinsic 评估显示生成题需多样策略且难度/正确率显著提升；extrinsic 上，用 SAGE 数据训练的 agent 在主流深度搜索基准获最高 23 % 相对提升，并可零样本迁移到 Google 搜索",
    "codeLinks": [
      "https://github.com/carriex/sage"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Multi-hop QA",
      "Benchmark"
    ],
    "id": 60
  },
  {
    "date": "2026.01",
    "name": "PaperSearchQA",
    "url": "https://arxiv.org/abs/2601.18207v1",
    "title": "PaperSearchQA",
    "description": "PaperSearchQA: Learning to Search and Reason over Scientific Papers with RLVR 现有 RLVR 搜索智能体只在通用 QA 上验证“最终答案对不对”，缺乏面向科学文献的深层技术问答，难以满足科研工作者与未来“AI 科学家”的真实需求。如何构建大规模、可验证reward 的科学文献搜索环境，让智能体学会在 1600 万篇生物医学摘要里做复杂检索与推理，并系统评估其规划、自检等能力。发布 PaperSearchQA——含 1600 万摘要的搜索语料 + 6 万可验证事实问答对 + 评测基准；基于 Search-R1 框架训练智能体，以“最终答案 EM”为可验证奖励，显著优于非 RL 检索基线，并展现出规划、推理、自验证等可解释行为；数据与代码全部开源，且创建流程可低成本扩展到其他科学领域",
    "codeLinks": [
      "https://github.com/jmhb0/PaperSearchQA"
    ],
    "datasetLinks": [
      "https://huggingface.co/datasets/jmhb/PaperSearchQA"
    ],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent",
      "Benchmark",
      "Open-Source"
    ],
    "id": 61
  },
  {
    "date": "2026.01",
    "name": "Dep-Search",
    "url": "https://arxiv.org/abs/2601.18771v1",
    "title": "Dep-Search",
    "description": "Dep-Search: Learning Dependency-Aware Reasoning Traces with Persistent Memory 现有“搜索+推理”框架全靠隐式自然语言串来决策搜什么、怎么用，导致子问题依赖关系混乱、旧知识无法重用、RL 信号稀疏，难以学会最优搜索策略。提出 Dep-Search，用依赖感知的结构化分解将主问题拆成带先后依赖的子图，引入持久记忆库保存已获事实；通过 GRPO 联合优化“何时检索/复用记忆/更新记忆”的显式动作，实现依赖-检索-记忆一体化控制，在 7 个 QA 数据集上显著超越强基线。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Memory",
      "Dataset"
    ],
    "id": 62
  },
  {
    "date": "2026.01",
    "name": "Yunque DeepResearch",
    "url": "https://arxiv.org/pdf/2601.19578",
    "title": "Yunque DeepResearch Technical Report 针对DeepResearch在长程任务中面临的上下文噪声累积、系统脆弱性导致级联错误、以及缺乏模块化可扩展性等关键限制，提出了",
    "description": "Yunque DeepResearch Technical Report 针对DeepResearch在长程任务中面临的上下文噪声累积、系统脆弱性导致级联错误、以及缺乏模块化可扩展性等关键限制，提出了Yunque DeepResearch框架。设计了一个层次化、模块化且鲁棒的架构，包含三个核心组件：集中式多智能体编排系统将子任务路由到原子能力池的工具和专用子代理；动态上下文管理机制将完成的子目标结构化为语义摘要以缓解信息过载；主动监督模块通过异常检测和上下文剪枝确保系统韧性。",
    "codeLinks": [
      "https://github.com/Tencent-BAC/YunqueAgent"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Multi-Agent",
      "Agent",
      "Deep Research"
    ],
    "id": 63
  },
  {
    "date": "2026.01",
    "name": "ProRAG",
    "url": "https://arxiv.org/abs/2601.21912v1",
    "title": "ProRAG",
    "description": "ProRAG: Process-Supervised Reinforcement Learning for Retrieval-Augmented Generation 通过MCTS构建过程奖励模型并引入双粒度优势机制，解决了长程多跳RAG任务中基于结果的RL奖励稀疏和信用分配困境，在5个多跳推理基准上显著超越强基线，特别在处理复杂长程任务时表现出优秀的鲁棒性和泛化能力。",
    "codeLinks": [
      "https://github.com/lilinwz/ProRAG"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Process Reward",
      "RAG",
      "Multi-hop QA",
      "Deep Research",
      "Benchmark"
    ],
    "id": 64
  },
  {
    "date": "2026.01",
    "name": "JADE",
    "url": "https://arxiv.org/abs/2601.21916v1",
    "title": "JADE",
    "description": "JADE: Bridging the Strategic-Operational Gap in Dynamic Agentic RAG * 动机：现有 Agentic RAG 范式面临关键二分困境：要么在刚性固定图架构内联合优化模块（静态联合优化），丧失动态适应能力；要么赋予动态规划能力却将执行器视为冻结黑盒（动态解耦优化），导致\"战略-运营不匹配\"——规划器设计的精妙策略因执行器未协同训练而无法实现，反而造成负面性能收益且增加系统复杂度。 1. 静态方法（如 MMOA-RAG）受限于固定工作流程，无法处理需要多变推理路径的复杂多跳查询； 2. 解耦方法（如 MAO-ARAG）仅优化规划器而冻结执行器，导致规划与实际执行能力脱节； 3. 单体方法（如 Search-R1）虽提供端到端灵活性，但缺乏结构先验导致训练不稳定，在巨大上下文窗口中同时学习推理、查询和过滤会陷入优化困境。 * 提出的方法： JADE（Joint Agentic Dynamic Execution），核心包括： 1. 参数共享的 MSMDP 建模：将动态 RAG 建模为多智能体半马尔可夫决策过程，规划器和执行器（查询重写、文档选择、答案生成等）共享同一个 LLM 主干，通过角色特定提示区分功能； 2. 统一经验回放缓冲：将异构的规划和执行转移数据聚合到共享缓冲区，使用 PPO 进行端到端联合优化； 3. 双层奖励机制：全局共享奖励（最终答案质量减去计算成本）促进团队协作解决信用分配问题，局部格式惩罚确保各角色输出结构合规； 4. 动态工作流编排：规划器根据查询复杂度自适应选择\"串行分解\"、\"并行分解\"或\"直接求解\"等工作流拓扑。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Multi-Agent",
      "Agent",
      "RAG",
      "Multi-hop QA"
    ],
    "id": 65
  },
  {
    "date": "2026.01",
    "name": "DeepSearchQA",
    "url": "https://arxiv.org/abs/2601.20975",
    "title": "DeepSearchQA",
    "description": "DeepSearchQA: Bridging the Comprehensiveness Gap for Deep Research Agents 通过引入 900 个要求生成完整答案集的多步骤检索任务，解决了现有单答案基准无法评估的\"全面性缺口\"问题（包括系统整理、实体去重和停止准则推理），采用 F1 分数等严格指标对深度研究智能体进行基于结果的评估，揭示了即使最先进的 Gemini Deep Research Agent 和 GPT-5 Pro 在平衡召回率与精确率（F1 约 81-82%）及完全正确率（约 66%）方面仍存在显著局限性。",
    "codeLinks": [],
    "datasetLinks": [
      "https://www.kaggle.com/benchmarks/google/dsqa/leaderboard"
    ],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 66
  },
  {
    "date": "2026.02",
    "name": "InfoReasoner",
    "url": "https://arxiv.org/abs/2602.00845",
    "title": "Optimizing Agentic Reasoning with Retrieval via Synthetic Semantic Information Gain Reward 针对智能体推理中检",
    "description": "Optimizing Agentic Reasoning with Retrieval via Synthetic Semantic Information Gain Reward 针对智能体推理中检索优化缺乏密集奖励信号的问题，提出了一种基于合成语义信息增益奖励的统一框架；理论上将信息增益重新定义为模型信念状态的不确定性减少，实践上通过双向文本蕴含的语义聚类设计输出感知的内在估计器，无需人工标注即可直接从输出分布计算奖励",
    "codeLinks": [
      "https://github.com/dl-m9/InfoReasoner"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Benchmark"
    ],
    "id": 67
  },
  {
    "date": "2026.02",
    "name": "RE-TRAC",
    "url": "https://arxiv.org/abs/2602.02486",
    "title": "RE-TRAC",
    "description": "RE-TRAC: REcursive TRAjectory Compression for Deep Search Agents 针对当前基于大语言模型（LLM）的深度研究代理在执行复杂信息检索任务时存在的局限性展开，动机源于主流的ReAct框架采用线性推理结构，难以回溯先前状态、探索替代路径或在长上下文下保持全局感知，容易陷入局部最优、重复探索和低效搜索。要解决的核心问题是如何突破ReAct框架的线性限制，实现跨轨迹的有效探索与全局感知，以提升深度研究代理的信息收集与推理效率。为解决该问题，作者提出了**RE-TRAC**（REcursive TRAjectory Compression），一种通过在每条搜索轨迹后生成结构化状态表示来总结证据、不确定性、失败原因及未来计划，并将后续轨迹建立在此状态表示之上的新型代理框架，从而支持迭代反思和全局引导的规划。该方法通过轨迹压缩机制实现递归状态更新，使研究过程更具渐进性和目标导向性。",
    "codeLinks": [
      "https://github.com/microsoft/InfoAgent"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Token-Efficient"
    ],
    "id": 68
  },
  {
    "date": "2026.02",
    "name": "DAS",
    "url": "https://arxiv.org/abs/2602.03304v1",
    "title": "To Search or Not to Search",
    "description": "To Search or Not to Search: Aligning the Decision Boundary of Deep Search Agents via Causal Intervention 如何诊断和纠正深度搜索智能体的决策边界错位问题（包括过度搜索和搜索不足），即确定何时积累的信息足以回答的阈值；提出DAS（Decision Boundary Alignment for Deep Search agents）框架，包含两个关键组件：一是基于因果干预的诊断方法，通过在每个决策点比较事实轨迹和反事实轨迹来识别边界错误；二是构建来自因果反馈的偏好数据集并通过偏好优化对齐策略，从而有效校准决策边界，缓解过度搜索和搜索不足问题。",
    "codeLinks": [
      "https://github.com/Applied-Machine-Learning-Lab/WWW2026_DAS"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Dataset"
    ],
    "id": 69
  },
  {
    "date": "2026.02",
    "name": "A-RAG",
    "url": "https://arxiv.org/abs/2602.03442v1",
    "title": "A-RAG",
    "description": "A-RAG: Scaling Agentic Retrieval-Augmented Generation via Hierarchical Retrieval Interfaces 现有RAG系统仍依赖两种范式（单次检索后拼接输入或预定义工作流逐步执行），这些范式不允许模型参与检索决策，无法随着模型能力提升而有效扩展；提出A-RAG框架，通过将分层检索接口直接暴露给模型，提供关键词搜索、语义搜索和块读取三种检索工具，使智能体能够在多个粒度上自适应地搜索和检索信息，从而有效利用模型能力并动态适应不同RAG任务。",
    "codeLinks": [
      "https://github.com/Ayanami0730/arag"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "RAG",
      "Benchmark"
    ],
    "id": 70
  },
  {
    "date": "2026.02",
    "name": "Search-R2",
    "url": "https://arxiv.org/abs/2602.03647v1",
    "title": "Search-R2",
    "description": "Search-R2: Enhancing Search-Integrated Reasoning via Actor-Refiner Collaboration 搜索集成推理使语言智能体能够超越静态参数知识主动查询外部信息源，但通过强化学习训练这些智能体时面临多尺度信用分配问题（现有方法依赖稀疏的轨迹级奖励，无法区分高质量推理和偶然猜测，导致冗余或误导性的搜索行为）；提出Search-R2框架，通过Actor-Refiner协作机制增强推理，其中Actor生成初始推理轨迹，Meta-Refiner通过\"剪切-再生\"机制选择性诊断和修复缺陷步骤，并引入结合结果正确性与证据信息密度的混合奖励设计，将Actor-Refiner交互形式化为平滑混合策略，证明选择性修正能严格优于强基线。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Multi-Agent",
      "Agent"
    ],
    "id": 71
  },
  {
    "date": "2026.02",
    "name": "BAR-RAG",
    "url": "https://arxiv.org/abs/2602.03689v1",
    "title": "Rethinking the Reranker",
    "description": "Rethinking the Reranker: Boundary-Aware Evidence Selection for Robust Retrieval-Augmented Generation 检索增强生成（RAG）系统依赖重排序器（reranker）从检索到的文档中选择最相关的证据，但现有方法忽视了检索文档与查询之间的边界关系，导致在证据选择时无法有效区分真正相关的文档和噪声文档；提出边界感知证据选择方法（Boundary-Aware Evidence Selection），通过引入边界感知机制来显式建模文档与查询之间的边界关系，实现更鲁棒的证据选择，提升检索增强生成系统在存在噪声文档时的性能。Reranker变成Selector。",
    "codeLinks": [
      "https://github.com/GasolSun36/BAR-RAG"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RAG",
      "Benchmark"
    ],
    "id": 72
  },
  {
    "date": "2026.02",
    "name": "BranPO",
    "url": "https://arxiv.org/abs/2602.03719v1",
    "title": "Training Multi-Turn Search Agent via Contrastive Dynamic Branch Sampling 现有的智能体强化学习在长周期多轮任务中面临稀疏轨迹级奖",
    "description": "Training Multi-Turn Search Agent via Contrastive Dynamic Branch Sampling 现有的智能体强化学习在长周期多轮任务中面临稀疏轨迹级奖励带来的学习困难，而基于树的方法虽然试图缓解此问题但存在高方差和计算效率低下的缺陷，作者通过经验分析发现性能差异主要由轨迹尾部附近的决策造成；提出分支相对策略优化（BranPO），通过截断轨迹尾部并重新采样替代延续来构建共享前缀上的对比后缀，结合难度感知分支采样和冗余步骤掩码技术，实现了无需价值模型的高效稳定训练。",
    "codeLinks": [
      "https://github.com/YubaoZhao/BranPO"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent",
      "Token-Efficient"
    ],
    "id": 73
  },
  {
    "date": "2026.02",
    "name": "DeepRead",
    "url": "https://arxiv.org/abs/2602.05014v1",
    "title": "DeepRead",
    "description": "DeepRead: Document Structure-Aware Reasoning to Enhance Agentic Search 现有的智能体搜索系统（如Search-o1-style）在处理文档问答任务时，未能充分利用文档的结构信息，导致在理解和推理复杂文档内容时效率低下；DeepRead框架，通过引入文档结构感知的推理机制来增强智能体搜索能力，使系统能够理解和利用文档的层次结构、章节关系等结构信息，从而显著提升文档问答任务的性能。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Token-Efficient"
    ],
    "id": 74
  },
  {
    "date": "2026.02",
    "name": "SAGE",
    "url": "https://arxiv.org/abs/2602.05975",
    "title": "SAGE",
    "description": "SAGE: Benchmarking and Improving Retrieval for Deep Research Agents 现有深度研究智能体（deep research agents）在复杂信息寻求任务中依赖检索系统，但缺乏系统性的研究来深入理解这些智能体的检索行为，特别是在需要深度推理的科学文献搜索任务中；SAGE（Scientific AGentic retrieval Evaluation）基准测试框架，包含1,200个查询和20万篇论文的科学文献语料库，涵盖四种科学领域，同时提出一种语料库级别的测试时扩展框架，通过利用LLM推理为每篇论文生成信息丰富的元数据和关键词来丰富语料库，使现成的检索器更容易找到相关论文。",
    "codeLinks": [
      "https://github.com/HughieHu/Sage"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 75
  },
  {
    "date": "2026.02",
    "name": "DLLM-Searcher",
    "url": "https://arxiv.org/abs/2602.07035",
    "title": "DLLM-Searcher",
    "description": "DLLM-Searcher: Adapting Diffusion Large Language Model for Search Agents 第一个dLLM Search Agent。针对扩散大语言模型推理和工具调用能力弱、ReAct 范式串行执行导致端到端延迟严重的问题，提出两阶段后训练（Agentic SFT 增强信息搜索与推理能力，Agentic VRPO 进一步提升智能体能力）和 P-ReAct 并行推理与行动范式（优先解码工具调用指令，在等待工具返回时持续思考实现并行化），使 dLLM 搜索智能体达到与主流 LLM 智能体相当性能并实现约 15% 推理加速。",
    "codeLinks": [
      "https://github.com/bubble65/DLLM-Searcher"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "SFT",
      "Agent",
      "Search Agent"
    ],
    "id": 76
  },
  {
    "date": "2026.02",
    "name": "SCOUT-RAG",
    "url": "https://arxiv.org/abs/2602.08400v1",
    "title": "SCOUT-RAG",
    "description": "SCOUT-RAG: Scalable and Cost-Efficient Unifying Traversal for Agentic Graph-RAG over Distributed Domains 传统 Graph-RAG（基于知识图谱的检索增强生成）依赖集中式知识图谱设计，但在以下场景面临挑战：分布式环境：数据分散在不同领域（如医院、跨国组织）；访问受限：无法获得全局图谱可见性；成本敏感：无法承受穷举式查询的高昂开销。需要在无全局可见性和避免穷举查询的约束下，智能选择相关领域并确定合适的遍历深度。渐进式跨领域检索：基于增量效用目标引导检索过程，而非一次性穷举；四智能体协作系统 ① 领域相关性估计 — 判断哪些领域可能包含相关信息 ② 扩展决策 — 决定何时扩展到额外领域 ③ 深度自适应 — 动态调整遍历深度，避免不必要的图谱探索 ④ 答案合成 — 整合检索结果生成高质量答案",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Multi-Agent",
      "Agent",
      "RAG"
    ],
    "id": 77
  },
  {
    "date": "2026.02",
    "name": "GISA",
    "url": "https://arxiv.org/abs/2602.08543v1",
    "title": "GISA",
    "description": "GISA: A Benchmark for General Information-Seeking Assistant 本研究旨在解决现有信息检索代理评估基准中存在的诸多问题，如任务设计不贴近真实用户需求、依赖反向构建查询导致的不自然性、以及静态答案集易受数据污染等；为实现这一目标，GISA采用了由人工精心设计的373个真实信息寻求查询，并引入四种结构化答案格式（项目、集合、列表和表格），支持确定性度量评估；同时构建了一个包含完整人类搜索轨迹的数据集，可用于过程级监督与模仿学习，并设立定期更新的动态子集以抵抗模型记忆",
    "codeLinks": [
      "https://github.com/RUC-NLPIR/GISA"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Benchmark",
      "Dataset"
    ],
    "id": 78
  },
  {
    "date": "2026.02",
    "name": "SIGHT",
    "url": "https://arxiv.org/abs/2602.11551",
    "title": "SIGHT",
    "description": "SIGHT: Reinforcement Learning with Self-Evidence and Information-Gain Diverse Branching for Search Agent 针对多轮搜索场景中搜索结果高冗余、低信噪比以及智能体被迫解释早期嘈杂结果导致的\"隧道视野\"问题，SIGHT 提出自证据支持机制将搜索结果蒸馏为高保真证据，并通过信息增益分数驱动多样化分支动态干预（去重、反思或自适应分支），结合 GRPO 训练整合自证据和正确性奖励，使模型无需外部验证器即可内化稳健探索策略",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent"
    ],
    "id": 79
  },
  {
    "date": "2026.02",
    "name": "DualGraph",
    "url": "https://arxiv.org/abs/2602.13830v1",
    "title": "A Tale of Two Graphs",
    "description": "A Tale of Two Graphs: Separating Knowledge Exploration from Outline Structure for Open-Ended Deep Research 针对开放式深度研究中\"搜索-然后生成\"线性累积导致的\"迷失在中间\"问题，以及大纲中心规划仅从大纲隐式推断知识缺口导致的弱监督问题，DualGraph 提出将知识探索与大纲结构分离的双图架构，通过大纲图捕获报告结构、知识图存储细粒度知识单元及其关系，联合分析两图拓扑生成针对性搜索查询，实现迭代知识驱动探索",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Deep Research"
    ],
    "id": 80
  },
  {
    "date": "2026.02",
    "name": "REDSearcher",
    "url": "https://arxiv.org/abs/2602.14234v1",
    "title": "REDSearcher",
    "description": "REDSearcher: A Scalable and Cost-Efficient Framework for Long-Horizon Search Agents 提出了 REDSearcher，一个统一框架，协同设计复杂任务合成、中期训练和后期训练：1. 任务合成：将任务合成建模为双约束优化，通过图拓扑和证据分散度精确控制任务难度，实现复杂高质量任务的可扩展生成；2. 工具增强查询：引入工具增强查询，鼓励主动使用工具而非被动回忆；3. 中期训练：强化核心原子能力（知识、规划、函数调用），大幅降低下游训练收集高质量轨迹的成本；4. 本地模拟环境：构建本地模拟环境，实现快速、低成本的强化学习算法迭代。实验结果：在纯文本和多模态搜索智能体基准测试中均达到最先进性能。开源贡献：将发布10K高质量复杂文本搜索轨迹、5K多模态轨迹和1K文本RL查询集，以及代码和模型检查点。",
    "codeLinks": [
      "https://github.com/RedSearchAgent/REDSearcher"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark",
      "Open-Source"
    ],
    "id": 81
  },
  {
    "date": "2026.02",
    "name": "ASQ",
    "url": "https://arxiv.org/abs/2602.17518v1",
    "title": "A Picture of Agentic Search 随着自动化搜索查询日益增多，信息检索系统面临范式转变，但现有工具仍以人为中心，导致性能评估与优化脱节。为此，本研究聚焦于缺乏智能体搜索行为数据集",
    "description": "A Picture of Agentic Search 随着自动化搜索查询日益增多，信息检索系统面临范式转变，但现有工具仍以人为中心，导致性能评估与优化脱节。为此，本研究聚焦于缺乏智能体搜索行为数据集这一核心问题，提出了一种系统性方法，收集推理增强检索中的全流程数据，并构建了Agentic Search Queryset（ASQ）数据集。该数据集基于HotpotQA、Researchy Questions和MS MARCO任务，包含智能体的查询、文档及内部推理，覆盖3类智能体和2种检索流程，旨在推动系统对新型代理用户的适应。",
    "codeLinks": [
      "https://github.com/fpezzuti/ASQ"
    ],
    "datasetLinks": [
      "https://huggingface.co/datasets/AgenticSearchQueryset/ASQ"
    ],
    "year": 2026,
    "tags": [
      "Agent",
      "Dataset"
    ],
    "id": 82
  },
  {
    "date": "2026.02",
    "name": "RVR",
    "url": "https://arxiv.org/abs/2602.18425v1",
    "title": "RVR",
    "description": "RVR: Retrieve-Verify-Retrieve for Comprehensive Question Answering 针对多答案查询需要全面检索多样化文档的问题，RVR 提出\"检索-验证-再检索\"多轮迭代框架，通过验证器筛选高质量子集并将已验证文档增强到查询中启动下一轮检索以发现未覆盖答案，即使使用现成检索器也有效且微调后性能进一步提升",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Multi-hop QA"
    ],
    "id": 83
  },
  {
    "date": "2026.02",
    "name": "Search-R1++",
    "url": "https://arxiv.org/abs/2602.19526v1",
    "title": "How to Train Your Deep Research Agent? Prompt, Reward, and Policy Optimization in Search-R1 通过解耦分析提示",
    "description": "How to Train Your Deep Research Agent? Prompt, Reward, and Policy Optimization in Search-R1 通过解耦分析提示模板、奖励函数和策略优化三个维度，来构建更可靠且高效的RL训练框架。作者采用包括：对比不同思维模式的提示模板（Fast Thinking vs. Slow Thinking）、设计并评估基于EM（Exact Match）和F1的奖励函数，并引入动作级惩罚机制以缓解答案回避问题，同时比较REINFORCE、PPO和GRPO等主流策略优化算法的表现。实验结果表明，Fast Thinking模板更具稳定性，F1奖励因训练崩溃表现不佳但可通过动作级惩罚改善，而REINFORCE在减少搜索步数的同时优于PPO，GRPO则稳定性最差。基于这些发现，作者提出了改进基线模型Search-R1++，显著提升了原有Search-R1在Qwen2.5-7B和Qwen2.5-3B上的性能。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent",
      "Deep Research"
    ],
    "id": 84
  },
  {
    "date": "2026.02",
    "name": "Search-P1",
    "url": "https://arxiv.org/abs/2602.22576",
    "title": "Search-P1",
    "description": "Search-P1: Path-Centric Reward Shaping for Stable and Efficient Agentic RAG Training 针对智能体 RAG 训练中稀疏结果奖励丢弃中间学习信号、失败样本无法贡献信号导致低样本效率的问题，Search-P1 提出路径中心奖励塑形框架，通过不依赖顺序的步骤覆盖率评估轨迹结构质量，使用软评分机制从失败样本提取学习信号，并结合参考规划器从自洽性和参考对齐双轨评估路径质量，在多个问答基准上相比强基线实现平均 7.7 个百分点准确率提升。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "RAG",
      "Benchmark",
      "Token-Efficient"
    ],
    "id": 85
  },
  {
    "date": "2026.03",
    "name": "DeepResearch-9K",
    "url": "https://arxiv.org/abs/2603.01152v1",
    "title": "DeepResearch-9K",
    "description": "DeepResearch-9K: A Challenging Benchmark Dataset of Deep-Research Agent 研究旨在解决当前深度研究型智能体（deep-research agents）发展中面临的两大瓶颈：一是缺乏具有真实世界难度的大规模、高挑战性数据集，二是缺少开放、可复用的数据合成与智能体训练框架。为此，论文构建了一个名为 DeepResearch-9K 的大规模基准数据集，该数据集包含 9000 个涵盖 L1 到 L3 三个难度级别的多跳问答问题，均由开源多跳 QA 数据集通过低成本自主流水线生成，并附有来自先进智能体 Tongyi-DeepResearch-30B-A3B 生成的高质量搜索轨迹、推理链和可验证答案。为支持智能体训练，作者进一步开发了开源训练框架 DeepResearch-R1，该框架支持多轮网页交互、多种强化学习（RL）方法以及包括基于规则的结果奖励和大语言模型作为评判者（LLM-as-judge）在内的多种奖励建模机制",
    "codeLinks": [
      "https://github.com/Applied-Machine-Learning-Lab/DeepResearch-R1"
    ],
    "datasetLinks": [
      "https://huggingface.co/datasets/artillerywu/DeepResearch-9K"
    ],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent",
      "Multi-hop QA",
      "Deep Research",
      "Benchmark",
      "Dataset",
      "Open-Source"
    ],
    "id": 86
  },
  {
    "date": "2026.03",
    "name": "OBM",
    "url": "https://arxiv.org/abs/2603.01416v1",
    "title": "Securing the Floor and Raising the Ceiling",
    "description": "Securing the Floor and Raising the Ceiling: A Merging-based Paradigm for Multi-modal Search Agents 该研究旨在解决当前多模态搜索智能体在构建过程中依赖大规模监督轨迹或昂贵的强化学习（RL）所带来的高训练成本、不稳定性以及标准视觉-语言模型（VLMs）面临的严重冷启动问题。论文要解决的核心问题是：如何在无需额外多模态训练数据的前提下，赋予VLMs自主调用外部搜索工具并进行多步推理的多模态搜索能力。为此，作者提出了一种无需训练的新范式——跨模态模型合并（cross-modal model merging），通过将一个基于文本的搜索智能体与基础VLM在参数级别上融合，实现多模态搜索能力的有效组合；同时，为缓解跨模态融合过程中的参数干扰，引入了一种基于显著性的合并算法Optimal Brain Merging（OBM），该方法利用少量校准样本根据参数对模型损失的影响来识别任务关键参数",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent"
    ],
    "id": 87
  },
  {
    "date": "2026.03",
    "name": "AgentIR",
    "url": "https://arxiv.org/abs/2603.04384v1",
    "title": "AgentIR",
    "description": "AgentIR: Reasoning-Aware Retrival for Deep Research Agents 与动机相似，需要适配Search Agent的检索器。现有检索模型在处理这类智能体发出的查询时，忽略了其在每次搜索前生成的自然语言推理痕迹中蕴含的丰富意图和上下文信息。为此，论文旨在解决如何有效利用这些推理轨迹以提升检索性能这一核心问题。为实现这一目标，作者提出了**Reasoning-Aware Retrieval**这一新范式，通过联合嵌入智能体的推理过程与查询来增强检索效果，并设计了数据合成方法**DR-Synth**，将标准问答数据集（如WebShaper）自动转换为适用于深度研究场景的训练样本。",
    "codeLinks": [
      "https://github.com/texttron/AgentIR"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark",
      "Dataset"
    ],
    "id": 88
  },
  {
    "date": "2026.03",
    "name": "MPW",
    "url": "https://arxiv.org/abs/2603.04751v1",
    "title": "Evaluating the Search Agent in a Parallel World 理想公司的工作。旨在解决当前对具备网页搜索能力的LLM代理（Search Agents）进行有效评估所面",
    "description": "Evaluating the Search Agent in a Parallel World 理想公司的工作。旨在解决当前对具备网页搜索能力的LLM代理（Search Agents）进行有效评估所面临的多重挑战，**研究动机**源于现有评估方法在动态性、可靠性和科学性上的不足：静态基准易因互联网信息演变而过时（如“难度坍塌”和“事实漂移”），难以区分模型是依赖参数记忆还是真实搜索与推理能力，且高质量人工标注成本高昂。为此，论文要**解决的核心问题**是如何构建一个可复现、抗时效干扰、能准确衡量搜索代理真实检索与推理能力的评估框架。为应对这些问题，作者**采用的主要方法/技术**是提出Mind-ParaWorld（MPW）框架，该框架通过采样现实世界实体生成超越模型知识截止时间的“未来场景与问题”，利用“平行世界法则模型”构建不可分割的原子事实和唯一真值，并引入“平行世界引擎模型”（PEM）动态生成基于这些原子事实的SERP式证据，使代理在封闭可控的虚拟环境中完成交互式搜索任务。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Benchmark"
    ],
    "id": 89
  },
  {
    "date": "2026.03",
    "name": "KARL",
    "url": "https://arxiv.org/abs/2603.05218v1",
    "title": "KARL",
    "description": "KARL: Knowledge Agents via Reinforcement Learning 该研究旨在应对企业级知识代理在复杂、多步骤的“基于证据的推理”（grounded reasoning）任务中表现不足的问题，尤其是在依赖专有数据且难以验证结果的场景下，现有模型缺乏系统性评估和有效训练方法（研究动机）。为此，论文聚焦于提升知识代理在多样化、高难度的企业搜索任务中的综合性能，并解决模型在分布外任务上的泛化能力与训练效率问题（解决的核心问题）。为实现这一目标，作者提出KARL——一种基于迭代大规模离线强化学习（iterative large-batch off-policy RL）的后训练范式，结合一个具备长视野推理和工具调用能力的代理合成管道（agentic synthesis pipeline），通过不断迭代生成高质量、多样化的合成训练数据来驱动多任务强化学习（采用的主要方法/技术）",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Deep Research",
      "Token-Efficient"
    ],
    "id": 90
  },
  {
    "date": "2026.03",
    "name": "DeepFact",
    "url": "https://arxiv.org/abs/2603.05912v1",
    "title": "DeepFact",
    "description": "DeepFact: Co-Evolving Benchmarks and Agents for Deep Research Factuality 旨在解决搜索增强型大语言模型代理生成的深度研究报道（DRRs）中声明级事实性验证困难的问题，其研究动机源于现有事实核查工具主要针对通用领域、原子化的简单事实，缺乏适用于复杂、多跳科学推理场景的评估基准，且静态专家标注的基准在实践中表现出脆弱性。论文要解决的核心问题是：如何构建一个可靠、可进化的DRR事实性评测基准，并开发能有效验证此类复杂报告事实性的方法。为此，作者提出了一种名为“先审计后评分”（Audit-then-Score, AtS）的演进式基准构建框架，该方法允许验证器对当前基准提出异议并提交证据，由专家作为审计员裁决争议，若提议被接受则更新基准标签和理由，从而实现基准的动态演化。基于此框架，作者构建了DeepFact-Bench——一个带可审计理由的版本化DRR事实性基准，并设计了DeepFact-Eval——一种文档级验证代理（及其轻量分组变体），用于评估DRR的事实一致性。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Multi-hop QA",
      "Deep Research",
      "Benchmark"
    ],
    "id": 91
  },
  {
    "date": "2026.03",
    "name": "WeDAS",
    "url": "https://arxiv.org/abs/2603.07241v1",
    "title": "Rethinking Deep Research from the Perspective of Web Content Distribution Matching 该论文提出WeDAS框架，通过**",
    "description": "Rethinking Deep Research from the Perspective of Web Content Distribution Matching 该论文提出WeDAS框架，通过**Query-Result Alignment Score（QRAS）** 和**少样本探测机制**解决深度搜索智能体的查询-内容错位问题：QRAS是一个0-10分的综合指标，由LLM从主题相关性、信息密度、噪音鲁棒性三个维度评估查询与检索结果的匹配度；少样本探测机制则通过迭代生成候选查询、计算QRAS分数、动态筛选高分查询的方式，在有限预算内估计局部网页内容分布，使智能体能够自适应调整查询粒度，在内容稀疏时放宽查询、密集时收紧查询，从而提升检索效率。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Token-Efficient"
    ],
    "id": 92
  },
  {
    "date": "2026.03",
    "name": "DualSpec",
    "url": "https://arxiv.org/abs/2603.07416v1",
    "title": "DualSpec",
    "description": "DualSpec: Accelerating Deep Research Agents via Dual-Process Action Speculation 该论文提出DualSpec框架，通过异构动作推测和语义验证加速深度研究智能体。其核心洞察是Search动作（需要显式推理制定查询）和Visit动作（基于检索结果直接选择）具有不同的不确定性特征，分别对应认知科学中的System 2和System 1。DualSpec采用小模型带推理推测Search、大模型跳过推理推测Visit的异构策略，并通过基于置信度的语义验证器（而非精确匹配）来接受或拒绝推测动作，将基座模型推理移出关键路径。实验表明该方法可实现1.33-3.28倍的端到端加速，同时保持准确率。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research"
    ],
    "id": 93
  },
  {
    "date": "2026.03",
    "name": "RecPilot",
    "url": "https://arxiv.org/abs/2603.07605v1",
    "title": "Deep Research for Recommender Systems 该论文提出RecPilot框架，将推荐系统从传统的\"物品列表展示\"转变为\"综合研究报告生成\"的深度研究范式。其核心包含两个智",
    "description": "Deep Research for Recommender Systems 该论文提出RecPilot框架，将推荐系统从传统的\"物品列表展示\"转变为\"综合研究报告生成\"的深度研究范式。其核心包含两个智能体：用户轨迹模拟智能体通过生成式建模和强化学习（结合结果奖励、协作一致性过程奖励和格式约束奖励）自主模拟用户从探索到决策的完整行为轨迹；自进化报告生成智能体则利用结构化评分标准和文本经验记忆双通道表征用户偏好，通过多维度兴趣分解进行并行排序，生成包含探索轨迹、意图摘要和多维度对比的可解释报告，并通过自进化机制基于用户反馈持续优化而无需重新训练。实验表明该方法在推荐准确性和报告质量上均显著优于基线，能有效降低用户决策负担。",
    "codeLinks": [
      "https://github.com/RUCAIBox/RecPilot"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Self-Play",
      "Process Reward",
      "Agent",
      "Deep Research"
    ],
    "id": 94
  },
  {
    "date": "2026.03",
    "name": "SynPlanResearch-R1",
    "url": "https://arxiv.org/abs/2603.07853v1",
    "title": "SynPlanResearch-R1",
    "description": "SynPlanResearch-R1: Encouraging Tool Exploration for Deep Research with Synthetic Plans 该论文提出SynPlanResearch-R1框架，通过计划引导的合成数据解决RLVR训练研究智能体时的探索受限问题。其核心是生成随机工具计划（指定web_search和crawl_webpage的调用序列），并通过线索注入软性引导大模型生成多样化轨迹，经格式和答案正确性过滤后用于冷启动SFT，为后续RL提供强初始化。同时提出两项训练稳定技巧：对无效轨迹进行损失掩码、对JSON错误立即终止惩罚。实验表明该方法能诱导更深的工具探索和更高的策略熵，在7个基准上相比SOTA提升最高达6%。",
    "codeLinks": [
      "https://github.com/HansiZeng/syn-plan-research"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "SFT",
      "Agent",
      "RAG",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 95
  },
  {
    "date": "2026.03",
    "name": "Ares",
    "url": "https://arxiv.org/abs/2603.07915v1",
    "title": "Ares",
    "description": "Ares: Adaptive Reasoning Effort Selection for Efficient LLM Agents 该论文提出ARES框架，通过轻量级路由器为LLM智能体的每一步动态选择最低足够的推理努力级别（低/中/高），以平衡性能与成本。其核心是自动化数据生成流程：先收集成功轨迹，再逐步骤验证最低足够推理努力（通过多次采样确保稳定性），最后生成推理依据用于监督微调；并进一步通过GRPO强化学习优化长期决策效果，结合结果奖励、推理成本惩罚和格式奖励。实验表明该方法可减少高达52.7%的推理token消耗，同时保持甚至提升任务成功率，且能跨模型规模泛化。",
    "codeLinks": [
      "https://github.com/UCSB-NLP-Chang/Ares"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "SFT",
      "Agent",
      "Token-Efficient"
    ],
    "id": 96
  },
  {
    "date": "2026.03",
    "name": "EvalAct",
    "url": "https://arxiv.org/abs/2603.09203",
    "title": "Evaluate-as-Action",
    "description": "Evaluate-as-Action: Self-Evaluated Process Rewards for Retrieval-Augmented Agents 将检索质量评估从隐式推理转化为显式策略动作，通过强制耦合的 Search→Evaluate 协议让智能体在每次检索后立即输出结构化自评分数，从而生成密集、轨迹对齐的过程信号；配合 PCAR 方法基于这些分数对 GRPO 优势值进行段级重缩放，实现细粒度信用分配，在七个开放域 QA 基准上取得最佳平均性能，尤其显著提升了多跳推理任务的准确率。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "RAG",
      "Multi-hop QA",
      "Benchmark"
    ],
    "id": 97
  },
  {
    "date": "2026.03",
    "name": "SearchLLM",
    "url": "https://arxiv.org/abs/2603.10473",
    "title": "Aligning Large Language Models with Searcher Preferences 这篇论文针对搜索引擎从\"以商品为中心的排序\"向\"以答案为中心的生成式合成\"范式转变的背",
    "description": "Aligning Large Language Models with Searcher Preferences 这篇论文针对搜索引擎从\"以商品为中心的排序\"向\"以答案为中心的生成式合成\"范式转变的背景，提出了首个面向开放式生成搜索的大型语言模型 SearchLLM，以解决现有生成式搜索在噪声检索鲁棒性、安全保障和用户偏好对齐方面的挑战；为此设计了一种分层多维奖励系统，将硬性约束（事实准确性、基本质量、格式合规）与行为优化目标分离，并通过基于用户查询、会话历史和检索证据的奖励模型结合规则检查与人工校准的LLM评判来生成可解释的多维度评分向量，同时采用门控聚合策略配合GRPO算法进行模型优化，最终在小红书平台部署后实现了有效消费率提升1.03%和重复搜索率降低2.81%的效果，同时保持了严格的安全可靠性标准。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based"
    ],
    "id": 98
  },
  {
    "date": "2026.03",
    "name": "MR-Search",
    "url": "https://arxiv.org/abs/2603.11327v1",
    "title": "Meta-Reinforcement Learning with Self-Reflection for Agentic Search 该论文提出MR-Search框架，通过元强化学习与自我反思机制解",
    "description": "Meta-Reinforcement Learning with Self-Reflection for Agentic Search 该论文提出MR-Search框架，通过元强化学习与自我反思机制解决智能体搜索中的稀疏奖励问题。其核心是将独立搜索尝试转变为跨轮次的元学习过程：每个元轮次包含多个内轮次，智能体在每轮后生成显式自我反思，将前序轮次作为上下文指导后续探索；同时提出多轮次RL算法，在轮次级别估计分组相对优势并传播未来奖励，实现细粒度信用分配。实验表明该方法在8个多跳问答基准上相比强基线实现9.2%-19.3%的相对提升，且能有效外推到更多测试轮次。",
    "codeLinks": [
      "https://github.com/tengxiao1/MR-Search"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Multi-hop QA",
      "Benchmark"
    ],
    "id": 99
  },
  {
    "date": "2026.03",
    "name": "InterDeepResearch",
    "url": "https://arxiv.org/abs/2603.12608v1",
    "title": "InterDeepResearch",
    "description": "InterDeepResearch: Enabling Human-Agent Collaborative Information Seeking through Interactive Deep Research 该论文提出InterDeepResearch系统，首个支持人机协作信息搜索的交互式深度研究系统。其核心是分层研究上下文架构，将研究过程组织为信息、动作、会话三个层次，支持动态上下文缩减和跨动作证据回溯；界面集成聊天式、图形式、卡片式三视图，通过跨视图联动和跨动作回溯机制，使用户能够实时观察研究过程、灵活调整研究方向、高效导航大规模上下文。实验表明该系统在基准测试上达到SOTA性能，用户研究验证了其有效支持人机协作。",
    "codeLinks": [
      "https://github.com/bopan3/InterDeepResearch"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 100
  },
  {
    "date": "2026.03",
    "name": "APEX-Searcher",
    "url": "https://arxiv.org/abs/2603.13853v1",
    "title": "APEX-Searcher",
    "description": "APEX-Searcher: Augmenting LLMs' Search Capabilities through Agentic Planning and Execution 该论文提出APEX-Searcher框架，通过显式分离战略规划与迭代执行来增强LLM的多跳搜索能力。其核心是两阶段训练：首先使用GRPO强化学习训练规划智能体，将复杂查询分解为逻辑有序的子问题序列；然后基于规划结果通过监督微调训练执行智能体，实现自适应多轮检索（包括知识充分性评估、动态查询生成和继续决策）。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "SFT",
      "Agent",
      "Multi-hop QA"
    ],
    "id": 101
  },
  {
    "date": "2026.03",
    "name": "OpenSeeker",
    "url": "https://arxiv.org/abs/2603.15594v1",
    "title": "OpenSeeker",
    "description": "OpenSeeker: Democratizing Frontier Search Agents by Fully Open-Sourcing Training Data 该论文提出OpenSeeker，首个完全开源（模型和数据）且达到前沿性能的搜索智能体，旨在打破工业巨头对高质量训练数据的垄断。其核心创新包括：事实可扩展可控QA合成，通过拓扑图扩展和实体混淆将真实网页转化为复杂多跳推理问题；去噪轨迹合成，采用回顾性摘要机制在生成阶段提供清晰上下文，但训练时基于原始噪声数据强制模型学习内在去噪能力。仅用11.7k样本和单次SFT，OpenSeeker在多个基准上达到SOTA，甚至超过采用复杂训练流程的工业模型。",
    "codeLinks": [
      "https://github.com/rui-ye/OpenSeeker"
    ],
    "datasetLinks": [
      "https://huggingface.co/datasets/OpenSeeker/OpenSeeker-v1-Data"
    ],
    "year": 2026,
    "tags": [
      "SFT",
      "Agent",
      "Search Agent",
      "Multi-hop QA",
      "Benchmark",
      "Open-Source"
    ],
    "id": 102
  },
  {
    "date": "2026.03",
    "name": "MiroThinker-1.7 & H1",
    "url": "https://arxiv.org/abs/2603.15726v1",
    "title": "MiroThinker-1.7 & H1",
    "description": "MiroThinker-1.7 & H1: Towards Heavy-Duty Research Agents via Verification 该论文提出MiroThinker-1.7和MiroThinker-H1，通过\"有效交互扩展\"而非简单增加轨迹长度来提升长程推理能力。其核心包括：Agentic Mid-training阶段通过大规模监督学习强化规划、推理、工具使用和摘要等原子能力；四阶段训练流程（Mid-training→SFT→DPO→GRPO）逐步优化交互质量；Heavy-duty推理模式引入局部验证器（优化中间步骤）和全局验证器（审计完整轨迹），在可控计算预算下选择最可靠证据支持的答案。实验表明该方法在多个基准上达到SOTA，在相同参数量下实现更高性能且减少43%交互轮次。",
    "codeLinks": [
      "https://github.com/MiroMindAI/MiroThinker"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Process Reward",
      "SFT",
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 103
  },
  {
    "date": "2026.03",
    "name": "MyScholarQA",
    "url": "https://arxiv.org/abs/2603.16120v1",
    "title": "Language Models Don't Know What You Want",
    "description": "Language Models Don't Know What You Want: Evaluating Personalization in Deep Research Needs Real Users 当前Deep Research工具虽能综合科学论文回答查询，但缺乏对用户个体需求的理解。为此，作者提出MyScholarQA（MySQA），一个开源个性化DR系统，通过三阶段方法实现以用户为中心的研究辅助：推断用户研究兴趣画像、推荐个性化操作建议、利用多LLM协同生成遵循用户批准动作的多章节报告。实验采用合成数据集进行离线评估，并开展真实用户访谈。结果显示，尽管MySQA在LLM judge评估中表现优于基线，但真实用户反馈揭示了**九类LLM无法检测的细微错误**，证明仅依赖自动指标会忽略关键的人因因素，强调真正的个性化必须依赖**真实用户参与**而非仅靠LLM裁判。",
    "codeLinks": [
      "https://github.com/allenai/personalized-scholarqa-eval"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Deep Research",
      "Benchmark",
      "Dataset",
      "Open-Source"
    ],
    "id": 104
  },
  {
    "date": "2026.03",
    "name": "TIPS",
    "url": "https://arxiv.org/abs/2603.22293",
    "title": "TIPS",
    "description": "TIPS: Turn-Level Information-Potential Reward Shaping for Search-Augmented LLMs 现有基于强化学习的搜索增强大语言模型在开放域问答任务上虽取得不错效果，但训练过程仍面临重大挑战：由于奖励稀疏以及推理与工具调用之间的信用分配困难，优化往往不稳定；为此，该论文提出TIPS（Turn-Level Information-Potential Reward Shaping）框架，通过基于教师模型下正确答案似然度的提升，为每个推理+工具调用片段分配密集的轮次级奖励，利用基于势能的奖励塑形方法提供细粒度且策略不变的指导，在七个QA基准上 consistently 优于GRPO/PPO基线，并显著提升训练稳定性。",
    "codeLinks": [
      "https://github.com/ucsd-wang-lab-lm/tips"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Benchmark"
    ],
    "id": 105
  },
  {
    "date": "2026.03",
    "name": "CDR",
    "url": "https://arxiv.org/abs/2603.25342v1",
    "title": "From Intent to Evidence",
    "description": "From Intent to Evidence: A Categorical Approach for Structural Evaluation of Deep Research Agents 该研究针对深度研究智能体（DRAs）评估缺乏理论严谨性的问题，基于范畴论将研究工作流形式化为函子组合，构建包含296个问题的机制感知基准，从序列连通性、V-结构拉回验证、拓扑排序和Yoneda本体论证伪四个维度进行压力测试；评估显示SOTA模型平均准确率仅19.9%，暴露出当前智能体虽能有机统一搜索与推理、在动态拓扑重排序和本体论验证上表现稳健，却在多跳结构综合上普遍崩溃，反映出对脆弱启发式而非系统性理解的依赖，实现复杂结构信息的泛化掌握仍是重大开放挑战。",
    "codeLinks": [
      "https://github.com/tzq1999/CDR"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Multi-hop QA",
      "Deep Research",
      "Benchmark"
    ],
    "id": 106
  },
  {
    "date": "2026.03",
    "name": "Marco-DeepResearch",
    "url": "https://arxiv.org/abs/2603.28376v1",
    "title": "Marco DeepResearch",
    "description": "Marco DeepResearch: Unlocking Efficient Deep Research Agents via Verification-Centric Design Marco DeepResearch 针对现有深度研究智能体在 QA 数据合成、轨迹构建和测试时扩展中缺乏显式验证机制导致错误传播的问题，提出了三层验证中心框架：在数据合成阶段引入验证机制控制问题难度并确保答案唯一正确，在轨迹构建阶段注入显式验证模式，在推理阶段将自身作为验证器实现测试时扩展，最终使 8B 规模的模型在 BrowseComp 等挑战性基准上超越或接近 30B 规模智能体的性能。",
    "codeLinks": [
      "https://github.com/AIDC-AI/Marco-DeepResearch"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 107
  },
  {
    "date": "2026.03",
    "name": "MiroEval",
    "url": "https://arxiv.org/abs/2603.28407v1",
    "title": "MiroEval",
    "description": "MiroEval: Benchmarking Multimodal Deep Research Agents in Process and Outcome MiroEval 针对现有深度研究系统评估仅关注最终输出、缺乏多模态覆盖、依赖合成任务且无法动态更新的局限，构建了包含100个真实用户需求任务（含30个多模态）的可更新基准，并提出三维评估框架——自适应综合质量评估、智能体事实性验证和过程中心评估——以全面审计系统能力；实验发现过程质量能有效预测整体结果并暴露输出指标无法发现的弱点，且多模态任务使多数系统性能下降3-10分，其中MiroThinker-H1表现最优。",
    "codeLinks": [
      "https://github.com/MiroMindAI/MiroEval"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 108
  },
  {
    "date": "2026.03",
    "name": "PAR<sup>2</sup>-RAG",
    "url": "https://arxiv.org/abs/2603.29085v1",
    "title": "PAR<sup>2</sup>-RAG",
    "description": "PAR<sup>2</sup>-RAG: Planned Active Retrieval and Reasoning for Multi-Hop Question Answering 针对大语言模型在多跳问答任务中表现脆弱的问题，提出了PAR²-RAG框架。现有迭代检索系统容易在早期锁定低召回率的检索路径并放大下游错误，而纯规划方法则产生无法适应中间证据变化的静态查询集。为此，作者设计了一个两阶段框架：首先通过广度优先锚定构建高召回率的证据前沿，确保覆盖充分；然后通过深度优先精修结合证据充分性控制进行迭代循环，实现灵活适应。该方法将\"覆盖\"与\"承诺\"分离。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RAG",
      "Multi-hop QA",
      "Benchmark"
    ],
    "id": 109
  },
  {
    "date": "2026.04",
    "name": "Doctor-RAG",
    "url": "https://arxiv.org/abs/2604.00865v1",
    "title": "Doctor-RAG",
    "description": "Doctor-RAG: Failure-Aware Repair for Agentic Retrieval-Augmented Generation 针对Agentic RAG在长推理轨迹中失败频发的问题，提出了Doctor-RAG（DR-RAG）框架。现有方法处理失败时要么仅做诊断分析，要么重跑整个检索-推理管道，导致计算开销大且推理冗余。为此设计了一个统一的诊断-修复框架：首先通过轨迹级失败诊断与定位，将错误归因到覆盖门控分类法并识别最早失败点；然后通过工具条件的局部修复，仅在失败点进行干预，同时最大化复用已验证的推理前缀和检索证据。通过显式分离错误归因与纠正，DR-RAG实现了精准错误定位和最小成本干预，在三个多跳问答基准测试上显著提升了答案准确率，同时大幅降低了推理token消耗。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "RAG",
      "Multi-hop QA",
      "Benchmark",
      "Token-Efficient"
    ],
    "id": 110
  },
  {
    "date": "2026.04",
    "name": "HERA",
    "url": "https://arxiv.org/pdf/2604.00901v1",
    "title": "Experience as a Compass",
    "description": "Experience as a Compass: Multi-agent RAG with Evolving Orchestration and Agent Prompts 针对现有多智能体RAG系统依赖静态编排策略和固定智能体行为导致在多跳任务上表现脆弱、错误传播难以归因、且难以持续适应动态环境的问题，提出了HERA(Hierarchical Evolution RAG)分层演化框架，通过经验库积累成功与失败轨迹的语义洞察来指导全局编排策略优化，同时采用角色感知提示演化（RoPE）对特定智能体进行双轴适应（操作规则和行为原则）的行为级改进，在六个知识密集型基准上相比近期SOTA平均提升38.69%，并展现出良好的跨分布泛化能力和token效率。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Multi-Agent",
      "Agent",
      "RAG",
      "Multi-hop QA",
      "Benchmark",
      "Token-Efficient"
    ],
    "id": 111
  },
  {
    "date": "2026.04",
    "name": "ORBIT",
    "url": "https://arxiv.org/abs/2604.01195v1",
    "title": "ORBIT",
    "description": "ORBIT: Scalable and Verifiable Data Generation for Search Agents on a Tight Budget 针对为DeepResearch构建训练数据集时人工标注昂贵、前置条件繁琐的问题，提出了ORBIT框架。现有数据生成方法依赖付费API服务，成本高昂。为此设计了一个节俭的模块化四阶段流程（种子创建、问答对生成、自我验证、外部验证），无需付费API即可生成20K推理密集型查询数据集——每对训练数据需4-5步推理、答案简短可验证，覆盖15个领域且需完整网络搜索验证。作者基于GRPO用ORBIT训练Qwen3-4B作为搜索代理基座模型，在维基百科问答任务上的实验表明，ORBIT-4B在小于4B参数的LLM中表现强劲，证明了合成数据集在训练搜索代理方面的实用性。",
    "codeLinks": [
      "https://github.com/castorini/orbit"
    ],
    "datasetLinks": [
      "https://huggingface.co/orbit-ai"
    ],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent",
      "Deep Research",
      "Dataset"
    ],
    "id": 112
  },
  {
    "date": "2026.04",
    "name": "Reasoning-Memory",
    "url": "https://arxiv.org/pdf/2604.01348v1",
    "title": "Procedural Knowledge at Scale Improves Reasoning 该论文针对现有测试时缩放方法孤立处理每个问题、未能系统性复用程序性知识（如问题重构、方法选择、验证回溯",
    "description": "Procedural Knowledge at Scale Improves Reasoning 该论文针对现有测试时缩放方法孤立处理每个问题、未能系统性复用程序性知识（如问题重构、方法选择、验证回溯等元推理策略）的局限，提出了**Reasoning Memory**框架——通过将大规模推理轨迹分解为3200万条\"子问题-子程序\"对构建知识库，并设计轻量级思维内检索机制，使模型能在推理过程中动态获取相关程序性先验，从而在数学、科学和编程任务上相比无检索基线提升最高19.2%，相比最强计算匹配基线提升7.9%。",
    "codeLinks": [
      "https://github.com/facebookresearch/reasoning-memory"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Memory"
    ],
    "id": 113
  },
  {
    "date": "2026.04",
    "name": "ContextBudget",
    "url": "https://arxiv.org/abs/2604.01664v1",
    "title": "ContextBudget",
    "description": "ContextBudget: Budget-Aware Context Management for Long-Horizon Search Agents 针对长程推理搜索智能体在部署时面临的上下文预算限制（受内存、延迟和成本约束）问题，提出了Budget-Aware Context Management (BACM)方法，将上下文管理建模为带预算约束的序列决策问题，使智能体能在纳入新观察前评估可用预算并决定何时及如何压缩交互历史；进一步开发了基于课程学习的端到端强化学习方法BACM-RL来学习不同预算下的压缩策略，在组合多目标问答和长程网页浏览基准上，该方法在多种模型规模和任务复杂度下均优于现有方法，在高复杂度场景下相比强基线提升超过1.6倍，且在预算缩减时仍保持显著优势。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 114
  },
  {
    "date": "2026.04",
    "name": "InfoSeeker",
    "url": "https://arxiv.org/abs/2604.02971v1",
    "title": "InfoSeeker",
    "description": "InfoSeeker: A Scalable Hierarchical Parallel Agent Framework for Web Information Seeking 论文的动机在于现有智能体搜索系统过度关注深度多步推理，却忽视了大规模信息综合的挑战——即跨多源聚合海量异构证据的需求；解决了数据密集型场景下传统框架面临的上下文窗口饱和、错误级联传播和高延迟三大核心问题；提出了InfoSeeker分层并行框架，基于\"近可分解性\"原则构建三层架构（战略Host-管理Manager-工作Worker），通过严格上下文隔离与MapReduce式聚合机制，在WideSearch和BrowseComp-zh基准上分别实现66.7%和13.8%的性能提升，同时获得3-5倍推理加速。",
    "codeLinks": [
      "https://github.com/Memento-Teams/InfoSeeker"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Benchmark"
    ],
    "id": 115
  },
  {
    "date": "2026.04",
    "name": "urlhealth",
    "url": "https://arxiv.org/abs/2604.03173v1",
    "title": "Detecting and Correcting Reference Hallucinations in Commercial LLMs and Deep Research Agents 这篇论文的动",
    "description": "Detecting and Correcting Reference Hallucinations in Commercial LLMs and Deep Research Agents 这篇论文的动机是系统性地测量商业大语言模型和深度研究智能体生成引用URL的可靠性，因为此前缺乏对此的大规模评估，而引用幻觉已导致法律制裁、学术撤稿等现实危害。研究解决了以下问题：发现3-13%的引用URL是幻觉（从未存在过）、5-18%无法解析；深度研究智能体虽然生成引用数量更多，但幻觉率反而更高；不同学术领域的引用可靠性差异显著（从商业的5.4%到神学的11.4%）；且部分模型会完全捏造失效URL，而另一些则只是检索到了已失效的真实链接。为此，作者提出了开源工具`urlhealth`，通过HTTP请求和Wayback Machine将失效URL分类为\"陈旧\"（真实但已下线）或\"幻觉\"（从未存在），并在智能体自校正实验中将其作为工具集成到生成流程中，使非解析URL率降低6-79倍至1%以下，不过效果取决于模型的工具使用能力。",
    "codeLinks": [
      "https://github.com/delip/urlhealth"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Open-Source"
    ],
    "id": 116
  },
  {
    "date": "2026.04",
    "name": "PRAISE",
    "url": "https://arxiv.org/abs/2604.03675v1",
    "title": "PRAISE",
    "description": "PRAISE: Prefix-Based Rollout Reuse in Agentic Search Training 现有基于强化学习的智能体搜索方法存在两个核心局限：昂贵的长程rollout在训练中被低效利用，且监督信号仅来自最终答案导致严重的奖励稀疏问题；为此，该论文提出PRAISE框架，通过从完整搜索轨迹中提取不同搜索轮次的前缀状态、生成中间答案，并将这些前缀既用于构建额外训练样本又通过相邻前缀性能差异推导步骤级奖励，同时采用单一共享模型进行搜索策略学习和前缀答案评估，实现了数据效率与信用分配的双重提升，在多跳问答基准上 consistently 优于强基线方法。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Process Reward",
      "Agent",
      "Multi-hop QA",
      "Deep Research",
      "Benchmark",
      "Token-Efficient"
    ],
    "id": 117
  },
  {
    "date": "2026.04",
    "name": "MIA",
    "url": "https://arxiv.org/abs/2604.04503v1",
    "title": "Memory Intelligence Agent 现有深度研究智能体（DRA）依赖记忆系统来利用历史经验以实现高效推理和自主进化，但现有方法仅通过检索相似轨迹来辅助推理，存在记忆进化无效、存储和检索",
    "description": "Memory Intelligence Agent 现有深度研究智能体（DRA）依赖记忆系统来利用历史经验以实现高效推理和自主进化，但现有方法仅通过检索相似轨迹来辅助推理，存在记忆进化无效、存储和检索成本不断增加等关键局限；为此，该论文提出Memory Intelligence Agent（MIA）框架，采用Manager-Planner-Executor架构——其中Memory Manager以非参数化方式存储压缩的历史搜索轨迹，Planner作为参数化记忆智能体生成搜索计划，Executor则在计划指导下执行搜索和信息分析——并通过交替强化学习范式增强Planner与Executor的协作、支持Planner在测试时持续学习进化、建立参数化与非参数化记忆之间的双向转换循环，以及引入反思和无监督判断机制来提升开放世界中的推理与自我进化能力，在11个基准测试上显著提升了当前SOTA大模型的深度研究性能，且使用轻量级Executor（Qwen2.5-VL-7B）也能实现平均31%的性能提升。",
    "codeLinks": [
      "https://github.com/ECNU-SII/MIA"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Self-Play",
      "Memory",
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 118
  },
  {
    "date": "2026.04",
    "name": "ASP",
    "url": "https://arxiv.org/abs/2604.04651v1",
    "title": "Search, Do not Guess",
    "description": "Search, Do not Guess: Teaching Small Language Models to Be Effective Search Agents 现有搜索智能体多依赖大语言模型（LLM），但其高计算成本限制了实际部署，因此近期研究致力于将智能体行为从LLM蒸馏到小语言模型（SLM）；然而，在复杂多跳推理任务上的全面评估发现，尽管SLM拥有较少的参数化知识，它们反而更少调用搜索工具且更容易产生幻觉，而标准的智能体蒸馏方法效果有限（如Qwen3-1.7B在Bamboogle上仅从50.6提升到53.2）；为此，该论文提出Always-Search Policy（ASP），一种轻量级微调方法，通过显式训练SLM始终检索并基于检索证据生成答案，而非依赖参数化知识，相比从LLM进行智能体蒸馏，该方法在Bamboogle上提升17.3分、HotpotQA上提升15.3分，实现了与LLM相当的结果，同时分析表明自适应搜索策略反而会降低SLM性能，验证了强制一致搜索行为的必要性。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Multi-hop QA"
    ],
    "id": 119
  },
  {
    "date": "2026.04",
    "name": "PRISM-MCTS",
    "url": "https://arxiv.org/pdf/2604.05424v1",
    "title": "PRISM-MCTS",
    "description": "PRISM-MCTS: Learning from Reasoning Trajectories with Metacognitive Reflection 动机源于 OpenAI-o1 等推理模型推动的\"慢思考\"范式转变，旨在通过蒙特卡洛树搜索（MCTS）实现从直觉式快思考到审慎式慢思考的跃迁；针对现有 MCTS 方法将推理轨迹视为孤立路径、缺乏全局信息共享而导致计算冗余严重的问题，该论文提出了一种受人类元认知反思启发的框架，通过过程奖励模型（PRM）与动态双内存机制（启发式内存记录成功经验、谬误内存拦截错误模式）实现全局知识共享，在并行搜索中主动剪枝低效分支并复用已验证步骤，从而在 GPQA 等复杂推理任务上将搜索轨迹数量减半的同时超越 MCTS-RAG 和 Search-o1 等基线，实现了\"更聪明地推理而非更努力地搜索\"的推断时扩展。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Process Reward",
      "RAG"
    ],
    "id": 120
  },
  {
    "date": "2026.04",
    "name": "DataSTORM",
    "url": "https://arxiv.org/abs/2604.06474v1",
    "title": "DataSTORM",
    "description": "DataSTORM: Deep Research on Large-Scale Databases using Exploratory Data Analysis and Data Storytelling 动机源于现有 LLM 智能体深度研究主要聚焦非结构化网络数据，而大规模结构化数据库的深度研究挑战尚未被充分探索；针对以数据为中心的研究需要迭代假设生成、结构化模式定量推理及连贯分析叙事收敛等复杂需求，该论文提出了一个基于探索性数据分析和数据叙事原则的 LLM 智能体系统，通过以论点驱动的分析流程（从数据发现候选论点、跨源迭代验证到构建分析叙事），在 InsightBench 上实现 19.4% 的洞察级召回率提升，并在 ACLED 真实复杂数据库上超越 ChatGPT Deep Research 等专有系统。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Deep Research"
    ],
    "id": 121
  },
  {
    "date": "2026.04",
    "name": "KDR",
    "url": "https://arxiv.org/abs/2604.07720v1",
    "title": "Towards Knowledgeable Deep Research",
    "description": "Towards Knowledgeable Deep Research: Framework and Benchmark 这篇论文针对现有深度研究（DR）代理仅依赖非结构化文本、缺乏结构化知识利用的局限，提出了知识化深度研究（KDR）这一新任务，要求智能体同时整合结构化与非结构化知识生成多模态报告；为此设计了混合知识分析框架（HKA），通过多智能体协作机制，特别是利用代码和视觉语言模型的结构化知识分析器来生成图表、表格及洞察，实现了文本、图表、表格的有机融合；并构建了包含9个领域、41个专家问题及1,252个表格的KDR-Bench基准和三类评估指标，实验表明HKA在通用和知识中心指标上优于多数现有DR代理，在视觉增强指标上甚至超越Gemini DR代理。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Multi-Agent",
      "Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 122
  },
  {
    "date": "2026.04",
    "name": "EigentSearch-Q+",
    "url": "https://arxiv.org/abs/2604.07927v1",
    "title": "EigentSearch-Q+",
    "description": "EigentSearch-Q+: Enhancing Deep Research Agents with Structured Reasoning Tools 该论文受 Anthropic \"think\" 工具范式和信息检索经典方法启发，针对现有深度研究代理依赖隐式推理导致的冗余搜索和脆弱证据聚合问题，提出了 **Q+** 结构化推理工具集——通过 `plan_next_searches`、`select_query_and_search`、`extract_relevant_details` 和 `analyze_search_progress` 四个显式工具将查询规划、搜索进度监控和证据提取过程外化为可审计的工具调用，并将其集成到 Eigent 多代理系统的浏览器代理中形成 **EigentSearch-Q+**，在 SimpleQA-Verified、FRAMES、WebWalkerQA 和 X-Bench 四个基准上相比基线系统取得了 0.6-3.8 个百分点的平均准确率提升，证明了即使对于具备内部推理能力的模型，显式的工具级结构化推理仍能有效增强深度研究代理的稳健性和可解释性。",
    "codeLinks": [
      "https://github.com/camel-ai/eigent_search"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 123
  },
  {
    "date": "2026.04",
    "name": "GuarantRAG",
    "url": "https://arxiv.org/abs/2604.08046v1",
    "title": "Guaranteeing Knowledge Integration with Joint Decoding for Retrieval-Augmented Generation 该论文针对RAG系统",
    "description": "Guaranteeing Knowledge Integration with Joint Decoding for Retrieval-Augmented Generation 该论文针对RAG系统中参数知识与非参数知识的\"整合瓶颈\"问题——即LLM常因内部知识与检索文档冲突而无法有效利用外部证据，提出GuarantRAG框架：通过对比DPO训练将模型自身的参数答案作为负样本、检索文档作为正样本，强制生成忠实于外部证据的Refer-Answer，再通过token级联合解码机制动态融合Inner-Answer的推理连贯性与Refer-Answer的事实精确性，从而在五个QA基准上实现准确率最高提升12.1%、幻觉降低16.3%。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "SFT",
      "RAG",
      "Benchmark"
    ],
    "id": 124
  },
  {
    "date": "2026.04",
    "name": "HiExp",
    "url": "https://arxiv.org/abs/2604.08124v1",
    "title": "Beyond Stochastic Exploration",
    "description": "Beyond Stochastic Exploration: What Makes Training Data Valuable for Agentic Search 该论文针对当前基于强化学习的搜索智能体依赖随机探索导致推理轨迹低效和训练不稳定的问题，提出了Hierarchical Experience (HiExp)框架——通过对比分析和多级聚类机制从原始推理轨迹中提取层次化经验知识，并利用经验对齐训练将随机探索正则化为策略性、经验驱动的搜索过程，最终在多个复杂搜索和数学推理基准上实现了显著的性能提升和跨任务泛化能力。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent",
      "Benchmark"
    ],
    "id": 125
  },
  {
    "date": "2026.04",
    "name": "Self-Correcting RAG",
    "url": "https://arxiv.org/abs/2604.10734v1",
    "title": "Self-Correcting RAG",
    "description": "Self-Correcting RAG: Enhancing Faithfulness via MMKP Context Selection and NLI-Guided MCTS 该论文针对RAG在复杂推理任务中上下文利用率低和易产生幻觉的问题，提出Self-Correcting RAG框架：在输入端将文档选择形式化为多维多选背包问题（MMKP）以最大化信息密度并去除冗余，在输出端引入NLI引导的蒙特卡洛树搜索（MCTS）动态探索推理路径并验证答案忠实性，实验表明该方法在六个多跳问答和事实核查数据集上显著提升了推理准确率并有效减少了幻觉。",
    "codeLinks": [
      "https://github.com/xjiacs/Self-Correcting-RAG"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RAG",
      "Multi-hop QA",
      "Dataset"
    ],
    "id": 126
  },
  {
    "date": "2026.04",
    "name": "Deep-Reporter",
    "url": "https://arxiv.org/abs/2604.10741v1",
    "title": "Deep-Reporter",
    "description": "Deep-Reporter: Deep Research for Grounded Multimodal Long-Form Generation 针对现有深度研究框架仅聚焦文本、忽视多模态证据的局限，提出了多模态长文本生成任务，通过智能体多模态搜索与过滤、清单引导的增量合成以及循环上下文管理三大模块，实现了图文融合的长篇 grounded 报告生成，并配套构建了 8K 高质量训练轨迹和 M2LongBench 评测基准以验证其有效性。",
    "codeLinks": [
      "https://github.com/fangda-ye/Deep-Report"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 127
  },
  {
    "date": "2026.04",
    "name": "PaperScope",
    "url": "https://arxiv.org/abs/2604.11307v1",
    "title": "PaperScope",
    "description": "PaperScope: A Multi-Modal Multi-Document Benchmark for Agentic Deep Research Across Massive Scientific Papers 该论文针对现有基准测试仅关注单文档理解、无法评估真实科研中跨多论文整合文本/图表/公式等多模态证据的需求，提出了PaperScope基准——一个基于2000+篇AI论文知识图谱构建的多模态多文档评测体系，通过优化的随机游走算法采样主题相关的论文集合，设计了涵盖主题归纳、跨文档推理、趋势摘要和问题求解的2400个问答对，实验揭示当前最先进的Deep Research系统在长上下文检索和深度多源推理方面仍存在显著局限。",
    "codeLinks": [
      "https://github.com/CherYou/PaperScope"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 128
  },
  {
    "date": "2026.04",
    "name": "GRIP",
    "url": "https://arxiv.org/abs/2604.11407v1",
    "title": "Retrieval as Generation",
    "description": "Retrieval as Generation: A Unified Framework with Self-Triggered Information Planning 该研究针对现有RAG系统将检索视为外部干预、依赖辅助控制器进行多阶段决策的问题，提出了GRIP框架，通过引入[RETRIEVE]、[ANSWER]等控制Token将检索行为直接嵌入到模型的Token级解码过程中，使模型能够在单一自回归轨迹内自主决定何时检索、如何重构查询以及何时终止，实现了检索与生成的端到端协调，在五个QA基准测试上超越了强RAG基线并与GPT-4o相当，同时显著减少了检索调用次数。",
    "codeLinks": [
      "https://github.com/WisdomShell/GRIP"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RAG",
      "Benchmark"
    ],
    "id": 129
  },
  {
    "date": "2026.04",
    "name": "AggAgent",
    "url": "https://arxiv.org/abs/2604.11407v1",
    "title": "Agentic Aggregation for Parallel Scaling of Long-Horizon Agentic Tasks 这篇论文针对长程智能体任务（如深度研究）的并行测试时扩展问",
    "description": "Agentic Aggregation for Parallel Scaling of Long-Horizon Agentic Tasks 这篇论文针对长程智能体任务（如深度研究）的并行测试时扩展问题，提出将聚合过程本身建模为智能体任务——AggAgent通过配备轻量级工具（获取解决方案、搜索轨迹、读取片段）按需导航和综合多个并行轨迹的信息，在六个基准测试上相比现有方法平均提升5.3%、在深度研究任务上提升10.3%，同时保持聚合成本仅相当于单次智能体轨迹的开销，实现了性能与效率的帕累托最优。",
    "codeLinks": [
      "https://github.com/princeton-pli/AggAgent"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Deep Research",
      "Benchmark",
      "Token-Efficient"
    ],
    "id": 130
  },
  {
    "date": "2026.04",
    "name": "OKH-RAG",
    "url": "https://arxiv.org/abs/2604.12185v1",
    "title": "Knowledge Is Not Static",
    "description": "Knowledge Is Not Static: Order-Aware Hypergraph RAG for Language Models 现有检索增强生成（RAG）方法将知识视为无序集合，忽略了现实世界中交互顺序对推理结果的关键影响；为此，该研究提出 Order-Aware Knowledge Hypergraph RAG（OKH-RAG），通过将顺序作为超图的核心结构属性，将检索重新定义为超边上的序列推断，并利用学习得到的转移模型自动推断优先级关系，在热带气旋和港口运营等顺序敏感任务中显著优于传统排列不变基线。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Memory",
      "RAG"
    ],
    "id": 131
  },
  {
    "date": "2026.04",
    "name": "NaviRAG",
    "url": "https://arxiv.org/abs/2604.12766v1",
    "title": "NaviRAG",
    "description": "NaviRAG: Towards Active Knowledge Navigation for Retrieval-Augmented Generation NaviRAG 针对传统 RAG 固定粒度分块导致的上下文缺失或语义稀释问题，提出了一种主动知识导航框架：通过将文档离线构建为层次化知识树保留语义关联，并引入\"先定位后觅食\"的在线导航机制，使 LLM Agent 能够根据查询需求在树结构中自顶向下动态探索，实现从粗粒度语义区域到细粒度证据的多步自适应检索，从而在复杂长链推理任务中显著提升了检索召回率和回答质量。",
    "codeLinks": [
      "https://github.com/ZzzDJH/NaviRAG"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "RAG",
      "Benchmark"
    ],
    "id": 132
  },
  {
    "date": "2026.04",
    "name": "QuarkMedSearch",
    "url": "https://arxiv.org/abs/2604.12867v1",
    "title": "QuarkMedSearch",
    "description": "QuarkMedSearch: A Long-Horizon Deep Search Agent for Exploring Medical Intelligence 该论文旨在解决医疗领域深度搜索Agent的训练数据稀缺、评估基准不完善以及通用Agent能力难以迁移到专业医疗场景的问题，提出了QuarkMedSearch框架，通过四阶段数据合成流水线（基于知识图谱构建种子QA、多跳事实扩展、关键实体混淆、多阶段验证）生成长程医疗推理数据，并采用SFT与RLVR相结合的两阶段后训练策略，最终构建了一个包含140道人工验证题目的QuarkMedSearch基准测试，在开源模型中实现了SOTA性能。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "SFT",
      "Agent",
      "Search Agent",
      "Multi-hop QA",
      "Deep Research",
      "Benchmark",
      "Open-Source"
    ],
    "id": 133
  },
  {
    "date": "2026.04",
    "name": "LMM-Searcher",
    "url": "https://arxiv.org/abs/2604.12890v1",
    "title": "Towards Long-horizon Agentic Multimodal Search 该研究针对多模态深度搜索智能体在长程交互中面临的上下文爆炸和视觉信息丢失问题，提出了LMM-Searche",
    "description": "Towards Long-horizon Agentic Multimodal Search 该研究针对多模态深度搜索智能体在长程交互中面临的上下文爆炸和视觉信息丢失问题，提出了LMM-Searcher框架，通过将视觉资产卸载到外部文件系统并以轻量级UID标识符替代原始图像，实现了按需渐进式加载；同时设计了专门的数据合成管道生成复杂跨模态多跳推理查询，并基于12K高质量轨迹微调Qwen3-VL-Thinking-30A3B模型，最终使智能体能够扩展至100轮交互，在MM-BrowseComp和MMSearch-Plus等长程基准上达到开源模型的最优性能。",
    "codeLinks": [
      "https://github.com/RUCAIBox/LMM-Searcher"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Multi-hop QA",
      "Deep Research",
      "Benchmark",
      "Open-Source"
    ],
    "id": 134
  },
  {
    "date": "2026.04",
    "name": "Cycle-Consistent Search",
    "url": "https://arxiv.org/abs/2604.12967v1",
    "title": "Cycle-Consistent Search",
    "description": "Cycle-Consistent Search: Question Reconstructability as a Proxy Reward for Search Agent Training 现有强化学习方法训练搜索代理严重依赖难以规模化获取的真实标准答案，为此本文提出Cycle-Consistent Search（CCS）框架，核心假设是最优搜索轨迹能无损编码问题意图、因而可通过重构原始问题来生成奖励信号；为避免模型依赖表面词汇而非真实搜索过程，该方法通过排除最终响应并对查询进行命名实体掩码等信息瓶颈约束，迫使重构依赖检索内容与结构框架，在问答基准上实现了与监督基线相当且优于其他无监督方法的性能。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent",
      "Benchmark"
    ],
    "id": 135
  },
  {
    "date": "2026.04",
    "name": "MERRIN",
    "url": "https://arxiv.org/abs/2604.13418v1",
    "title": "MERRIN",
    "description": "MERRIN: A Benchmark for Multimodal Evidence Retrieval and Reasoning in Noisy Web Environments 受真实世界搜索查询模糊多跳、网络结果多模态异构且常冲突的现状驱动，本文提出 MERRIN 基准测试，评估 AI 代理在无显式模态提示下识别相关模态、检索视频音频等复杂证据并进行多跳推理的能力；实验发现现有代理平均准确率仅 22.3%，最强者也仅达 40.1%，主要因过度探索、源选择低效及过度依赖文本模态而难以应对嘈杂网络环境。",
    "codeLinks": [
      "https://github.com/HanNight/MERRIN"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Multi-hop QA",
      "Benchmark"
    ],
    "id": 136
  },
  {
    "date": "2026.04",
    "name": "π-Play",
    "url": "https://arxiv.org/abs/2604.14054v1",
    "title": "π-Play",
    "description": "π-Play: Multi-Agent Self-Play via Privileged Self-Distillation without External Data 该论文针对深度搜索智能体训练中的稀疏奖励、弱信用分配和数据稀缺问题，发现自博弈过程中自然产生的问题构建路径（QCP）可作为高质量特权信息，据此提出π-Play框架——让考官生成任务及QCP、教师模型利用QCP进行密集自蒸馏监督，从而将稀疏奖励的自博弈转化为密集反馈的自进化循环，在无外部数据情况下超越全监督方法并提升2-3倍效率。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Self-Play",
      "Multi-Agent",
      "Agent",
      "Search Agent",
      "Token-Efficient"
    ],
    "id": 137
  },
  {
    "date": "2026.04",
    "name": "CW-GRPO",
    "url": "https://arxiv.org/abs/2604.14267v1",
    "title": "Enhancing LLM-based Search Agents via Contribution Weighted Group Relative Policy Optimization 动机在于解",
    "description": "Enhancing LLM-based Search Agents via Contribution Weighted Group Relative Policy Optimization 动机在于解决搜索智能体训练中过程监督不稳定、结果监督无法区分各轮次贡献的困境；它通过 LLM Judge 评估每轮搜索的检索效用与推理正确性，将过程信号转化为贡献权重来重新分配轨迹级优势，从而在保持 GRPO 训练稳定性的同时实现细粒度的信用分配，实验显示其在多跳问答等知识密集型任务上显著优于基线方法。",
    "codeLinks": [
      "https://github.com/zsxmwjz/CW-GRPO"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Process Reward",
      "Agent",
      "Search Agent",
      "Multi-hop QA"
    ],
    "id": 138
  },
  {
    "date": "2026.04",
    "name": "MindDR",
    "url": "https://arxiv.org/abs/2604.14518v1",
    "title": "Mind DeepResearch Technical Report 动机是突破当前深度研究系统依赖超大规模模型（>100B参数）和昂贵训练范式导致的高成本瓶颈，解决小型模型在长程推理、搜索效率和报告",
    "description": "Mind DeepResearch Technical Report 动机是突破当前深度研究系统依赖超大规模模型（>100B参数）和昂贵训练范式导致的高成本瓶颈，解决小型模型在长程推理、搜索效率和报告生成质量上的性能不足问题；为此提出了一个仅使用约30B参数的多智能体框架，通过 Planning Agent、DeepSearch Agent 和 Report Agent 的协作架构实现任务并行与上下文隔离，并设计了四阶段训练流程（SFT冷启动→Search-RL优化搜索效率→Report-RL提升报告质量→偏好对齐优化用户体验），在多个基准上达到与更大模型相当的性能，且已在理想汽车的AI产品中实际部署。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Multi-Agent",
      "SFT",
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark",
      "Token-Efficient"
    ],
    "id": 139
  },
  {
    "date": "2026.04",
    "name": "Corpus2Skill",
    "url": "https://arxiv.org/pdf/2604.14572v1",
    "title": "Don't Retrieve, Navigate",
    "description": "Don't Retrieve, Navigate: Distilling Enterprise Knowledge into Navigable Agent Skills for QA and RAG 这篇论文针对传统RAG将大语言模型视为搜索结果被动消费者、无法感知知识库组织结构或回溯整合分散证据的局限，提出了Corpus2Skill框架：离线阶段通过迭代聚类文档并生成层级摘要，将文档库蒸馏为可导航的树形技能目录；在线服务时让LLM智能体基于可见的层级结构主动导航——先获得知识库鸟瞰图，再逐层深入主题分支，按需检索完整文档，从而实现可回溯、可跨分支组合证据的主动式检索，在企业客服RAG基准WixQA上超越了稠密检索、RAPTOR及智能体RAG基线。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "RAG",
      "Benchmark"
    ],
    "id": 140
  },
  {
    "date": "2026.04",
    "name": "DR<sup>3</sup>-Eval",
    "url": "https://arxiv.org/abs/2604.14683v1",
    "title": "DR<sup>3</sup>-Eval",
    "description": "DR<sup>3</sup>-Eval: Towards Realistic and Reproducible Deep Research Evaluation 该论文提出DR3-Eval基准测试，旨在解决深度研究智能体评估中动态网络环境导致的不可复现性和任务定义模糊问题；通过构建基于真实多模态用户文件的静态沙盒语料库（含支持性、干扰性和噪声文档），并采用逆向构建方法从验证证据派生查询，实现了真实性与可验证性的平衡，同时提出五维度评估框架（信息召回、事实准确性、引用覆盖、指令遵循、深度质量）以全面衡量智能体的检索鲁棒性和幻觉控制能力。",
    "codeLinks": [
      "https://github.com/NJU-LINK/DR3-Eval"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 141
  },
  {
    "date": "2026.04",
    "name": "UniDoc-RL",
    "url": "https://arxiv.org/abs/2604.14967v1",
    "title": "UniDoc-RL",
    "description": "UniDoc-RL: Coarse-to-Fine Visual RAG with Hierarchical Actions and Dense Rewards 动机：现有视觉RAG系统依赖通用检索信号，忽略了复杂推理所需的细粒度视觉语义；解决的问题：如何让LVLM智能体联合执行检索、重排序、主动视觉感知和推理，从粗粒度到细粒度地获取视觉证据；提出的方法：UniDoc-RL，一个统一的强化学习框架，通过分层动作空间（从文档检索→图像选择→区域裁剪）和密集多奖励机制，基于GRPO实现端到端训练，使智能体能够抑制无关内容并关注信息密集区域。",
    "codeLinks": [
      "https://github.com/deepglint/UniDoc-RL"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "RAG"
    ],
    "id": 142
  },
  {
    "date": "2026.04",
    "name": "IG-Search",
    "url": "https://arxiv.org/abs/2604.15148v1",
    "title": "IG-Search",
    "description": "IG-Search: Step-Level Information Gain Rewards for Search-Augmented Reasoning 动机在于解决现有搜索增强推理中轨迹级奖励无法区分查询质量、且在全部失败时梯度消失的问题；它通过信息增益（IG）为每个搜索步骤提供细粒度奖励——衡量实际检索文档相对于随机文档对正确答案置信度的提升，并通过 GRPO 的逐 token 优势调制将信号反馈给查询 token，同时引入死区过滤、非对称负值缩放等稳定化机制，在无需中间标注的情况下实现了步骤级信用分配，显著提升了多跳推理性能。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Process Reward",
      "Multi-hop QA"
    ],
    "id": 143
  },
  {
    "date": "2026.04",
    "name": "Skill-RAG",
    "url": "https://arxiv.org/abs/2604.15771v1",
    "title": "Skill-RAG",
    "description": "Skill-RAG: Failure-State-Aware Retrieval Augmentation via Hidden-State Probing and Skill Routing 这篇论文的动机在于发现现有RAG系统将检索失败仅视为重试信号而非诊断对象，导致查询与证据空间的结构性错位问题未被解决；针对查询-证据对齐差距导致的持续性检索失败，提出了Skill-RAG框架，通过隐藏状态探测器识别失败状态并由技能路由器选择查询重写、问题分解、证据聚焦或退出等技能来纠正错位，实验表明该方法显著提升了多轮检索后困难案例的准确率。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RAG",
      "Benchmark"
    ],
    "id": 144
  },
  {
    "date": "2026.04",
    "name": "MemSearch-o1",
    "url": "https://arxiv.org/abs/2604.17265v1",
    "title": "MemSearch-o1",
    "description": "MemSearch-o1: Empowering Large Language Models with Reasoning-Aligned Memory Growth in Agentic Search 动机源于 LLM 在自主智能体搜索中因迭代式\"思考-检索\"循环导致系统记忆不断累积，引发记忆稀释问题，且现有记忆管理方法难以捕捉查询与文档间的细粒度语义关系并容易丢失大量信息；为此，该论文提出了 MemSearch-o1 框架，通过从查询的记忆种子 token 动态增长细粒度记忆片段，再利用贡献函数回溯并深度精炼记忆，最终重组为全局连接的记忆路径，将记忆管理从流式拼接转变为结构化、token 级别的增长与路径推理，从而在 8 个基准数据集上有效缓解记忆稀释并激活 LLM 的推理潜力。",
    "codeLinks": [
      "https://github.com/Applied-Machine-Learning-Lab/ACL2026_MemSearch-o1"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Memory",
      "Agent",
      "Benchmark",
      "Dataset"
    ],
    "id": 145
  },
  {
    "date": "2026.04",
    "name": "AutoSearch",
    "url": "https://arxiv.org/abs/2604.17337v1",
    "title": "AutoSearch",
    "description": "AutoSearch: Adaptive Search Depth for Efficient Agentic RAG via Reinforcement Learning Agentic RAG 系统通过多步检索交互解决复杂任务，但冗余搜索步骤带来高昂计算成本与延迟，现有方法限制搜索深度虽降低成本却导致复杂问题探索不足；为此，作者提出 AutoSearch，一种基于强化学习的框架，通过自生成中间答案评估每一步搜索并识别由问题复杂度和智能体能力共同决定的最小充分搜索深度，以奖励达到该深度、惩罚过度搜索的方式促进高效检索，同时引入稳定搜索行为与提升复杂问题答案质量的奖励机制，在多个基准上实现了更优的准确率-效率权衡。",
    "codeLinks": [
      "https://github.com/bofusun/AutoSearch"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "RAG",
      "Benchmark",
      "Token-Efficient"
    ],
    "id": 146
  },
  {
    "date": "2026.04",
    "name": "STRIDE",
    "url": "https://arxiv.org/abs/2604.17405v1",
    "title": "STRIDE",
    "description": "STRIDE: Strategic Iterative Decision-Making for Retrieval-Augmented Multi-Hop Question Answering 该文针对现有迭代式RAG方法在多跳问答中过早绑定实体导致词汇歧义级联错误、以及忽视子问题间逻辑依赖造成刚性顺序执行的问题，提出了STRIDE框架，通过策略层先构建实体无关的抽象推理骨架再实例化具体子问题、控制层依据依赖关系动态调度并行/顺序执行并自适应决定检索或推理、执行层分离事实提取与逻辑推理，同时辅以STRIDE-FT利用自生成轨迹进行模块化微调，从而在无需人工标注的情况下显著提升了复杂多跳推理的准确性与鲁棒性。",
    "codeLinks": [
      "https://github.com/MINE-USTC/STRIDE"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RAG",
      "Multi-hop QA",
      "Benchmark"
    ],
    "id": 147
  },
  {
    "date": "2026.04",
    "name": "EHRAG",
    "url": "https://arxiv.org/abs/2604.17458v1",
    "title": "EHRAG",
    "description": "EHRAG: Bridging Semantic Gaps in Lightweight GraphRAG via Hybrid Hypergraph Construction and Retrieval 针对现有轻量级 GraphRAG 仅依赖命名实体识别的结构共现关系、无法捕捉不相连实体间潜在语义关联的问题，提出了一种混合超图构建与检索框架：通过句子级共现构建结构超边，同时基于实体文本嵌入聚类构建语义超边，并采用结构-语义混合扩散检索机制结合主题感知评分与个性化 PageRank 精排来识别相关文档，在四个数据集上超越现有最优基线，且保持了线性索引复杂度和零 token 消耗的轻量特性。",
    "codeLinks": [
      "https://github.com/yfsong00/EHRAG"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Memory",
      "RAG",
      "Benchmark",
      "Dataset"
    ],
    "id": 148
  },
  {
    "date": "2026.04",
    "name": "COSEARCH",
    "url": "https://arxiv.org/abs/2604.17555v1",
    "title": "COSEARCH",
    "description": "COSEARCH: Joint Training of Reasoning and Document Ranking via Reinforcement Learning for Agentic Search 动机源于一个关键观察：现有强化学习智能搜索系统仅优化推理智能体而固定检索系统，但 Oracle 检索实验表明检索质量是性能瓶颈；它解决了检索系统与推理智能体无法协同优化的问题，提出通过 GRPO 联合训练多步推理智能体和生成式文档排序模型，并引入语义分组策略（按 token-level F1 聚类子查询以构建有效优化组）和复合奖励（结合 Hit@k 排序质量与轨迹级答案正确性），在 7 个 QA 基准上相比 Search-R1 取得 +6.6%~10.8% 的相对 F1 提升，证明了联合优化检索与推理的可行性与有效性。",
    "codeLinks": [
      "https://github.com/snap-research/CoSearch"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Benchmark"
    ],
    "id": 149
  },
  {
    "date": "2026.04",
    "name": "LiteResearcher",
    "url": "https://arxiv.org/abs/2604.17931v1",
    "title": "LiteResearcher",
    "description": "LiteResearcher: A Scalable Agentic RL Training Framework for Deep Research Agent 旨在解决 Agentic RL 在深度研究场景中难以扩展的瓶颈——手工合成数据无法激发真实搜索能力，而依赖真实搜索进行训练又成本高昂且不稳定；为此，该框架构建了一个轻量级虚拟世界来镜像真实搜索动态，使一个仅 4B 参数的小模型通过可扩展的 RL 训练即可在 GAIA 和 Xbench 等基准上超越大规模开源及商业模型（如通义 DeepResearch 和 Claude-4.5 Sonnet），取得 71.3% 和 78.0% 的开源最优成绩。",
    "codeLinks": [
      "https://github.com/simplex-ai-inc/LiteResearcher"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark",
      "Open-Source"
    ],
    "id": 150
  },
  {
    "date": "2026.04",
    "name": "CalibAdv",
    "url": "https://arxiv.org/abs/2604.18235v1",
    "title": "Negative Advantage Is a Double-Edged Sword",
    "description": "Negative Advantage Is a Double-Edged Sword: Calibrating Advantage in GRPO for Deep Search 本文针对深度搜索智能体在使用 GRPO 训练时面临的两大核心问题——正确中间步骤被错误惩罚以及负向优势主导导致的训练崩溃——提出了 CalibAdv 方法，通过基于中间步骤检索文档正确性的软惩罚机制、最终答案步骤的正负优势重平衡策略，以及将格式相关特殊 token 与优势信号解耦，实现了对 GRPO 优势值的细粒度校准，在提升模型问答性能的同时有效稳定了训练过程。",
    "codeLinks": [
      "https://github.com/wujwyi/CalibAdv"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Process Reward",
      "Agent",
      "Search Agent"
    ],
    "id": 151
  },
  {
    "date": "2026.04",
    "name": "ArbGraph",
    "url": "https://arxiv.org/abs/2604.18362v1",
    "title": "ArbGraph",
    "description": "ArbGraph: Conflict-Aware Evidence Arbitration for Reliable Long-Form Retrieval-Augmented Generation 动机是现有长文本RAG在检索证据存在噪声或矛盾时缺乏显式冲突解决机制，导致生成过程中错误会传播；解决的问题是在生成长文本前如何显式地仲裁和解决检索证据中的事实冲突；提出的方法是 ArbGraph 框架，通过将文档分解为原子声明并构建带有显式支持/矛盾关系的证据图，在生成前进行迭代式可信度仲裁，从而筛选出一致可靠的证据集用于下游生成。",
    "codeLinks": [
      "https://github.com/1212Judy/ArbGraph"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RAG",
      "Benchmark"
    ],
    "id": 152
  },
  {
    "date": "2026.04",
    "name": "DR-Venus",
    "url": "https://arxiv.org/abs/2604.19859v1",
    "title": "DR-Venus",
    "description": "DR-Venus: Towards Frontier Edge-Scale Deep Research Agents with Only 10K Open Data 旨在解决边缘端小型深度研究智能体在有限开放数据下性能不足的问题——这类小模型虽在成本、延迟和隐私上具备部署优势，但此前难以达到前沿水平；为此，该工作提出了一套两阶段训练方案，先通过结合严格数据清洗与长程轨迹重采样的智能体监督微调建立基础智能体能力，再通过基于信息增益和格式感知正则化设计的回合级奖励进行智能体强化学习以提升长程任务执行可靠性，最终仅用约 10K 开放数据训练出的 4B 模型便在多项深度研究基准上显著超越此前 9B 以下智能体模型，并缩小了与 30B 级大模型的差距，揭示了小模型在测试时扩展下的惊人潜力。",
    "codeLinks": [
      "https://github.com/inclusionAI/DR-Venus"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "SFT",
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 153
  },
  {
    "date": "2026.04",
    "name": "S2G-RAG",
    "url": "https://arxiv.org/abs/2604.23783v1",
    "title": "S2G-RAG",
    "description": "S2G-RAG: Structured Sufficiency and Gap Judging for Iterative Retrieval-Augmented QA 该论文提出S2G-RAG框架，旨在解决迭代式RAG在多跳问答中的检索控制瓶颈：现有系统难以判断当前证据是否充分、无法明确下一跳缺失信息，且多轮检索易积累噪声干扰后续推理。为此，作者设计了轻量级控制器S2G-Judge，每轮显式输出\"证据充分性\"二元判断和结构化的信息缺口（gap items），将缺失信息映射为下一轮查询目标，并通过句子级证据提取器维持紧凑上下文；该控制器通过从多轮执行轨迹中蒸馏过程监督信号进行训练，在TriviaQA、HotpotQA和2WikiMultiHopQA上显著提升了多跳问答性能与鲁棒性。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Process Reward",
      "RAG",
      "Multi-hop QA",
      "Benchmark"
    ],
    "id": 154
  },
  {
    "date": "2026.04",
    "name": "DRACULA",
    "url": "https://arxiv.org/abs/2604.23815v1",
    "title": "DRACULA",
    "description": "DRACULA: Hunting for the Actions Users Want Deep Research Agents to Execute 现有深度研究（DR）智能体的评估仅针对最终报告打分，导致无法研究哪些中间动作能真正提升报告质量，为此研究者构建了首个包含用户对中间动作反馈的 DRACULA 数据集（8,103 条动作偏好与 5,230 条执行判断），并通过模拟实验发现 LLM 利用用户完整选择历史最能预测其偏好动作，且用户未明确的目标会导致同一查询下选择差异，进而提出基于用户历史交互动态生成新动作的在线干预策略，揭示了\"决定执行哪些动作\"是比\"如何执行\"更关键的挑战。",
    "codeLinks": [
      "https://github.com/allenai/dracula"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Dataset"
    ],
    "id": 155
  },
  {
    "date": "2026.04",
    "name": "SEARCH-R",
    "url": "https://arxiv.org/abs/2604.24515v1",
    "title": "SEARCH-R",
    "description": "SEARCH-R: Structured Entity-Aware Retrieval with Chain-of-Reasoning Navigator for Multi-hop Question Answering 该论文针对多跳问答（MHQA）中推理路径生成缺乏有效控制、容易偏离正确方向，以及传统检索方法过度依赖相似度分数而非信息实际效用导致检索结果同质化或无用的问题，提出了SEARCH-R框架：通过微调Llama3.1-8B训练端到端推理路径导航器来实现受控的子问题分解，并设计了基于依赖树的检索机制以定量评估文档的信息贡献度，从而在三个多跳问答数据集上验证了有效性。",
    "codeLinks": [
      "https://github.com/Applied-Machine-Learning-Lab/ACL2026_SEARCH-R"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Multi-hop QA",
      "Benchmark",
      "Dataset"
    ],
    "id": 156
  },
  {
    "date": "2026.04",
    "name": "EDR",
    "url": "https://arxiv.org/abs/2604.24978v1",
    "title": "Dont Stop Early",
    "description": "Dont Stop Early: Scalable Enterprise Deep Research with Controlled Information Flow and Evidence-Aware Termination 这篇论文针对现有 Deep Research 系统在企业场景中因信息覆盖不均、上下文膨胀和过早停止而难以产出决策就绪报告的问题，提出了一个可扩展的企业深度研究（EDR）架构。该架构首先通过大纲生成与反思将研究请求分解为覆盖驱动的信息目标，确保所有分析维度在调查前就被明确枚举；然后利用依赖关系构建有向无环图（DAG）执行计划，使独立步骤可并行运行，同时通过显式依赖链接控制中间结果的共享时机，将每个智能体的上下文局部化，防止无关信息累积；最后为每个研究步骤预设基于证据的终止条件，要求智能体迭代收集并评估证据直至满足充分性标准，从而避免过早停止并稳定各章节的分析深度。实验表明，该系统在企业销售赋能任务和公开 DeepResearch Bench 基准上均优于现有基线，消融研究进一步证实依赖控制的信息流和步骤级充分性条件是提升覆盖率和报告质量的关键。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Process Reward",
      "Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 157
  },
  {
    "date": "2026.04",
    "name": "AutoResearchBench",
    "url": "https://arxiv.org/abs/2604.25256v1",
    "title": "AutoResearchBench",
    "description": "AutoResearchBench: Benchmarking AI Agents on Complex Scientific Literature Discovery 动机在于现有通用智能体基准无法有效评估 AI 在科研场景中的文献检索能力，因此作者构建了一个专门衡量自主科学文献发现的基准测试；它解决了通用基准缺乏研究深度、文献细粒度利用和开放性问题，提出了包含\"深度研究\"（渐进式多步追踪目标论文）和\"广度研究\"（全面收集满足条件论文集）两种任务的评测框架，实验显示即使最强 LLM 在该基准上准确率也仅约 9%，凸显了自主科研文献发现的巨大挑战。",
    "codeLinks": [
      "https://github.com/CherYou/AutoResearchBench"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 158
  },
  {
    "date": "2026.04",
    "name": "ReaLM-Retrieve",
    "url": "https://arxiv.org/abs/2604.26649v1",
    "title": "When to Retrieve During Reasoning",
    "description": "When to Retrieve During Reasoning: Adaptive Retrieval for Large Reasoning Models 该文针对大型推理模型（如 DeepSeek-R1、OpenAI o1）在生成长达数万 token 的多步推理链时，传统 RAG\"先检索后生成\"的范式无法应对推理中途知识缺口、且现有迭代检索方法存在粒度不匹配、信号不可用和效率崩溃等问题，提出了 ReaLM-Retrieve 框架，通过步骤级不确定性检测（RSUS）、学习式检索干预策略和效率优化集成机制，实现了在推理步骤粒度上的自适应检索，在 MuSiQue 等基准上平均提升 10.1% F1 的同时减少 47% 的检索调用。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Process Reward",
      "RAG",
      "Benchmark",
      "Token-Efficient"
    ],
    "id": 159
  },
  {
    "date": "2026.04",
    "name": "NeocorRAG",
    "url": "https://arxiv.org/abs/2604.27852v1",
    "title": "NeocorRAG",
    "description": "NeocorRAG: Less Irrelevant Information, More Explicit Evidence, and More Effective Recall via Evidence Chains 该研究针对RAG中\"检索召回率提升却无法有效转化为推理准确率改善\"的核心痛点，提出了一种名为NeocorRAG的框架；其动机源于发现现有检索指标（如Recall@n）仅能衡量\"是否命中相关文档\"，却无法评估检索内容对下游推理的真实贡献，导致高召回往往伴随大量干扰噪声和隐性证据缺失，为此作者创新性地提出\"召回转化率（RCR）\"指标来量化检索对推理的实际贡献，并揭示了当前结构增强方法（高召回但噪声大）与推理增强方法（低噪声但召回不足）之间的权衡困境；NeocorRAG通过系统性地挖掘和利用\"证据链\"来优化检索质量，具体采用激活路径搜索算法在文档子图中锁定候选证据空间、利用前缀树约束解码精确生成证据链、并基于证据链过滤干扰文档并显化隐性关联证据",
    "codeLinks": [
      "https://github.com/BUPT-Reasoning-Lab/NeocorRAG"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RAG"
    ],
    "id": 160
  },
  {
    "date": "2026.05",
    "name": "Ψ-RAG",
    "url": "https://arxiv.org/abs/2605.00529v1",
    "title": "Hierarchical Abstract Tree for Cross-Document Retrieval-Augmented Generation 该工作针对现有树形检索增强生成（Tree-RA",
    "description": "Hierarchical Abstract Tree for Cross-Document Retrieval-Augmented Generation 该工作针对现有树形检索增强生成（Tree-RAG）方法仅能处理单文档、难以扩展至跨文档多跳问答的局限性，提出了 Ψ-RAG 框架：通过\"合并与折叠\"迭代构建自适应数据分布的层次抽象树索引，并配备一个能动态重组查询、协同树索引与稀疏关键词索引进行多轮交互推理的多粒度检索智能体，从而在保持高效索引的同时，显著提升跨文档多跳检索与生成性能。",
    "codeLinks": [
      "https://github.com/Newiz430/Psi-RAG"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "RAG",
      "Multi-hop QA",
      "Benchmark"
    ],
    "id": 161
  },
  {
    "date": "2026.05",
    "name": "Verbal-R3",
    "url": "https://arxiv.org/abs/2605.01399v1",
    "title": "Verbal-R3",
    "description": "Verbal-R3: Verbal Reranker as the Missing Bridge between Retrieval and Reasoning 现有RAG直接将原始检索文本注入LLM上下文，导致信息整合次优（存在暴露偏差、分布不匹配和噪声干扰）如何有效桥接检索结果与LLM推理能力，使模型能准确利用检索到的证据；引入\"Verbal Annotations\"（ verbal化的查询-文档逻辑关联分析叙事）作为认知桥梁，并基于此构建Verbal-R3框架——包含一个执行迭代检索推理的Generator和一个生成Verbal Annotations及相关性评分的Verbal Reranker，配合相关性引导的测试时缩放策略来高效分配计算资源。",
    "codeLinks": [
      "https://github.com/0k9d0h1/VerbalR3"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RAG",
      "Benchmark"
    ],
    "id": 162
  },
  {
    "date": "2026.05",
    "name": "SciResearcher",
    "url": "https://arxiv.org/abs/2605.01489v1",
    "title": "SciResearcher",
    "description": "SciResearcher: Scaling Deep Research Agents for Frontier Scientific Reasoning SciResearcher 针对现有深度研究智能体在前沿科学领域的数据构建局限，提出了一个全自动框架：通过智能体网络探索构建两类任务——概念任务利用\"锚点实体\"迭代增强生成多跳推理问题，计算任务则经三级证据筛选提取科学模型并辅以多求解器验证；基于所构建的 SciResearcherQA 数据集对 Qwen3-8B 进行监督微调与强化学习后，得到的 SciResearcher-8B 在多个前沿科学推理基准上取得同规模新 SOTA，甚至超越更大参数的专有智能体，为扩展科学发现智能体提供了可扩展的新范式。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "SFT",
      "Agent",
      "Search Agent",
      "Multi-hop QA",
      "Deep Research",
      "Benchmark",
      "Dataset"
    ],
    "id": 163
  },
  {
    "date": "2026.05",
    "name": "OpenSeeker-v2",
    "url": "https://arxiv.org/abs/2605.04036v1",
    "title": "OpenSeeker-v2",
    "description": "OpenSeeker-v2: Pushing the Limits of Search Agents with Informative and High-Difficulty Trajectories 动机是打破工业巨头对前沿搜索智能体开发的垄断，证明无需耗费大量资源的预训练、持续预训练和强化学习流程，仅用监督微调也能训练出顶尖搜索智能体；它解决了学术界因资源受限难以追赶工业级搜索智能体性能的问题，通过扩大知识图谱规模以丰富探索、扩展工具集以增强功能、并严格过滤低步数轨迹筛选高质量数据这三种简单的数据合成策略，仅用 10.6k 数据点进行 SFT，就在四个基准上超越了使用重资源流程训练的通义 DeepResearch，成为首个由纯学术团队仅靠 SFT 达到 SOTA 的搜索智能体。",
    "codeLinks": [
      "https://github.com/rui-ye/OpenSeeker"
    ],
    "datasetLinks": [
      "https://huggingface.co/datasets/OpenSeeker/OpenSeeker-v1-Data"
    ],
    "year": 2026,
    "tags": [
      "RL-based",
      "SFT",
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 164
  },
  {
    "date": "2026.05",
    "name": "LongSeeker",
    "url": "https://arxiv.org/abs/2605.05191v1",
    "title": "LongSeeker",
    "description": "LongSeeker: Elastic Context Orchestration for Long-Horizon Search Agents 这篇论文的动机是：长程搜索智能体在执行多步推理时，工作上下文会无限制增长，导致噪声累积、成本上升和错误率增加，因此需要一种自适应的上下文管理机制。它解决的问题是：现有方法（如滑动窗口截断、阈值重启、固定粒度摘要）无法根据任务演化状态对历史信息进行精细化、按需的塑形，导致重要证据丢失或冗余信息干扰。提出的方法是 Context-ReAct 范式，通过 Skip、Compress、Rollback、Snippet、Delete 五种原子元操作，让智能体在每一步主动决定何时、何地、如何重塑上下文，从而实现弹性上下文编排；并基于此微调出 LongSeeker 模型，在 BrowseComp 等长程搜索基准上显著超越同类基线。",
    "codeLinks": [
      "https://github.com/PolarSeeker/LongSeeker"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 165
  },
  {
    "date": "2026.05",
    "name": "VOI",
    "url": "https://arxiv.org/abs/2605.05701v1",
    "title": "Inference-Time Budget Control for LLM Search Agents 该文针对LLM搜索智能体在推理时面临工具调用与生成token双重硬预算约束的问题，提出了一种无需",
    "description": "Inference-Time Budget Control for LLM Search Agents 该文针对LLM搜索智能体在推理时面临工具调用与生成token双重硬预算约束的问题，提出了一种无需训练的两阶段推理时预算控制方法：搜索阶段通过任务级信息价值（VOI）评分在检索、问题分解和回答承诺之间动态分配剩余预算，回答阶段则通过基于证据的选择性最终确定器仅对低风险的答案形式错误（如极性、二元选择等）进行保守重写，从而在四个多跳问答基准和多个预算级别下实现了相比基线的一致性能提升。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Multi-hop QA",
      "Benchmark"
    ],
    "id": 166
  },
  {
    "date": "2026.05",
    "name": "WCR",
    "url": "https://arxiv.org/abs/2605.05702v1",
    "title": "Knowledge-Graph Paths as Intermediate Supervision for Self-Evolving Search Agents 该论文针对 Search Self-",
    "description": "Knowledge-Graph Paths as Intermediate Supervision for Self-Evolving Search Agents 该论文针对 Search Self-Play（SSP）自进化搜索智能体框架的两个瓶颈——Proposer 因缺乏关系上下文而生成大量无效问题、Solver 仅获得稀疏二元奖励导致部分正确轨迹被浪费——提出利用知识图谱路径作为构造派生的中间监督：一方面通过 LLM 引导的子图提取为 Proposer 提供关系上下文以生成更连贯的多跳问题，另一方面基于构造路径的中间实体设计路径点覆盖奖励（WCR），为错误但覆盖部分路径点的 Solver 轨迹赋予分级部分奖励，从而在无需额外人工标注的情况下同时提升问题构造质量和训练样本效率，在 7 个 QA 基准和 9 种模型配置下均优于标准 SSP，尤其在多跳推理任务上效果显著。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Self-Play",
      "Agent",
      "Search Agent",
      "Multi-hop QA",
      "Benchmark",
      "Token-Efficient"
    ],
    "id": 167
  },
  {
    "date": "2026.05",
    "name": "LatentRAG",
    "url": "https://arxiv.org/abs/2605.06285v1",
    "title": "LatentRAG",
    "description": "LatentRAG: Latent Reasoning and Retrieval for Efficient Agentic RAG 该论文针对现有智能体RAG（Agentic RAG）方法因需逐令牌自回归生成冗长的思维链和子查询而导致推理延迟极高（约为单步RAG的16–22倍）的问题，提出了LatentRAG框架，通过将推理与检索从离散语言空间转移到连续潜空间，利用单次前向传播生成潜思维和潜子查询令牌，并设计潜空间对齐目标实现检索模型的端到端联合优化，同时引入可选的并行潜解码机制以兼顾透明性，最终在七个基准数据集上实现了与显式Agentic RAG相当的性能（差距<5%），并将推理延迟降低约90%。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "RAG",
      "Benchmark",
      "Dataset"
    ],
    "id": 168
  },
  {
    "date": "2026.05",
    "name": "Source Attribution Evaluation",
    "url": "https://arxiv.org/abs/2605.06635v1",
    "title": "Cited but Not Verified",
    "description": "Cited but Not Verified: Parsing and Evaluating Source Attribution in LLM Deep Research Agents 该论文的动机是：当前LLM深度研究智能体生成的引用无法被可靠验证，现有评估方法仅关注二元归因或引用匹配，缺乏对链接可访问性、主题相关性和事实准确性的多维度端到端评估框架。它解决的问题是：如何系统性地量化LLM引用质量，并探究增加搜索深度是否会提升引用可靠性。提出的方法是首个基于Markdown AST解析器的三阶段评估流水线——结构提取引用-声明对、检索实际来源内容，并通过LLM-as-a-judge在\"链接有效、内容相关、事实准确\"三个维度进行评分；对14个模型的基准测试揭示，即使最强模型的链接有效性超94%、相关性超80%，事实准确率仅39-77%，且消融实验证明随着工具调用从2次增至150次，事实准确性平均暴跌42%，证实了\"信息过载\"效应——更多检索反而损害事实合成能力。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 169
  },
  {
    "date": "2026.05",
    "name": "PACEvolve++",
    "url": "https://arxiv.org/abs/2605.07039v1",
    "title": "PACEvolve++",
    "description": "PACEvolve++: Improving Test-time Learning for Evolutionary Search Agents 针对现有进化搜索智能体依赖固定提示策略、无法将搜索经验内化为决策偏好的局限，提出了一个顾问模型强化学习框架：通过将\"搜索决策\"（假设生成与选择）与\"代码实现\"解耦，让可训练的顾问模型专注学习任务特定的搜索动态，同时设计了一种阶段自适应的信用分配机制——早期探索时利用组相对反馈学习广泛偏好，后期精炼时转为评估候选对 best-of-k 前沿的贡献——从而在专家并行负载均衡、序列推荐和蛋白质适应度外推等真实任务上实现了更快的收敛和更稳定的测试时训练。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent"
    ],
    "id": 170
  },
  {
    "date": "2026.05",
    "name": "CGDP",
    "url": "https://arxiv.org/abs/2605.07042v1",
    "title": "The Context Gathering Decision Process",
    "description": "The Context Gathering Decision Process: A POMDP Framework for Agentic Search 该论文指出LLM智能体在复杂环境中因上下文窗口有限，迭代搜索时会出现工作记忆退化为有损表示、重复循环和过早停止等问题；为此，作者将交互式信息搜索形式化为\"上下文收集决策过程（CGDP）\"这一POMDP框架，并提出谓词自适应识别（PBAI）算法将搜索分解为显式模块化操作，进而推导出两个干预措施——用持久化的谓词信念状态替代隐式轨迹历史以在限制上下文的同时保留多跳推理，以及用程序性启发式信号替代LLM自评估来检测搜索停滞以避免冗余循环和过早终止，实验表明前者提升多跳推理最多11.4%，后者节省最多39%的token且不影响性能。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Multi-hop QA"
    ],
    "id": 171
  },
  {
    "date": "2026.05",
    "name": "HyperEyes",
    "url": "https://arxiv.org/abs/2605.07177v1",
    "title": "HyperEyes",
    "description": "HyperEyes: Dual-Grained Efficiency-Aware Reinforcement Learning for Parallel Multimodal Search Agents 动机在于现有顺序处理的多模态搜索智能体存在冗余交互轮次，且单纯并行调用易退化为暴力过度搜索；它通过统一有依据搜索（UGS）将视觉定位与检索融合为原子动作以实现并发查询，并采用双粒度效率感知强化学习框架——宏观上通过 TRACE 动态收紧轨迹级效率参考以抑制冗余工具调用，微观上通过 OPD 对失败轨迹注入教师模型的密集 token 级修正信号——在六个基准上实现开源可比规模模型中最优的准确率与效率帕累托前沿，其中 30B 模型以 9.9% 的准确率提升和 5.3 倍的工具调用轮次缩减超越最强开源基线。",
    "codeLinks": [
      "https://github.com/Guankai-Li/HyperEyes"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent",
      "Benchmark",
      "Token-Efficient",
      "Open-Source"
    ],
    "id": 172
  },
  {
    "date": "2026.05",
    "name": "InterLV-Search-Bench",
    "url": "https://arxiv.org/abs/2605.07510v1",
    "title": "InterLV-Search",
    "description": "InterLV-Search: Benchmarking Interleaved Multimodal Agentic Search 该论文的动机在于现有基准测试将视觉证据仅视为答案终点而非搜索轨迹中的动态控制信号，忽略了视觉证据在决定下一步检索目标中的关键作用；它解决了现有基准无法评估\"交错式多模态搜索\"（即视觉和文本证据在搜索过程中反复相互引导、动态切换）能力的问题；提出的方法是构建三层级基准测试 InterLV-Search（主动视觉证据寻求、受控离线交错搜索、开放网页交错搜索），包含 2,061 个样本并涵盖多分支搜索场景，同时配套提供标准化评估框架 InterLV-Agent 用于统一工具调用、轨迹记录和模型对比，实验表明当前多模态智能体在该任务上准确率仍低于 50%，凸显了视觉证据定位、搜索控制和多模态证据整合等核心挑战。",
    "codeLinks": [
      "https://github.com/hbhalpha/InterLV-Search-Bench"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Benchmark"
    ],
    "id": 173
  },
  {
    "date": "2026.05",
    "name": "PiCA",
    "url": "https://arxiv.org/abs/2605.09287v1",
    "title": "PiCA",
    "description": "PiCA: Pivot-Based Credit Assignment for Search Agentic Reinforcement Learning 现有基于大语言模型的搜索智能体在强化学习训练中面临长程信用分配的三大挑战：奖励稀疏导致步骤级动作质量难以区分、信用孤立导致步骤间序列依赖被忽略、以及分布偏移导致奖励估计偏离模型自然生成分布。为此，论文提出PiCA（Pivot-Based Credit Assignment），一种基于支点的步骤奖励机制，它基于Potential-Based Reward Shaping将搜索轨迹重构为累积搜索进度的序列过程，通过从历史轨迹中识别能显著提升正确答案概率的\"支点步骤\"（黄金子查询与子答案）作为信息峰值，将过程奖励定义为依赖历史上下文的成功概率，从而提供密集、支点感知且轨迹依赖的指导，同时保持分布一致性。实验表明，PiCA在7个知识密集型QA基准上显著优于强基线，3B和7B模型分别提升15.2%和2.2%。",
    "codeLinks": [
      "https://github.com/novdream/PiCA"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Process Reward",
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 174
  },
  {
    "date": "2026.05",
    "name": "RubricEM",
    "url": "https://arxiv.org/abs/2605.10899v1",
    "title": "RubricEM",
    "description": "RubricEM: Meta-RL with Rubric-guided Policy Decomposition beyond Verifiable Rewards 动机在于训练深度研究智能体时，传统强化学习依赖可验证奖励的范式已无法适用——这类智能体的输出缺乏标准答案、决策轨迹漫长且涉及多步工具调用，而现有后训练机制也无法将历史经验转化为可复用知识；为此，论文提出将评分标准（rubric）作为策略执行、评判反馈和智能体记忆的共享接口，构建了 RubricEM 框架，该框架通过阶段化策略分解让研究轨迹具备规划、证据收集、审阅和综合的阶段意识，利用 Stage-Structured GRPO 基于阶段性评分标准提供更密集的语义反馈以解决长时程信用分配问题，并训练共享骨干的反思元策略将已评判轨迹蒸馏为可复用的评分标准指导，最终在四个长格式研究基准上，RubricEM-8B 超越了同类开源模型并接近专有深度研究系统的性能。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark",
      "Open-Source"
    ],
    "id": 175
  },
  {
    "date": "2026.05",
    "name": "CuSearch",
    "url": "https://arxiv.org/abs/2605.11611v1",
    "title": "CuSearch",
    "description": "CuSearch: Curriculum Rollout Sampling via Search Depth for Agentic RAG 该工作指出现有 RLVR 方法在训练 agentic RAG 时采用均匀采样 rollout，忽视了搜索深度更深的轨迹包含更多检索决策点、监督信号更密集的事实，且随着训练进行批次内深度分布上移，均匀采样无法自适应利用这一变化；为此提出 CuSearch 框架，通过 SDGA 算子将固定更新预算重新分配给更深搜索的轨迹（SDGA-Auto 隐式跟随深度分布上移，SDGA-Phase 显式推进课程阈值），在多个模型和检索框架上持续提效，ZeroSearch 上较标准 GRPO 最高提升 11.8 个精确匹配点，并验证了搜索深度可作为无需标注的检索监督密度代理指标。",
    "codeLinks": [
      "https://github.com/MrToser/CuSearch"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "RAG"
    ],
    "id": 176
  },
  {
    "date": "2026.05",
    "name": "AgentDisCo",
    "url": "https://arxiv.org/abs/2605.11732",
    "title": "AgentDisCo",
    "description": "AgentDisCo: Towards Disentanglement and Collaboration in Open-ended Deep Research Agents 动机在于现有深度研究智能体将信息探索与利用混为一谈，缺乏解耦和协作机制；它通过引入对抗优化的 Critic 与 Generator 双智能体架构，让评判智能体评估大纲并优化查询、生成智能体检索结果并修订大纲，同时利用元优化框架自动生成质量信号并构建可复用策略库实现自我优化，还提出基于用户浏览历史的 GALA 基准和海报渲染智能体，在多个基准上达到或超越领先闭源系统性能。",
    "codeLinks": [
      "https://github.com/AgentDisCo-Project"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 177
  },
  {
    "date": "2026.05",
    "name": "EcoGEO",
    "url": "https://arxiv.org/abs/2605.12887v1",
    "title": "EcoGEO",
    "description": "EcoGEO: Trajectory-Aware Evidence Ecosystems for Web-Enabled LLM Search Agents 动机在于现有 GEO 研究仅聚焦单网页优化，忽略了智能体搜索是多步轨迹过程，影响力取决于页面在浏览路径中的组织与连接方式；它解决了页面级 GEO 无法引导智能体在多步证据采集中持续强化目标产品的问题，提出了 TRACE 方法——通过构建协调的入口页与支持页生态系统，利用共享术语、内部链接和一致属性来塑造智能体的查询、爬取与综合过程，从而在轨迹层面提升目标推荐成功率。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent"
    ],
    "id": 178
  },
  {
    "date": "2026.05",
    "name": "PyRAG",
    "url": "https://arxiv.org/pdf/2605.12975v1",
    "title": "Retrieval is Cheap, Show Me the Code",
    "description": "Retrieval is Cheap, Show Me the Code: Executable Multi-Hop Reasoning for Retrieval-Augmented Generation 动机源于现有 RAG 系统在多跳问答中的脆弱性——自由形式的自然语言推理导致中间状态隐含、检索查询漂移、自反思不可靠；为此，作者提出将多跳 RAG 重新定义为可执行 Python 程序的程序合成与执行，使推理过程变量化、中间状态透明化、反馈确定性化，并支持编译器驱动的自修复与执行驱动的自适应检索，在五个 QA 基准上持续超越强基线。",
    "codeLinks": [
      "https://github.com/GasolSun36/PyRAG"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RAG",
      "Multi-hop QA",
      "Benchmark"
    ],
    "id": 179
  },
  {
    "date": "2026.05",
    "name": "ViDR",
    "url": "https://arxiv.org/abs/2605.13034v1",
    "title": "ViDR",
    "description": "ViDR: Grounding Multimodal Deep Research Reports in Source Visual Evidence 这篇论文提出了ViDR框架，旨在解决当前深度研究系统过度依赖文本证据、而原始视觉证据（如图表）未被充分利用的问题。ViDR通过将来源图表构建为可检索、可解释、可路由且可验证的证据对象，并辅以上下文感知过滤、大纲感知重排序和VLM视觉分析来精炼网络图片，同时引入MMR Bench+基准测试，显著提升了多模态深度研究报告的证据基础、视觉支撑力和可验证性。",
    "codeLinks": [
      "https://github.com/PKU-JX-LAB/PKU_MMDR"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Deep Research",
      "Benchmark"
    ],
    "id": 180
  },
  {
    "date": "2026.05",
    "name": "R<sup>2</sup>-Mem",
    "url": "https://arxiv.org/abs/2605.13486v1",
    "title": "R<sup>2</sup>-Mem",
    "description": "R<sup>2</sup>-Mem: Reflective Experience for Memory Search 现有深度搜索智能体虽能让记忆系统无需预管理大量信息即可检索细粒度历史内容，但由于无法从历史搜索轨迹中学习，导致反复重复过去的错误行为；为此，作者提出 R<sup>2</sup>-Mem（Reflective Experience for Memory Search），一个面向记忆搜索的反思经验框架，其核心是在离线阶段通过评分器（Rubric-guided Evaluator）对历史轨迹中的高低质量步骤进行打分，再由自反思学习器（Self-Reflection Learner）将这些经验蒸馏为抽象规则，在线推理时检索并复用这些经验来指导后续搜索动作，从而避免重复错误并保持高质量行为——实验表明该框架在无需强化学习且成本极低的情况下，可将 F1 提升最高 22.6%，同时减少 12.9% 的 token 消耗和 20.2% 的搜索迭代次数。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Memory",
      "Agent",
      "Search Agent",
      "Benchmark"
    ],
    "id": 181
  },
  {
    "date": "2026.05",
    "name": "MultiSearch",
    "url": "https://arxiv.org/abs/2605.13534v1",
    "title": "Scaling Retrieval-Augmented Reasoning with Parallel Search and Explicit Merging 针对现有深度搜索智能体在每一步推理中仅生",
    "description": "Scaling Retrieval-Augmented Reasoning with Parallel Search and Explicit Merging 针对现有深度搜索智能体在每一步推理中仅生成单查询检索导致信息覆盖不足、噪声过高、信噪比低及推理冗余的问题，提出了一个基于强化学习的框架，通过多视角并行检索扩大信息覆盖并减少对单一结果的依赖，再通过显式合并与精炼检索内容提升信噪比，同时采用多进程奖励设计的 RL 训练策略优化检索与整合能力，在 7 个基准数据集上验证了其优于基线方法的推理性能。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "RAG",
      "Search Agent",
      "Benchmark",
      "Dataset"
    ],
    "id": 182
  },
  {
    "date": "2026.05",
    "name": "Argus",
    "url": "https://arxiv.org/abs/2605.16217v1",
    "title": "Argus",
    "description": "Argus: Evidence Assembly for Scalable Deep Research Agents 动机在于解决现有深度研究智能体并行搜索时重复收集证据、导致边际收益递减和上下文膨胀的问题；它提出了一种由 Searcher 负责通过 ReAct 式交互收集子查询证据、由 Navigator 维护共享证据图并调度搜索与综合推理的双智能体协作框架，将深度研究从并行暴力求解转变为互补证据的拼图式组装，从而在多个基准上显著提升性能并保持可控的上下文开销。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 183
  },
  {
    "date": "2026.05",
    "name": "GRASP",
    "url": "https://arxiv.org/abs/2605.16598v1",
    "title": "GRASP",
    "description": "GRASP: Graph Agentic Search over Propositions for Multihop Question Answering 旨在解决现有知识图谱增强的智能体检索系统在多跳问答中面临的高昂索引构建成本与推理阶段 token 消耗累积的问题，提出了一种通过将多跳查询动态分解为依赖感知的子计划、并根据问题复杂度弹性调度子智能体数量的方法；每个子智能体在由实体、命题和段落构成的三层层次化图上进行搜索，利用实体层实现精准遍历、通过命题层的互反排名投票完成高召回段落检索，从而在 MuSiQue、2WikiMultihopQA 和 HotpotQA 的开放检索与 LongBench 扩展上下文推理场景中，以比现有最优方法减少 30-50% token 的代价取得了最高的问答准确率，并引入了\"success economy\"（按难度加权的每正确答案摊销 token 成本）这一效率感知评估指标。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Multi-hop QA",
      "Token-Efficient"
    ],
    "id": 184
  },
  {
    "date": "2026.05",
    "name": "SD-Search",
    "url": "https://arxiv.org/abs/2605.18299v1",
    "title": "SD-Search",
    "description": "SD-Search: On-Policy Hindsight Self-Distillation for Search-Augmented Reasoning 动机在于解决搜索增强推理智能体在标准 GRPO 强化学习框架下面临的核心困境：整个轨迹只共享一个基于最终答案正确性的结果奖励，导致模型无法判断轨迹中每个搜索查询的优劣，从而难以学习高质量的检索策略。为此，论文提出了同策略事后自蒸馏方法，让同一模型分别扮演\"学生\"和\"教师\"两种角色——学生只能看到推理时的标准上下文，而教师额外获得一个事后信息块（包含同问题下多个 rollouts 的搜索查询及成败标签）；通过最小化学生在搜索查询 token 上的分布与教师分布之间的 Jensen-Shannon 散度，将事后才能获得的步骤级监督信号蒸馏给学生，使其学会哪些查询值得发出、哪些应避免。该方法完全在标准 RL 训练循环内实现，无需外部大模型教师或额外标注，在七个单跳和多跳问答基准上均显著超越纯结果奖励基线，并与依赖 72B 教师模型的领先流程监督方法持平或更优。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Process Reward",
      "Agent",
      "Multi-hop QA",
      "Benchmark"
    ],
    "id": 185
  },
  {
    "date": "2026.05",
    "name": "DeepWeb-Bench",
    "url": "https://arxiv.org/abs/2605.21482v1",
    "title": "DeepWeb-Bench",
    "description": "DeepWeb-Bench: A Deep Research Benchmark Demanding Massive Cross-Source Evidence and Long-Horizon Derivation 这篇论文的动机是当前深度研究基准对前沿模型过于简单、缺乏区分度；它解决的问题是如何构建一个能真正考验大规模证据收集、跨来源调和与长程多步推导的综合基准；提出的方法是DEEPWEB-BENCH，通过8×8矩阵式任务结构覆盖检索、推导、推理和校准四类能力，并配备四级来源追溯与细粒度评分规则，实验发现检索并非瓶颈而推导与校准才是主要难点，且强弱模型的失败模式存在质性差异。",
    "codeLinks": [
      "https://github.com/sixiongxie1001-dot/deep-research-benchmark2.0"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Deep Research",
      "Benchmark"
    ],
    "id": 186
  },
  {
    "date": "2026.05",
    "name": "SGR-Bench",
    "url": "https://arxiv.org/abs/2605.22219v1",
    "title": "SGR-Bench",
    "description": "SGR-Bench: Benchmarking Search Agents on State-Gated Retrieval 该文提出状态门控检索（State-Gated Retrieval, SGR）这一被现有基准忽视的核心能力——在专业数据检索网站上，答案证据往往隐藏在筛选器、视图层级等站点特定状态之后，找到正确网站只是第一步，更关键的是配置正确的检索状态才能使证据可见。为此构建 SGR-BENCH 基准（100 个任务、12 个数据生态系统），通过系统化整理与配对任务设计评测 11 个系统，发现最强模型 Item-F1 仅 66.18%，主要失败原因并非找不到网站或组装答案，而是检索状态维持失败——\"范围漂移\"和\"标准不匹配\"占失败原因的 64.7%。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Benchmark"
    ],
    "id": 187
  },
  {
    "date": "2026.05",
    "name": "Search-E1",
    "url": "https://arxiv.org/abs/2605.22511",
    "title": "Search-E1",
    "description": "Search-E1: Self-Distillation Drives Self-Evolution in Search-Augmented Reasoning 这篇论文的动机是质疑搜索增强推理领域日益复杂的后训练方法——这些方法不断引入外部强监督系统、辅助模块、树状搜索或手工奖励函数，导致训练流程臃肿且依赖额外资源；作者想验证这些复杂机制是否真的必要。它解决的问题是如何在不借助任何外部教师、过程奖励模型或额外标注的前提下，为搜索增强智能体提供密集的逐 token 监督信号，从而克服标准 GRPO 仅依赖最终答案正确性、导致整个轨迹内所有 token 共享同一稀疏梯度、无法区分搜索步骤质量的缺陷。提出的方法是 Search-E1，一种自进化训练流程：交替执行标准 GRPO（在轨迹层面探索）与离线自蒸馏 OFSD（在 token 层面巩固）——每次 GRPO 收敛后，从策略自身的 rollout 中挖掘同一问题的\"高效正确轨迹\"作为参考、\"低效/错误轨迹\"作为学生输入，通过非对称提示让同一模型分别扮演学生（仅见问题）和教师（额外见参考轨迹），并以带逐点裁剪的 token 级前向 KL 散度对齐两者分布，从而将优质轨迹中的逐步搜索模式蒸馏到策略的推理时分布中，实现纯粹依靠自身 rollout 的闭环自我进化。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Self-Play",
      "Process Reward",
      "Agent"
    ],
    "id": 188
  },
  {
    "date": "2026.05",
    "name": "LLM-Wiki",
    "url": "https://arxiv.org/abs/2605.25480v2",
    "title": "Retrieval as Reasoning",
    "description": "Retrieval as Reasoning: Self-Evolving Agent-Native Retrieval via LLM-Wiki 该论文提出LLM-Wiki，动机在于当前 RAG 系统将知识扁平化为文本块，导致检索沦为一次性相似度匹配，无法满足智能体迭代推理的需求；它解决了传统检索缺乏结构化导航、无法动态调整检索计划、以及知识库缺乏自我纠错能力的问题，通过将文档编译为带双向链接的 Wiki 页面、暴露搜索/阅读/链接追踪等组合式工具接口、并引入 Error Book 实现持续的结构与语义自纠错，从而将\"检索\"转变为智能体可规划、可遍历、可验证的推理过程，在多跳 QA 基准上取得 SOTA 且优势随推理深度递增。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Self-Play",
      "Agent",
      "RAG",
      "Multi-hop QA",
      "Benchmark"
    ],
    "id": 189
  },
  {
    "date": "2026.05",
    "name": "RAG-Match",
    "url": "https://arxiv.org/abs/2605.25486v1",
    "title": "RAG-Match",
    "description": "RAG-Match: Retrieval-Augmented Knowledge Injection and Hierarchical Reasoning for Calibrated Semantic Relevance 动机在于解决知识密集型搜索中语义相关性判断的困难——现有模型仅靠标签监督或浅层语义匹配，无法处理需要背景知识、隐式意图推理和细粒度区分的复杂查询；为此，该工作提出了一个三阶段框架：首先通过检索增强预训练让模型学习从查询生成知识合成的文档，将外部知识内化为参数化的语义先验；然后引入层次化推理对齐，将相关性判断分解为\"查询 grounding\"和\"多维度文档评估\"两阶段，以结构化思维链替代直接分类；最后通过差异引导偏好优化，利用少量人工标注对困难边界案例进行决策校准，减少模型的高估偏差。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RAG",
      "Benchmark"
    ],
    "id": 190
  },
  {
    "date": "2026.05",
    "name": "VeriTrace",
    "url": "https://arxiv.org/abs/2605.26081v1",
    "title": "VeriTrace",
    "description": "VeriTrace: Evolving Mental Models for Deep Research Agents 该论文的动机在于：深度研究智能体面对海量、相互关联且充满不确定性的信息时，现有系统将中间表征的演化完全交给大模型的隐性推理，导致中间层易被混合质量的信息污染，错误沿依赖关系传播，最终使得模型规模沦为对缺失调控机制的替代；为此，论文提出了VeriTrace框架，通过基于认知图的三个显式反馈回路——解释性更新（对新发现进行分类而非被动吸收）、偏差反馈（将搜索结果与预期对比并选择针对性搜索策略）、模式修正（当框架与现实脱节时重组认知结构同时保留证据）——来持续对齐智能体的心智模型与现实，在相同骨干模型下显著提升了深度研究的洞察力和整体表现。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research"
    ],
    "id": 191
  },
  {
    "date": "2026.05",
    "name": "LOGICALRAG",
    "url": "https://arxiv.org/abs/2605.27123v1",
    "title": "Rethinking Agentic RAG",
    "description": "Rethinking Agentic RAG: Toward LLM-Driven Logical Retrieval Beyond Embeddings 该文认为当前 Agentic RAG 过度追求复杂的检索后端（密集/混合/图检索），却忽视了 LLM 本身已具备精确表达检索意图的能力，且复杂后端导致多轮查询结果冗余重叠、LLM 难以修复失败检索，同时建设和维护成本高昂；为此提出 LOGICALRAG 框架，将检索后端简化为轻量级倒排索引，让 LLM 通过布尔逻辑表达式（AND/OR/NOT）和可调节匹配粒度直接驱动检索过程，使查询意图被忠实执行，实验表明该方法在准确率上与强混合基线持平的同时，大幅降低了系统成本与延迟，并有效减少了证据缺失时的幻觉问题。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "RAG",
      "Benchmark"
    ],
    "id": 192
  },
  {
    "date": "2026.05",
    "name": "PL-Search",
    "url": "https://arxiv.org/abs/2605.28354v1",
    "title": "Plan Before Search",
    "description": "Plan Before Search: Search Agents Need Plan 现有将大语言模型训练为检索增强推理智能体的范式通常依赖从更强模型蒸馏获取SFT冷启动再辅以强化学习，但这一做法忽略了子技能间的依赖结构以及蒸馏并非获取能力的唯一途径；为此，作者提出Plan——一种在检索前就将问题分解为有序子问题的结构化智能体行为，使每一步搜索都能锚定到预设计的子问题上以避免被早期部分相关文档带偏，同时发现相同奖励信号在不同规模模型上会诱导出性质迥异的RL失败模式，进而提出一种自举范式：用小规模种子模型生成筛选后的轨迹来激活任意目标模型中的Plan能力，从而彻底摆脱对外部更强模型的蒸馏依赖，该流程在所有测试模型上均能成功激活Plan并在多跳QA基准上持续超越有竞争力的基线。",
    "codeLinks": [
      "https://github.com/qzp2018/PL-Search"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "SFT",
      "Agent",
      "RAG",
      "Search Agent",
      "Multi-hop QA",
      "Benchmark"
    ],
    "id": 193
  },
  {
    "date": "2026.05",
    "name": "LiveBrowseComp",
    "url": "https://arxiv.org/abs/2605.28721v1",
    "title": "LiveBrowseComp",
    "description": "LiveBrowseComp: Are Search Agents Searching, or Just Verifying What They Already Know? 该文动机在于质疑当前搜索智能体在静态基准上的高分是否源于真正的证据发现能力，还是仅利用内在知识进行验证；它揭示了\"内在知识依赖（IKD）\"问题——即智能体过度依赖参数化知识、将搜索当作确认工具而非发现机制，导致固定基准随模型知识扩展而失效；为此提出了 LiveBrowseComp 基准，通过选取90天内发布的冷门事实构建问题，迫使智能体必须依赖实时检索而非记忆猜测，从而有效区分\"已知\"与\"能发现\"的搜索能力。",
    "codeLinks": [],
    "datasetLinks": [
      "https://huggingface.co/datasets/Forival/LiveBrowseComp"
    ],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Benchmark"
    ],
    "id": 194
  },
  {
    "date": "2026.05",
    "name": "LongTraceRL",
    "url": "https://arxiv.org/abs/2605.31584v1",
    "title": "LongTraceRL",
    "description": "LongTraceRL: Learning Long-Context Reasoning from Search Agent Trajectories with Rubric Rewards 动机在于提升大语言模型在长上下文中的推理能力，解决现有方法面临的两大核心问题：训练数据中干扰项混淆度低、与现实场景脱节，以及结果奖励过于稀疏导致无法监督中间推理步骤甚至引发奖励作弊。为此，该方法提出了基于搜索代理轨迹的分层干扰项构建策略——利用代理阅读但未引用的文档作为高混淆度干扰项、搜索结果中未打开的文档作为低混淆度干扰项，显著提升了训练数据的挑战性；同时设计了基于黄金实体的评分标准奖励，仅对最终答案正确的响应进行细粒度实体级过程监督，从而有效区分正确响应的推理质量并防止奖励作弊。",
    "codeLinks": [
      "https://github.com/THU-KEG/LongTraceRL"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Process Reward",
      "Agent",
      "Search Agent"
    ],
    "id": 195
  },
  {
    "date": "2026.06",
    "name": "observation-masking",
    "url": "https://arxiv.org/abs/2606.00408v1",
    "title": "Masking Stale Observations Helps Search Agents -- Until It Doesn't",
    "description": "Masking Stale Observations Helps Search Agents -- Until It Doesn't: A Regime Map and Its Mechanism 这篇论文研究了长程搜索智能体中\"掩码过时观测\"这一轻量上下文管理手段的有效性边界，通过系统扫描4B至284B参数的模型与多种检索器，发现其收益呈非对称倒U型分布：在弱检索器下因证据不足而收益平缓，在中等能力模型配强检索器时因剥离噪声、腾出轮次空间而达到峰值（+11.7pts），但在强模型饱和时反而会驱逐关键信号导致性能崩溃（−1.1pts）；机制上，掩码实现了\"token换轮次\"的权衡，移除了模型注意力已衰减的中间噪声，但当模型具备隐式过滤能力后，提升检索器质量而非启发式剪枝才是突破上下文瓶颈的根本方向。",
    "codeLinks": [
      "https://github.com/i-DeepSearch/observation-masking"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Search Agent",
      "Deep Research"
    ],
    "id": 196
  },
  {
    "date": "2026.06",
    "name": "Critic-R",
    "url": "https://arxiv.org/abs/2606.00590v1",
    "title": "Critic-R",
    "description": "Critic-R: Improving Agentic Search using Instruction-tuned Retrievers with Natural Language Introspective Feedback 现有 Agentic Search 系统将检索器视为固定黑盒，导致检索失败成为性能瓶颈，且优化检索器通常需要昂贵的人工标注；Critic-R 通过引入一个独立 Critic 模型分析推理智能体的内省反馈，在推理时迭代评估并重写检索查询以修复失败（Critic-R-Zero），同时将成功与失败的检索轨迹作为自动监督信号微调检索器（Critic-Embed），两者结合后在无需人工标注和修改推理智能体的情况下显著提升了多跳问答的检索质量与答案准确率。",
    "codeLinks": [],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Agent",
      "Multi-hop QA"
    ],
    "id": 197
  },
  {
    "date": "2026.06",
    "name": "DR-Rubric",
    "url": "https://arxiv.org/abs/2606.01091v1",
    "title": "Deep Research as Rubric for Reinforcement Learning 这篇论文提出 **DR-Rubric** 框架，将评分标准构建重新定义为\"深度研究\"问题：通过迭代",
    "description": "Deep Research as Rubric for Reinforcement Learning 这篇论文提出 **DR-Rubric** 框架，将评分标准构建重新定义为\"深度研究\"问题：通过迭代多轮 agentic 搜索主动收集任务特定的事实证据、结构约束和失败模式，再将其蒸馏为原子化、可独立验证的约束条件，为 GRPO 强化学习提供细粒度奖励信号；同时展示了模型自举生成评分标准的能力，初始自举驱动推理能力专业化，后续迭代逐步修复任务平衡性，最终仅用 1K–3K 训练样本就在 6 个智能体与专家推理基准上超越所有同规模基线。",
    "codeLinks": [
      "https://github.com/meiotoufa/DR-Rubric"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 198
  },
  {
    "date": "2026.06",
    "name": "DRIFT",
    "url": "https://arxiv.org/abs/2606.02060v1",
    "title": "Where Do Deep-Research Agents Go Wrong? Span-Level Error Localization in Agent Trajectories 该研究针对深度研",
    "description": "Where Do Deep-Research Agents Go Wrong? Span-Level Error Localization in Agent Trajectories 该研究针对深度研究智能体（deep-research agents）的评估仅关注最终答案、无法诊断轨迹中何处出错的问题，提出了**DRIFT**——一个以\"声明（claim）\"为中心的多智能体审计框架，通过构建声明账本追踪智能体在轨迹中形成的各类承诺、检验其是否被证据支持或存在矛盾、并回溯依赖关系来定位最早产生危害的错误片段；为此作者还构建了包含1,000个专家验证实例的**TELBench**基准，实验表明DRIFT在片段级错误定位和首次错误准确率上比直接全上下文提示提升最多30个百分点，为智能体可靠性提供了过程级的诊断视角。",
    "codeLinks": [
      "https://github.com/NJU-LINK/DRIFT"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Multi-Agent",
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 199
  },
  {
    "date": "2026.06",
    "name": "TVIR",
    "url": "https://arxiv.org/pdf/2606.02320v1",
    "title": "TVIR",
    "description": "TVIR: Building Deep Research Agents Towards Text–Visual Interleaved Report Generation 现有深度研究智能体虽擅长多步检索与长文本报告生成，但现有基准和系统仍以文本为中心，忽视了真实世界专业报告中视觉证据作为核心推理组件的关键作用，导致视觉元素常被当作装饰性补充而非与文本语义对齐的证据；为此，该工作提出了TVIR框架，包含100个专家策划的多模态任务基准TVIR-BENCH、一个将视觉资产（检索图像与代码生成图表）深度融入规划与写作流程的层次化多智能体系统TVIR-AGENT，以及一套同时审计文本质量与视觉证据可靠性的双路径评估体系，从而推动深度研究从纯文本任务向多模态证据驱动报告生成演进。",
    "codeLinks": [
      "https://github.com/NJU-LINK/TVIR"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "Multi-Agent",
      "Agent",
      "Search Agent",
      "Deep Research",
      "Benchmark"
    ],
    "id": 200
  },
  {
    "date": "2026.06",
    "name": "Harness-1",
    "url": "https://arxiv.org/pdf/2606.02373v1",
    "title": "Harness-1",
    "description": "Harness-1: Reinforcement Learning for Search Agents with State-Externalizing Harnesses 动机在于传统搜索智能体将状态管理（如记忆已见文档、追踪未满足约束、记录验证状态）与语义搜索决策混为一谈，导致强化学习优化困难；它通过引入\"状态外部化\"原则，将候选池、精选集、证据图、验证记录等可恢复性簿记工作卸载到环境端维护，让 20B 规模的策略专注于搜索、筛选、验证和终止等语义决策，并配合自动播种、紧凑状态渲染和多样性激励等训练机制，在 8 个跨领域检索基准上实现了比开源对手高 11.4 分的平均召回率，且在未见过的迁移任务上提升更为显著。",
    "codeLinks": [
      "https://github.com/pat-jj/harness-1"
    ],
    "datasetLinks": [],
    "year": 2026,
    "tags": [
      "RL-based",
      "Agent",
      "Search Agent",
      "Benchmark",
      "Open-Source"
    ],
    "id": 201
  }
];
