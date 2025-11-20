# LLM Agents, AI Workflow, & Agentic MLLM

[TOC]



## Res
### Related Topics
↗ [AIGC WorkFlow & Agents](../../../../❌%20AI4X,%20AGI%20(Artificial%20General%20Intelligence)%20&%20AIGC/🌀%20AIGC%20WorkFlow%20&%20Agents/AIGC%20WorkFlow%20&%20Agents.md)
↗ [LLM Utilization & Prompt Engineering](../../LLM%20Training,%20Utilization,%20and%20Evaluation/LLM%20Utilization%20&%20Prompt%20Engineering/LLM%20Utilization%20&%20Prompt%20Engineering.md)
↗ [AI Embodiment & World Model](../../../../❌%20AI4X,%20AGI%20(Artificial%20General%20Intelligence)%20&%20AIGC/🤔%20AI%20Embodiment%20&%20World%20Model/AI%20Embodiment%20&%20World%20Model.md)
↗ [Agentic AI Workflow Dev](../../../../../../Software%20Engineering/🤖%20AI(LLM)%20x%20SE/Agentic%20AI%20Workflow%20Dev/Agentic%20AI%20Workflow%20Dev.md)
- LLM App Dev Framework
	- ↗ [LangChain & LangGraph](../../../../../../Software%20Engineering/🤖%20AI(LLM)%20x%20SE/Agentic%20AI%20Workflow%20Dev/LLM%20Workflow%20&%20Agents%20Dev%20Frameworks/LangChain%20&%20LangGraph.md)
	- ↗ [Google ADK (Agent Development Kits)](../../../../../../Software%20Engineering/🤖%20AI(LLM)%20x%20SE/Agentic%20AI%20Workflow%20Dev/LLM%20Workflow%20&%20Agents%20Dev%20Frameworks/Google%20ADK%20(Agent%20Development%20Kits).md)
- LLM App Dev Platform & AI Workflow
	- ↗ [Dify.AI](../../../../../../Software%20Engineering/🤖%20AI(LLM)%20x%20SE/Agentic%20AI%20Workflow%20Dev/LLM%20Workflow%20&%20Agents%20Dev%20Platforms/Dify.AI.md)
	- ↗ [Coze](../../../../../../Software%20Engineering/🤖%20AI(LLM)%20x%20SE/Agentic%20AI%20Workflow%20Dev/LLM%20Workflow%20&%20Agents%20Dev%20Platforms/Coze.md)
↗ [Multimodal AI & MLLM](../../../🐝%20Multimodal%20AI%20&%20MLLM/Multimodal%20AI%20&%20MLLM.md)

↗ [Web Automation, Testing, and WebDriver](../../../../../../Software%20Engineering/☝️%20Application%20Software%20Engineering/Desktop%20&%20Monolithic%20Application%20Development/🤠%20Web%20Browser%20Development/Web%20Automation,%20Testing,%20and%20WebDriver/Web%20Automation,%20Testing,%20and%20WebDriver.md)
↗ [Web Content Search Services & Wiki Projects & Wikimedia Foundation (WMF)](../../../../../../🔑%20CS%20Core/Generic%20Software%20Tools%20&%20Projects/🔍%20Web%20Content%20Search%20Services%20&%20Wiki%20Projects%20&%20Wikimedia%20Foundation%20(WMF)/Web%20Content%20Search%20Services%20&%20Wiki%20Projects%20&%20Wikimedia%20Foundation%20(WMF).md)

↗ [APIs & Interfaces in Web Development](../../../../../../Software%20Engineering/☝️%20Application%20Software%20Engineering/🕸️%20Web%20Development%20&%20The%20Internet/👬%20APIs%20&%20Interfaces%20in%20Web%20Development/APIs%20&%20Interfaces%20in%20Web%20Development.md)
↗ [DBMS (DataBase Management System) Implementations](../../../../../../🔑%20CS%20Core/🍕%20Computer%20Storage%20&%20Database%20Systems/Database%20Systems/DBMS%20(DataBase%20Management%20System)%20Implementations/DBMS%20(DataBase%20Management%20System)%20Implementations.md)
- ↗ [Vector Database](../../../../../../🔑%20CS%20Core/🍕%20Computer%20Storage%20&%20Database%20Systems/Database%20Systems/DBMS%20(DataBase%20Management%20System)%20Implementations/Vector%20Database/Vector%20Database.md)

↗ [(CS) Academics Roadmap & Tool Chain](../../../../../../Academics%20🎓%20(In%20CS)/🚸%20(CS)%20Academics%20Roadmap%20&%20Tool%20Chain/(CS)%20Academics%20Roadmap%20&%20Tool%20Chain.md)

↗ [Knowledge Graph (KG)](../../../../🗝️%20AI%20Basics%20&%20Machine%20Learning%20(ML)/Knowledge%20Representation%20and%20Reasoning%20(KRR)/Knowledge%20Graph%20(KG)/Knowledge%20Graph%20(KG).md)


