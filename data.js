window.FEED_DATA = [
  {
    "id": "manus-work-reselect1031",
    "source": "张涛 · Manus 联合创始人",
    "avatar": "M",
    "avatarClass": "anthropic",
    "channel": "official",
    "evidence": "团队自述",
    "kind": "official",
    "topic": "团队与协作",
    "tags": [
      "内部工作方式",
      "踩坑复盘"
    ],
    "date": "2026-10-30",
    "time": "10 月 30 日",
    "title": "Manus 让 Agent 跑了一个周末，周一堆出 200 多个待拍板事项。",
    "summary": "张涛在团队复盘中提到，他们尝试让 Agent 自动收集内部反馈，为每个反馈启动任务。一个周末后，200 多个事项等着人作决定，人的注意力成了瓶颈。\n\n团队由此重新划分工作：修复有没有通过测试，可以交给系统检查；一个产品改动值不值得做，仍由人拍板。",
    "body": "现在，一条用户报错先由 Agent 排查并找到相关改动，再交给工程师判断是否处理。工程师自己的 Agent 负责修改，另一个 Agent 运行测试、验证结果，最终由有权限的人批准合并和发布。\n\n支撑这套流程的是内部工具 Mono：它为多个代码仓库提供统一入口，把历史决策、测试和发布方式一起交给 Agent。团队也在尝试让工程、产品和设计进入同一个会话，共享讨论背景，减少交接时重新解释的工作。",
    "links": [
      {
        "label": "原文",
        "url": "https://manus.im/blog/rebuilding-manus-with-manus"
      }
    ],
    "images": [
      {
        "src": "assets/2026-10-31/manus-team.webp",
        "alt": "Manus 原文示意工程师、产品经理与设计师在同一会话协作",
        "caption": "原文协作示意：工程、产品、设计在同一会话接力；图中的定价修改是演示案例。",
        "credit": "Manus",
        "sourceUrl": "https://manus.im/blog/rebuilding-manus-with-manus",
        "originalUrl": "https://files.manuscdn.com/assets/dashboard/materials/2026/10/30/555809c7e478f1452de193557b3e53d840e1dba6804d42452b258d0fa94ba160.webp"
      }
    ],
    "comments": [],
    "commentStatus": "",
    "detailLabel": "他们后来怎样分工",
    "highlights": {
      "summary": [
        "200 多个事项等着人作决定",
        "一个产品改动值不值得做，仍由人拍板"
      ],
      "body": [
        "共享讨论背景，减少交接时重新解释的工作"
      ]
    },
    "issueDate": "2026-10-31-reselected"
  },
  {
    "id": "sandman-training-reselect1031",
    "source": "Amazon · Sandman 团队",
    "avatar": "A",
    "avatarClass": "google",
    "channel": "official",
    "evidence": "团队技术报告",
    "kind": "official",
    "topic": "训练与推理",
    "tags": [
      "强化学习现场",
      "奖励与评测"
    ],
    "date": "2026-10-29",
    "time": "10 月 29 日",
    "title": "代码没修好，测试却过了：Amazon 怎样处理训练中的假奖励？",
    "summary": "Amazon 的 Sandman 团队遇到过这样的情况：Agent 加入一个测试配置文件，让测试通过了，却没有真正修复问题。网络和资源条件的变化，也会让同一补丁得到不同的判分。\n\n他们把生成代码和最终评分放进不同环境，并在训练前检查：参考修复应当通过，什么都不改应当失败。先确认判分可信，才能拿它作为训练奖励。",
    "body": "Agent 完成修改后，训练程序只提取补丁，放进独立环境运行测试，避免把执行过程中留下的文件和进程带进评分。报告中的处理还包括排除测试配置文件改动，以及在评分前检查运行条件。\n\n遇到基础设施故障时，系统先重试；仍拿不到有效结果就重新采样，而不是直接记作模型失败。团队在 10 月四组内部代码 Agent 训练中创建了约 310 万个沙箱，也记录了超时后环境没有清理、批量启动拥堵等问题。",
    "links": [
      {
        "label": "技术报告",
        "url": "https://arxiv.org/html/2610.39711v1"
      }
    ],
    "images": [],
    "comments": [],
    "commentStatus": "",
    "detailLabel": "判分流程怎样改",
    "highlights": {
      "summary": [
        "让测试通过了，却没有真正修复问题",
        "把生成代码和最终评分放进不同环境"
      ],
      "body": [
        "而不是直接记作模型失败"
      ]
    },
    "issueDate": "2026-10-31-reselected"
  },
  {
    "id": "tw93-workflow-reselect1031",
    "source": "Tw93 · 小红书 / X",
    "avatar": "Tw",
    "avatarClass": "xhs",
    "channel": "xiaohongshu",
    "evidence": "开发者经验",
    "kind": "opinion",
    "topic": "工具与工作方式",
    "tags": [
      "AI 编程",
      "评论里的分歧"
    ],
    "date": "2026-10-30",
    "time": "小红书 10 月 30 日 · X 英文帖 10 月 29 日",
    "title": "Tw93：换一个新模型，先让它重做以前出过错的任务。",
    "summary": "Tw93 建议把线上 Bug 和用户反馈变成测试案例，每次发布前跑一遍，换模型时也重跑。这样就能具体看到：哪些旧问题修好了，哪些又出现了。\n\n他还把写代码与审查分给不同 Agent；多个 Agent 同时工作时，各用独立目录，合并后再统一验证。",
    "body": "在需求阶段，他倾向于先讲背景、目标和期望结果，把实现拆成小步。排错时，如果连续两次没有修好，就增加日志看真实运行情况；多次尝试仍无效，再整理问题与已试过的办法，重开上下文。",
    "links": [
      {
        "label": "X 原帖及讨论",
        "url": "https://x.com/HiTw93/status/2115805352520282623"
      },
      {
        "label": "小红书原帖",
        "url": "https://www.xiaohongshu.com/search_result/6ae3de1c000000001200f7f1?xsec_token=ABM9qkWkpjP4Tltp_4OD8vFtWKuOXcDPbJ-ndUckweXN8=&xsec_source="
      }
    ],
    "images": [],
    "comments": [
      {
        "author": "geektao0319",
        "role": "原帖回复者",
        "date": "2026-10-30（北京）",
        "text": "这位开发者说，两个 AI 共用一个目录时，差点把另一个尚未检查的改动一起上线。他还遇到过 Agent 重复添加网站已有的统计功能。",
        "url": "https://x.com/geektao0319/status/2116033254943801615",
        "linkLabel": "查看这条回复",
        "evidence": "个人经验",
        "mode": "摘编",
        "context": "回应独立工作目录的建议。",
        "highlights": [
          "差点把另一个尚未检查的改动一起上线"
        ]
      },
      {
        "author": "_gvieira",
        "role": "原帖回复者",
        "date": "2026-10-30（北京）",
        "text": "他更愿意自己确定实现的大体结构，再让 Agent 写代码。只给最终目标，会让他花时间反推模型为什么做出那些选择。",
        "url": "https://x.com/_gvieira/status/2115922377401836020",
        "linkLabel": "查看这条回复",
        "evidence": "个人经验",
        "mode": "摘编",
        "context": "回应“先描述目标，少规定实现”的建议。",
        "highlights": [
          "自己确定实现的大体结构"
        ]
      }
    ],
    "commentStatus": "摘编自 X 原帖回复。",
    "detailLabel": "需求和排错时，他怎么做",
    "highlights": {
      "summary": [
        "把线上 Bug 和用户反馈变成测试案例",
        "各用独立目录，合并后再统一验证"
      ],
      "body": [
        "增加日志看真实运行情况"
      ]
    },
    "issueDate": "2026-10-31-reselected"
  },
  {
    "id": "meta-router-reselect1031",
    "source": "Meta Engineering",
    "avatar": "M",
    "avatarClass": "google",
    "channel": "official",
    "evidence": "团队工程复盘",
    "kind": "official",
    "topic": "工具与工作方式",
    "tags": [
      "上下文管理",
      "失败复盘"
    ],
    "date": "2026-10-19",
    "time": "10 月 19 日 · 实践回看",
    "title": "Meta 的 Agent 把不同系统的规则混用了，团队给它重新分了工。",
    "summary": "Meta 最初让一个通用 Agent 掌握整条数据接入流程。上线后，它会把一个系统的字段命名规则用到另一个系统，或套用不合适的代码生成方式。\n\n团队后来让总调度只安排步骤，把具体判断交给 14 个专业 Agent，每个只加载自己的领域资料。团队报告，配置准备从先前系统约一天缩短到一小时以内。",
    "body": "总调度负责收集字段、检查目标是否已存在、安排顺序和处理结果；专业 Agent 负责具体领域的操作。不同工作流可以复用同一批 Agent，新增任务时，先尝试重新组合现有步骤。\n\nMeta 报告，约三分之二的改动无需人工大幅修改。这篇复盘中，导致错误的一个具体问题是上下文混杂：规则都在，但模型没有正确区分各自适用的系统。",
    "links": [
      {
        "label": "原文",
        "url": "https://engineering.fb.com/2026/10/19/ml-applications/thin-orchestrator-ai-agent-architecture/"
      }
    ],
    "images": [
      {
        "src": "assets/2026-10-31/meta-workflow.jpg",
        "alt": "Meta 原文的轻量调度与领域工作流架构图",
        "caption": "调度层安排步骤，领域 Agent 在各自的上下文里完成具体工作。",
        "credit": "Meta Engineering",
        "sourceUrl": "https://engineering.fb.com/2026/10/19/ml-applications/thin-orchestrator-ai-agent-architecture/",
        "originalUrl": "https://engineering.fb.com/wp-content/uploads/2026/10/Meta-Thin-Orchestrator-workflow.jpg",
        "placement": "details"
      }
    ],
    "comments": [],
    "commentStatus": "",
    "detailLabel": "新的分工和流程图",
    "highlights": {
      "summary": [
        "把一个系统的字段命名规则用到另一个系统",
        "每个只加载自己的领域资料"
      ],
      "body": [
        "不同工作流可以复用同一批 Agent"
      ]
    },
    "issueDate": "2026-10-31-reselected"
  },
  {
    "id": "rescale-triage-reselect1031",
    "source": "Rescale / AWS 工程团队",
    "avatar": "R",
    "avatarClass": "mistral",
    "channel": "official",
    "evidence": "联合工程复盘",
    "kind": "official",
    "topic": "团队与协作",
    "tags": [
      "上线取舍",
      "实际收益"
    ],
    "date": "2026-10-22",
    "time": "10 月 22 日 · 实践回看",
    "title": "值班工程师每天都在翻报错日志，Rescale 把第一轮排查交给 AI。",
    "summary": "夜间测试一失败，Rescale 工程师就要翻日志、找历史记录，再确定问题该交给谁。团队让 Agent 先做分类、收集证据，输出带文件位置和修复建议的报告，工程师接手后再判断。\n\n上线后，团队报告，分类与人工判断的一致率从 44% 升至 68%；分析测试故障造成的发布阻塞时间下降了 20%。",
    "body": "五天联合开发中，团队先一起回答需求问题、划定首期范围，再让 AI 实现。为了直接接入已有流程，他们中途放弃新增运行平台，改用现有集群。\n\n首期先做好分类和建议，自动生成修复 PR 留到后续。这让团队可以先观察第一轮排查能省多少时间，再决定继续自动化哪些步骤。",
    "links": [
      {
        "label": "原文",
        "url": "https://aws.amazon.com/blogs/machine-learning/how-rescale-built-an-ai-triage-agent-with-strands-agents-and-ai-dlc/"
      }
    ],
    "images": [],
    "comments": [],
    "commentStatus": "",
    "detailLabel": "首期做了什么，推迟了什么",
    "highlights": {
      "summary": [
        "先做分类、收集证据",
        "发布阻塞时间下降了 20%"
      ],
      "body": [
        "自动生成修复 PR 留到后续"
      ]
    },
    "issueDate": "2026-10-31-reselected"
  },
  {
    "id": "github-memory-reselect1031",
    "source": "GitHub",
    "avatar": "GH",
    "avatarClass": "anthropic",
    "channel": "official",
    "evidence": "官方功能发布",
    "kind": "official",
    "topic": "工具与工作方式",
    "tags": [
      "团队知识",
      "审查习惯"
    ],
    "date": "2026-10-28",
    "time": "10 月 28 日",
    "title": "反复出现的代码审查意见，GitHub 想让 Agent 下次直接记住。",
    "summary": "GitHub 的 Dreaming 会回看过去的工作，把反复被接受的代码审查意见整理成后续指导，也会维护个人与仓库记忆。涉及仓库中的技能或指令文件时，它会提交修改提议，交给团队审阅。\n\n这项功能于 10 月 28 日以公开预览形式发布，需要主动启用。",
    "body": "同一组发布还包括跨仓库搜索。Agent 可以查找相关服务、共享库和历史代码，减少每次开始任务前由人收集背景的工作。\n\n例如修复一个跨服务的问题时，可以先查清几处实现和调用关系，再确定哪些地方需要一起修改。",
    "links": [
      {
        "label": "原文",
        "url": "https://github.blog/changelog/2026-10-28-github-intelligence-puts-your-code-context-and-history-to-work/"
      }
    ],
    "images": [],
    "comments": [],
    "commentStatus": "",
    "detailLabel": "还有哪些上下文能力",
    "highlights": {
      "summary": [
        "把反复被接受的代码审查意见整理成后续指导",
        "需要主动启用"
      ],
      "body": [
        "跨仓库搜索"
      ]
    },
    "issueDate": "2026-10-31-reselected"
  },
  {
    "id": "mistral-large4-1031",
    "source": "Mistral AI",
    "avatar": "M",
    "avatarClass": "mistral",
    "channel": "official",
    "evidence": "官方披露",
    "kind": "official",
    "topic": "产品与模型",
    "tags": [
      "开放权重",
      "推理成本"
    ],
    "date": "2026-10-29",
    "time": "10 月 29 日",
    "title": "Mistral 开放升级版 Large 4 权重，同时提供三档推理模式。",
    "summary": "Mistral 发布了进一步训练的 Large 4 权重，支持低、中、高三档推理模式。公司报告，Terminal-Bench 4.0 得分从预览版的 28% 提高到 41%，输出 token 减少 30%。\n\n产品团队可以按任务选择投入多少推理计算：日常请求控制开销，复杂任务使用更高档位。",
    "body": "",
    "links": [
      {
        "label": "原文",
        "url": "https://mistral.ai/news/mistral-large-4-oss/"
      }
    ],
    "images": [],
    "comments": [],
    "commentStatus": "本条未采集评论",
    "detailLabel": "",
    "highlights": {
      "summary": [
        "低、中、高三档推理模式",
        "输出 token 减少 30%"
      ],
      "body": []
    },
    "issueDate": "2026-10-31"
  },
  {
    "id": "seed-ye-1031",
    "source": "叶德珩 · 本人主页",
    "avatar": "叶",
    "avatarClass": "maimai",
    "channel": "official",
    "evidence": "本人公开信息",
    "kind": "official",
    "topic": "团队与招聘",
    "tags": [
      "Seed",
      "强化学习"
    ],
    "date": "2026-10-30",
    "time": "10 月 31 日查看本人主页",
    "title": "叶德珩加入字节 Seed，从游戏强化学习转向基础模型。",
    "summary": "叶德珩的个人主页已列出字节 Seed 研究员身份：2017—2026 年在腾讯，2026 年起在 Seed 从事基础模型研究。此前项目包括绝悟系列，研究经历涵盖强化学习与智能体。",
    "body": "",
    "links": [
      {
        "label": "本人主页",
        "url": "https://yedeheng.github.io/"
      }
    ],
    "images": [],
    "comments": [],
    "commentStatus": "本条未采集评论",
    "detailLabel": "",
    "highlights": {
      "summary": [
        "2026 年起在 Seed 从事基础模型研究"
      ],
      "body": []
    },
    "issueDate": "2026-10-31"
  },
  {
    "id": "anthropic-safety-1031",
    "source": "Anthropic",
    "avatar": "A",
    "avatarClass": "anthropic",
    "channel": "official",
    "evidence": "官方技术经验",
    "kind": "official",
    "topic": "训练与推理",
    "tags": [
      "安全监测",
      "推理成本"
    ],
    "date": "2026-10-30",
    "time": "10 月 30 日新介绍 · 技术文 10 月 16 日",
    "title": "Claude 每次回答后做一次风险自评，额外计算开销估计低于 2%。",
    "summary": "Anthropic 介绍，Claude 回答后会复用已有对话缓存，生成一份简短安全评估，再交给离线流程复核。这套机制自 6 月开始使用，公司估计额外推理计算开销低于 2%。\n\n把初筛安排在回答之后，后续复核就可以集中处理可疑对话，无需把所有检查都放进用户等待回答的过程。",
    "body": "",
    "links": [
      {
        "label": "技术文",
        "url": "https://safeguards.anthropic.com/2026/self-assessment/"
      },
      {
        "label": "官方帖",
        "url": "https://x.com/AnthropicAI/status/2115871889549865429"
      }
    ],
    "images": [],
    "comments": [],
    "commentStatus": "本条未采集评论",
    "detailLabel": "",
    "highlights": {
      "summary": [
        "复用已有对话缓存",
        "额外推理计算开销低于 2%"
      ],
      "body": []
    },
    "issueDate": "2026-10-31"
  },
  {
    "id": "xhs-interview-1031",
    "source": "fangliqian · 小红书",
    "avatar": "小红书",
    "avatarClass": "xhs",
    "channel": "xiaohongshu",
    "evidence": "个人面试经历",
    "kind": "opinion",
    "topic": "团队与招聘",
    "tags": [
      "后训练",
      "失败诊断"
    ],
    "date": "2026-10-30",
    "time": "10 月 30 日 · 个人自述",
    "title": "后训练岗位面试追问：为什么训练完，性能反而下降了？",
    "summary": "fangliqian 在华为后训练岗位面试复盘中写到，问题涉及微调和强化学习的目标函数、数据构造、评测指标，以及偏好训练后性能下降的原因和改进办法。还要求用基础 math 库实现因果注意力。\n\n评论里，作者补充：实际面试会继续问这些基础知识在实习项目里怎么用。",
    "body": "",
    "links": [
      {
        "label": "原帖",
        "url": "https://www.xiaohongshu.com/search_result/6ae40d1a0000000026002909?xsec_token=ABsGEOUzPAM_Ox-2GEdZLzQDu6KfAkf9wRjaK7jSAKjA4=&xsec_source="
      }
    ],
    "images": [],
    "comments": [],
    "commentStatus": "摘编自原帖评论区。",
    "collectionNote": "读取到 12 条评论及回复，选取 1 条作者补充；链接进入原帖，未获取评论直达链接。",
    "detailLabel": "",
    "highlights": {
      "summary": [
        "偏好训练后性能下降的原因和改进办法",
        "在实习项目里怎么用"
      ],
      "body": []
    },
    "issueDate": "2026-10-31"
  },
  {
    "id": "google-orbit-1031",
    "source": "Google Research",
    "avatar": "G",
    "avatarClass": "google",
    "channel": "official",
    "evidence": "官方工程进展",
    "kind": "official",
    "topic": "产品与模型",
    "tags": [
      "算力设施",
      "原型验证"
    ],
    "date": "2026-10-30",
    "time": "10 月 30 日",
    "title": "Google 的太空 TPU 原型运行了 Gemma 4，并传回响应。",
    "summary": "Google 介绍，Project Suncatcher 原型卫星已在轨运行 Gemma 4。接下来将测试 TPU 在热应力和辐射环境下的可靠性，计划之一是 2027 年进行双星互联测试。",
    "body": "",
    "links": [
      {
        "label": "原文",
        "url": "https://blog.google/innovation-and-ai/models-and-research/google-research/project-suncatcher-satellite-response/"
      }
    ],
    "images": [],
    "comments": [],
    "commentStatus": "本条未采集评论",
    "detailLabel": "",
    "highlights": {
      "summary": [
        "已在轨运行 Gemma 4",
        "热应力和辐射环境下的可靠性"
      ],
      "body": []
    },
    "issueDate": "2026-10-31"
  },
  {
    "id": "reddit-batching-1031",
    "source": "Mchanger · Reddit",
    "avatar": "r/",
    "avatarClass": "reddit",
    "channel": "reddit",
    "evidence": "个人部署测试",
    "kind": "opinion",
    "topic": "训练与推理",
    "tags": [
      "并发",
      "吞吐与延迟"
    ],
    "date": "2026-10-31",
    "time": "10 月 31 日读取",
    "title": "一张 RTX 3090 同时服务四路请求，总吞吐提高，每路速度却下降了。",
    "summary": "LocalLLaMA 用户 Mchanger 分享个人部署测试：单路生成约 30 token/秒；四路并发合计约 64，每路约 16。显卡每秒产出更多，但单个使用者拿到回答的速度变慢。\n\n评论者还注意到，从 12 路增至 16 路并发，总吞吐只从约 110 增到 111 token/秒，继续加并发的收益已经很小。",
    "body": "",
    "links": [
      {
        "label": "原帖",
        "url": "https://www.reddit.com/r/LocalLLaMA/comments/1xjx63n/just_rediscovered_batching_and_swarming_while/"
      }
    ],
    "images": [],
    "comments": [],
    "commentStatus": "摘编自原帖评论区。",
    "collectionNote": "读取帖子及 4 条评论/回复，选取 1 条有数据依据的补充；工具未返回评论直达链接。",
    "detailLabel": "",
    "highlights": {
      "summary": [
        "显卡每秒产出更多，但单个使用者拿到回答的速度变慢",
        "总吞吐只从约 110 增到 111 token/秒"
      ],
      "body": []
    },
    "issueDate": "2026-10-31"
  },
  {
    "id": "lfm3",
    "source": "Liquid AI",
    "avatar": "∿",
    "avatarClass": "liquid",
    "channel": "official",
    "evidence": "官方披露",
    "kind": "official",
    "topic": "训练与推理",
    "tags": [
      "小模型",
      "多教师蒸馏"
    ],
    "date": "2026-10-27",
    "time": "10 月 27 日",
    "title": "Liquid AI 用六位专项教师，把不同能力教给同一个小模型。",
    "summary": "LFM3-1.7B 的后训练流程里，六位教师分别覆盖代码、数学、工具、长上下文、智能体和企业工作流。团队通过多领域在策略蒸馏，把这些专长整合进同一个学生模型，再放进真实智能体运行框架中做强化学习。",
    "originalTitle": "Liquid AI公开小模型的“多位老师教一个学生”路线",
    "body": "模型卡列出四个阶段：监督微调、多领域强化学习、多教师在策略蒸馏，最后是在实际运行框架中的强化学习。\n\n这里的“在策略”是让学生自己生成回答或行动轨迹，再接受教师指导。它提供了一条整合专项能力的路线，也可以与直接合并模型参数的方法作比较。",
    "links": [
      {
        "label": "原文",
        "url": "https://huggingface.co/LiquidAI/LFM3-1.7B"
      },
      {
        "label": "发布",
        "url": "https://www.liquid.ai/blog/lfm3"
      }
    ],
    "images": [],
    "comments": [],
    "commentStatus": "首期未采集评论",
    "detailLabel": "四阶段训练怎样衔接",
    "highlights": {
      "summary": [
        "把这些专长整合进同一个学生模型"
      ],
      "body": [
        "让学生自己生成回答或行动轨迹，再接受教师指导"
      ]
    },
    "issueDate": "2026-10-29"
  },
  {
    "id": "anthropic",
    "source": "Anthropic · Latent Space",
    "avatar": "A",
    "avatarClass": "anthropic",
    "channel": "interview",
    "evidence": "具名访谈",
    "kind": "interview",
    "topic": "训练与推理",
    "tags": [
      "模型评测",
      "上线经验"
    ],
    "date": "2026-10-27",
    "time": "10 月 27 日",
    "title": "模型上线前，Anthropic 让客户拿自己的工具和工作流来测。",
    "summary": "Anthropic 平台负责人 Katelyn Lesse、Angela Jiang 在访谈中介绍，提前试用客户会在自己的环境里评测模型，反馈官方产品没有覆盖的问题。\n\n她们还谈到另一项上线设计：把会话记录、智能体控制程序和执行代码的沙箱分开。即使执行环境出故障，任务进度仍可以保留下来，减少从头再来的返工。",
    "originalTitle": "Anthropic负责人谈上线幕后：让客户在自己的环境里测",
    "body": "",
    "links": [
      {
        "label": "访谈",
        "url": "https://latent.space/p/opus55/"
      },
      {
        "label": "背景技术文（4月8日）",
        "url": "https://www.anthropic.com/research/managed-agents"
      }
    ],
    "images": [],
    "comments": [],
    "commentStatus": "首期未采集评论",
    "detailLabel": "",
    "highlights": {
      "summary": [
        "在自己的环境里评测模型",
        "即使执行环境出故障，任务进度仍可以保留下来"
      ],
      "body": []
    },
    "issueDate": "2026-10-29"
  },
  {
    "id": "carbon",
    "source": "Google",
    "avatar": "G",
    "avatarClass": "google",
    "channel": "official",
    "evidence": "官方发布",
    "kind": "official",
    "topic": "产品与模型",
    "tags": [
      "Gemini",
      "有限开放"
    ],
    "date": "2026-10-28",
    "time": "10 月 28 日",
    "title": "Gemini 4 Carbon 发布，先向部分安全防御人员开放。",
    "summary": "Google 把 Carbon 重点放在长时间、多步骤工程任务和网络安全防御上。10 月 28 日发布时，先向部分安全防御人员开放，再通过 Fairwind 计划逐步扩大到可信合作伙伴。普通开发者、企业和消费者的全面开放仍在后续计划中。",
    "originalTitle": "Gemini 4 Carbon发布，但目前是有限开放",
    "body": "",
    "links": [
      {
        "label": "原文",
        "url": "https://blog.google/innovation-and-ai/models-and-research/gemini-models/introducing-gemini-4-carbon/"
      }
    ],
    "images": [],
    "comments": [],
    "commentStatus": "首期未采集评论",
    "detailLabel": "",
    "highlights": {
      "summary": [
        "先向部分安全防御人员开放"
      ],
      "body": []
    },
    "issueDate": "2026-10-29"
  },
  {
    "id": "genie",
    "source": "Google DeepMind",
    "avatar": "✳",
    "avatarClass": "deepmind",
    "channel": "official",
    "evidence": "官方发布",
    "kind": "official",
    "topic": "产品与模型",
    "tags": [
      "世界模型",
      "研究预览"
    ],
    "date": "2026-10-27",
    "time": "10 月 27 日",
    "title": "Genie 4 把场景、环境音和对话放进同一个交互世界。",
    "summary": "DeepMind 展示的 Genie 4 支持实时交互：用户用文字改变场景，系统同时生成环境音和交互对话。10 月 27 日发布时，它面向可信测试者提供研究预览，消费者与开发者开放还在后续安排中。",
    "originalTitle": "Genie 4把可交互场景、声音和对话放进同一模拟环境",
    "body": "",
    "links": [
      {
        "label": "原文",
        "url": "https://deepmind.google/blog/genie-4-a-new-generation-of-world-simulation/"
      }
    ],
    "images": [],
    "comments": [],
    "commentStatus": "首期未采集评论",
    "detailLabel": "",
    "highlights": {
      "summary": [
        "同时生成环境音和交互对话",
        "面向可信测试者提供研究预览"
      ],
      "body": []
    },
    "issueDate": "2026-10-29"
  },
  {
    "id": "xhs",
    "source": "AgentAlpha · 小红书",
    "avatar": "小红书",
    "avatarClass": "xhs",
    "channel": "xiaohongshu",
    "evidence": "社区观点",
    "kind": "opinion",
    "topic": "训练与推理",
    "tags": [
      "后训练",
      "评测讨论"
    ],
    "date": "2026-10-28",
    "time": "10 月 28 日",
    "title": "后训练会不会只学会刷榜？一篇小红书笔记提出评测疑问。",
    "summary": "AgentAlpha 在《大模型后训练时代：五年高考三年模拟》中讨论公开评测过拟合，主张把评测放进能操作、能获得反馈的任务环境。\n\n这篇讨论关心的是：模型在熟悉的题目上得分提高之后，进入真实任务还能不能完成工作。",
    "originalTitle": "小红书讨论：只盯公开榜单，可能漏掉实际任务",
    "body": "",
    "links": [
      {
        "label": "原帖",
        "url": "https://www.xiaohongshu.com/search_result/6ae20ceb00000000240075c2?xsec_token=ABxS-C1hYgStH4VrRzSsyI-Nj6igZRNn5WdO-Q3Gana1E=&xsec_source="
      }
    ],
    "images": [],
    "comments": [],
    "commentStatus": "首期未采集评论",
    "detailLabel": "",
    "highlights": {
      "summary": [
        "能操作、能获得反馈的任务环境"
      ],
      "body": []
    },
    "issueDate": "2026-10-29"
  },
  {
    "id": "maimai",
    "source": "胡豆豆 · 脉脉",
    "avatar": "脉",
    "avatarClass": "maimai",
    "channel": "maimai",
    "evidence": "待核实线索",
    "kind": "lead",
    "topic": "团队与招聘",
    "tags": [
      "九坤",
      "产品岗位"
    ],
    "date": "2026-10-29T07:36:00",
    "time": "10 月 29 日 · 07:36",
    "title": "九坤相关招聘转发，列出了聊天产品和模型调度岗位。",
    "summary": "胡豆豆在脉脉转发一组“九坤岗位”：工作地点在北京，包括网页前端、客户端、大模型产品经理，以及模型接入与调度平台研发。帖子提到面向消费者的聊天产品。\n\n这是一条个人招聘转发，可以用来观察岗位需求；产品细节还要等待后续公开信息。",
    "originalTitle": "脉脉出现九坤聊天产品相关招聘转发",
    "body": "",
    "links": [
      {
        "label": "原帖",
        "url": "https://maimai.cn/community/feed-detail/1933070113?fid=1933070113&efid=JWxqKDxBaESCUtV93vRnnQ"
      }
    ],
    "images": [],
    "comments": [],
    "commentStatus": "首期未采集评论",
    "detailLabel": "",
    "highlights": {
      "summary": [
        "模型接入与调度平台研发",
        "个人招聘转发"
      ],
      "body": []
    },
    "issueDate": "2026-10-29"
  }
];
window.FEED_ISSUES = [
  {
    "id": "2026-10-31-reselected",
    "label": "10 月 31 日 · 兴趣重选",
    "date": "2026-10-31",
    "edition": 3,
    "title": "AI 进了团队，工作到底怎么变？",
    "intro": "这次选了 6 个更贴近工作现场的故事：谁来拍板、训练奖励怎样判、经验如何留给下一次。既看最近的变化，也回看两篇 10 月下旬的工程复盘。",
    "coverage": "北京时间 10 月 31 日兴趣重选；来源发表于 10 月 19—30 日。已读小红书搜索与 Tw93 笔记正文、X 原帖及 34 条回复、Manus/Meta/GitHub 官方文章、Rescale 与 AWS 联合复盘、Amazon Sandman 技术报告。Reddit 搜索后端本次返回解析错误，网页检索线索未入选；脉脉未采集新帖。图源为原文，评论附直达链接。",
    "count": 6
  },
  {
    "date": "2026-10-31",
    "edition": 2,
    "title": "模型之外，工程现场还有什么？",
    "intro": "看看模型的推理开销、人才流动与部署细节。这次把原文配图和有用的评论放在一起：不仅看发布了什么，也看实践中遇到了什么。",
    "coverage": "北京时间 10 月 29 日上期发送后至 31 日上午；10 月 31 日网页更新时补充原文图片和评论。已读小红书笔记正文及 12 条评论/回复、Anthropic 官方 X 原帖、厂商文章、研究者主页、Reddit 最新 5 帖，以及入选帖的 4 条评论/回复。脉脉本期未取得可核验新帖。部分评论只有原帖入口，没有评论直达链接。",
    "id": "2026-10-31",
    "count": 6
  },
  {
    "date": "2026-10-29",
    "edition": 1,
    "title": "从“模型更强”到“真的能用”。",
    "intro": "多领域能力怎样装进一个小模型？上线后，怎样评测、怎样从失败中恢复？沿着这两条线，看看产品背后的工作。",
    "coverage": "北京时间 10 月 27 日至 29 日上午。已读取小红书两篇笔记正文、脉脉“大模型”按时间排序结果及入选帖全文，核对官方模型卡、发布文章和原始访谈。脉脉职言与评论未完整覆盖。",
    "id": "2026-10-29",
    "count": 6
  }
];
window.FEED_META = {
  "updatedAt": "2026-10-31T15:41:40+08:00",
  "schedule": "每天北京时间 09:00 开始整理",
  "latestDate": "2026-10-31",
  "latestId": "2026-10-31-reselected"
};