### Papers
https://huggingface.co/papers/2508.06433
https://www.arxiv.org/abs/2508.06433
Memp: Exploring Agent Procedural Memory
- [Runnan Fang](https://arxiv.org/search/cs?searchtype=author&query=Fang,+R), [Yuan Liang](https://arxiv.org/search/cs?searchtype=author&query=Liang,+Y), [Xiaobin Wang](https://arxiv.org/search/cs?searchtype=author&query=Wang,+X), [Jialong Wu](https://arxiv.org/search/cs?searchtype=author&query=Wu,+J), [Shuofei Qiao](https://arxiv.org/search/cs?searchtype=author&query=Qiao,+S), [Pengjun Xie](https://arxiv.org/search/cs?searchtype=author&query=Xie,+P), [Fei Huang](https://arxiv.org/search/cs?searchtype=author&query=Huang,+F), [Huajun Chen](https://arxiv.org/search/cs?searchtype=author&query=Chen,+H), [Ningyu Zhang](https://arxiv.org/search/cs?searchtype=author&query=Zhang,+N)
- Large Language Models (LLMs) based agents excel at diverse tasks, yet they suffer from brittle procedural memory that is manually engineered or entangled in static parameters. In this work, we investigate strategies to endow agents with a learnable, updatable, and lifelong procedural memory. We propose Memp that distills past agent trajectories into both fine-grained, step-by-step instructions and higher-level, script-like abstractions, and explore the impact of different strategies for Build, Retrieval, and Update of procedural memory. Coupled with a dynamic regimen that continuously updates, corrects, and deprecates its contents, this repository evolves in lockstep with new experience. Empirical evaluation on TravelPlanner and ALFWorld shows that as the memory repository is refined, agents achieve steadily higher success rates and greater efficiency on analogous tasks. Moreover, procedural memory built from a stronger model retains its value: migrating the procedural memory to a weaker model yields substantial performance gains.


### Agentical LLM Projects
https://github.com/aiwaves-cn/agents
An Open-source Framework for Data-centric, Self-evolving Autonomous Language Agents

https://github.com/Alibaba-NLP/DeepResearch/
Tongyi DeepResearch, the Leading Open-source DeepResearch Agent

https://storage.googleapis.com/coscientist_paper/ai_coscientist.pdf
https://research.google/blog/accelerating-scientific-breakthroughs-with-an-ai-co-scientist/
Accelerating scientific breakthroughs with an AI co-scientist
February 19, 2025, Juraj Gottweis, Google Fellow, and Vivek Natarajan, Research Lead
- We introduce AI co-scientist, a multi-agent AI system built with Gemini 2.0 as a virtual scientific collaborator to help scientists generate novel hypotheses and research proposals, and to accelerate the clock speed of scientific and biomedical discoveries.

https://agentgym.github.io/
AgentGym: Evolving Large Language Model-based Agents across Diverse Environments
- [Zhiheng Xi](https://woooodyy.github.io/), Yiwen Ding, Wenxiang Chen, Boyang Hong, [Honglin Guo](https://scholar.google.com/citations?user=HrYYk4YAAAAJ), Junzhe Wang, Dingwen Yang, Chenyang Liao, [Xin Guo](https://scholar.google.com/citations?user=TwzyqksAAAAJ), Wei He, [Songyang Gao](https://scholar.google.com/citations?user=O42mLrsAAAAJ), Lu Chen, [Rui Zheng](https://scholar.google.com/citations?user=7Z0V_SoAAAAJ&hl=en), [Yicheng Zou](https://scholar.google.com/citations?user=X_nKjOYAAAAJ&hl=en),  [Tao Gui](https://guitaowufeng.github.io/), [Qi Zhang](http://qizhang.info/), [Xipeng Qiu](https://xpqiu.github.io/), [Xuanjing Huang](https://xuanjing-huang.github.io/), [Zuxuan Wu](https://zxwu.azurewebsites.net/), [Yu-Gang Jiang](https://scholar.google.com/citations?user=f3_FP8AAAAAJ&hl=en),
- Fudan NLP Lab & Fudan Vision and Learning Lab

🏠 https://novix.science/
🚧 https://github.com/HKUDS/AI-Researcher
📄 https://arxiv.org/abs/2505.18705 | AI-Researcher: Autonomous Scientific Innovation
- [Jiabin Tang](https://arxiv.org/search/cs?searchtype=author&query=Tang,+J), [Lianghao Xia](https://arxiv.org/search/cs?searchtype=author&query=Xia,+L), [Zhonghang Li](https://arxiv.org/search/cs?searchtype=author&query=Li,+Z), [Chao Huang](https://arxiv.org/search/cs?searchtype=author&query=Huang,+C)
- The powerful reasoning capabilities of Large Language Models (LLMs) in mathematics and coding, combined with their ability to automate complex tasks through agentic frameworks, present unprecedented opportunities for accelerating scientific innovation. In this paper, we introduce AI-Researcher, a fully autonomous research system that transforms how AI-driven scientific discovery is conducted and evaluated. Our framework seamlessly orchestrates the complete research pipeline--from literature review and hypothesis generation to algorithm implementation and publication-ready manuscript preparation--with minimal human intervention. To rigorously assess autonomous research capabilities, we develop Scientist-Bench, a comprehensive benchmark comprising state-of-the-art papers across diverse AI research domains, featuring both guided innovation and open-ended exploration tasks. Through extensive experiments, we demonstrate that AI-Researcher achieves remarkable implementation success rates and produces research papers that approach human-level quality. This work establishes new foundations for autonomous scientific innovation that can complement human researchers by systematically exploring solution spaces beyond cognitive limitations.


### Agentic (M)LLM Products
https://labs.google.com/mariner/landing

https://deepmind.google/blog/sima-2-an-agent-that-plays-reasons-and-learns-with-you-in-virtual-3d-worlds/


### Others
https://academy.langchain.com/courses/deep-research-with-langgraph/
Project: Deep Research with LangGraph
Build your own deep research agent to handle research tasks. Learn how to use LangGraph to build a multi-agent system, then use LangSmith to evaluate its performance.

Anthropic: ["How we built our multi-agent research system"](https://www.anthropic.com/engineering/multi-agent-research-system)
Anthropic: ["How Anthropic teams use Claude Code"](https://www-cdn.anthropic.com/58284b19e702b49db9302d5b6f135ad8871e7658.pdf)
Anthropic :  ["Claude for life sciences"](https://www.anthropic.com/news/claude-for-life-sciences)

Anthropic: "[Introducing Agent Skills](https://www.anthropic.com/news/skills)"
- Claude can now use _Skills_ to improve how it performs specific tasks. Skills are folders that include instructions, scripts, and resources that Claude can load when needed.
- Claude will only access a skill when it's relevant to the task at hand. When used, skills make Claude better at specialized tasks like working with Excel or following your organization's brand guidelines.
Anthropic: ["Equipping agents for the world with Agent Skills"](https://www.anthropic.com/engineering/equipping-agents-for-the-real-world-with-agent-skills)

McKinsey: ["Seizing the agentic AI advantage"](https://drive.google.com/file/d/12XzdsgGjDBCkRjRt7ZhihqlN_EO1y_f1/view?usp=share_link)
McKinsey: ["Reimagining life science enterprises with agentic AI"](https://drive.google.com/file/d/1DnhQxaFxCbzHudJuDIMlClCRq9wQ6QxB/view?usp=share_link)
Open AI: ["GDPval evaluating AI model performance"](https://drive.google.com/file/d/13DVuFCbVtg1QupfpZmjcQ6AamypG935k/view)
Appel et al. : [Anthropic Economic Index report: Uneven geographic and enterprise AI adoption](https://www.anthropic.com/research/anthropic-economic-index-september-2025-report)



## Intro
### LLM Agent
![](../../../../../../../Assets/Pics/Pasted%20image%2020240512204130.png)
<small>https://docs.phidata.com/introduction</small>

**Problem:** LLMs have limited context and cannot take actions.  
**Solution:** Add memory, knowledge and tools.
- **Memory:** Enables LLMs to have long-term conversations by storing **chat history** in a database.
- **Knowledge:** Provides LLMs with **business context** by storing information in a vector database.
- **Tools:** Enable LLMs to **take actions** like pulling data from an API, sending emails or querying a database.

![MCP.excalidraw | 800](../../../../../../../Assets/Illustrations/AI%20&%20LLM/MCP.excalidraw.md)


### Agentic LLM Workflows



## Ref
[LLM-Agent原理讲解 - shikanon的文章 - 知乎]: https://zhuanlan.zhihu.com/p/659784334
![](../../../../../../../Assets/Pics/Screenshot%202024-03-22%20at%201.30.46%20PM.png)

[The Dawn of AI Cybersecurity: How LLM-Agents Are Changing the Game | Cyber Builders]: https://open.substack.com/pub/cyberbuilders/p/ai-cybersecurity-llm-agents?utm_campaign=post&utm_medium=web

[复旦 | 推出通用大模型Agent平台：AgentGym，提供一条龙服务！]: 

[Accelerating scientific breakthroughs with an AI co-scientist | February 19, 2025, Juraj Gottweis, Google Fellow, and Vivek Natarajan, Research Lead]: https://research.google/blog/accelerating-scientific-breakthroughs-with-an-ai-co-scientist/
We introduce AI co-scientist, a multi-agent AI system built with Gemini 2.0 as a virtual scientific collaborator to help scientists generate novel hypotheses and research proposals, and to accelerate the clock speed of scientific and biomedical discoveries.
