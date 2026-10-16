---
id: "2cd92b812c13525a"
title: "Open From Data Center to Desktop: NVIDIA Expands Nemotron Family With Highest Efficiency Super VL and Bolt Models"
url: "https://blogs.nvidia.com/blog/nemotron-3-5-super-vl"
link: "https://blogs.nvidia.com/blog/nemotron-3-5-super-vl"
source: "NVIDIA Blog"
domain: "blogs.nvidia.com"
source_type: "company_blog"
collector: "rss"
date: "2026-10-15T15:00:24Z"
published_date: "2026-10-15"
collected_at: "2026-10-16T12:06:51Z"
authors: ["Kari Briski"]
language: "en"
summary: "NVIDIA today released Nemotron 3.5 Super VL, an open 120-billion-parameter model that delivers the fastest task completion and highest accuracy for specialized always-on agents. \n Joining it are two new edge models: Nemotron 3.5 Bolt 74B-A9B 24GB, optimized to balance intelligence and speed per GB for local agentic workloads, and Nemotron 3.5 Bolt E4B 4GB, optimized for intelligence per GB for…"
tags: ["AI", "Corporate", "Deep Learning", "Nemotron"]
orgs: ["Nvidia", "Perplexity", "Salesforce", "Scale AI"]
topics: ["agents & coding", "models & research", "chips & infrastructure", "search & media"]
content_source: "fulltext"
word_count: 1189
paywalled: false
image: "https://blogs.nvidia.com/wp-content/uploads/2026/10/FIRST-agentic-ai-nemotron-3.5-super-vl-blog-1920x1080-5783765.jpeg"
discussion_url: null
score: null
comments: null
community: null
---

# Open From Data Center to Desktop: NVIDIA Expands Nemotron Family With Highest Efficiency Super VL and Bolt Models

NVIDIA Blog · Kari Briski · 2026-10-15

NVIDIA today released Nemotron 3.5 Super VL, an open 120-billion-parameter model that delivers the fastest task completion and highest accuracy for specialized always-on agents.
Joining it are two new edge models: Nemotron 3.5 Bolt 74B-A9B 24GB, optimized to balance intelligence and speed per GB for local agentic workloads, and Nemotron 3.5 Bolt E4B 4GB, optimized for intelligence per GB for fast conversational agents.
Super VL and Bolt 74B-A9B are available now, with Bolt E4B coming Oct. 23.
The three open models together cover the full range of agent deployments, from large enterprise servers down to edge devices and local hardware. 
Any organization that wants to run agents on NVIDIA infrastructure now has an open, optimized model for their tier, without having to choose between capability and deployability.
Super VL and Bolt join the Nemotron family alongside Lightning and Ultra.
Lightning, released in August, handles high-throughput workloads; Ultra handles the hardest reasoning tasks; and Bolt brings intelligence to the edge.
Nemotron 3.5 Super VL: Frontier Accuracy at One-Fifth the Size
Super VL, built in collaboration with the Nemotron Coalition, delivers leading accuracy on multimodal agentic tasks — instruction following, tool use, multistep business workflows, and visual understanding — comparable with NVIDIA’s largest reasoning model at roughly one-fifth the parameter count.
As the fastest open agentic model in its class — 5x faster than the next best — it helps enterprise agents complete high-volume tasks faster across workflows that span days or weeks.
Unlike closed frontier models, organizations can post-train Super VL on their own data, deploy it on their own infrastructure and oversee what they build.
Nemotron 3.5 Bolt: Agentic Intelligence at the Edge
Bolt 74B-A9B 24GB is designed to run everyday agentic tasks locally on NVIDIA RTX/DGX Spark, using a native 2-bit quantization to fit in 24GB of memory and run alongside other applications.
Relative to other models with a similar memory footprint, it provides a good balance of intelligence and speed: smart enough to get most jobs done, yet much faster than the smartest models.
With Bolt 74B-A9B 24GB, users can delegate their projects to popular local agent harnesses — from researching the web to writing to debugging code — all without sending those workloads to the cloud. It is the #1 open model in its class on PinchBench, and the #2 open model for BrowseComp.
Bolt E4B 4GB is built for physical and conversational agents on GeForce RTX, Jetson, and RTX/DGX Spark. It combines natural conversation with multi-turn agentic capabilities to power fast local voice assistants, interactive characters and embedded interfaces. 
Adoption of Custom Super Intelligence
Dozens of organizations across industries are post-training Super VL on their own data, tools, policies and workflows to push accuracy higher on the specialized tasks that define their agent deployments.
Super VL is being post-trained and customized by organizations across industries. Scale AI post-trained the model for Skydance’s vendor credit finance agent and for EY’s M&A due diligence agent. AfterQuery customized the model for Hebbia for credit agreement analysis. AI21 and Alice post-trained the model for cybersecurity attack resilience. Mercor post-trained the model on APEX-SWE coding benchmark, for coding agents that plan, write and debug code. ModelScope enables developers to fine-tune the model through its ms-swift framework for specialized multimodal applications.
Additional organizations customizing Nemotron 3.5 Super VL include Ramp for financial document intelligence; Dream, sovereign AI-powered cybersecurity research and vulnerability analysis; Lila Sciences for scientific discovery and search, and R1 for medical claims analysis and revenue cycle management. TrainLoop post-trained the model with dermatology data from Nolla, which just became the first company approved for AI to write initial patient prescriptions.
Software platform companies integrating Nemotron 3.5 Super VL include: 
- Atlassian, for tasks like agentic search across apps such as Jira and Confluence.
- CrowdStrike, which is customizing the model for agentic blue teaming in enterprise security.
- Dassault Systèmes, powering engineering design and simulation.
- Perplexity, for search and agentic tasks in Perplexity Search and Computer.
- Salesforce, which is customizing Nemotron to power AI agents that digitize and automate complex government workflows in secure customer environments through Missionforce Operations.
- Synopsys software for semiconductor design verification interoperates with the model.
What Nemotron 3.5 Super VL Actually Sees
Nemotron 3.5 Super VL’s vision language strengths are targeted at what agents encounter in practice: optical character recognition, tables, charts and structured information in visual documents.
It processes a web page, extracts text, reads graphs and charts, and returns insights from what it finds. The same applies to PDFs and other documents agents commonly work with.
Nemotron 3.5 Super VL understands images, webpages and PDFs and acts on that understanding. Combining text and visual understanding in one model means agents don’t need to route tasks between separate systems — context carries through as work moves from document to data to decision.
Open for Maximum Control, Security, and Privacy
Openness and customizability reinforce each other. The model ships with open weights, open datasets and training recipes.
Control runs in two directions. Organizations can run the model wherever their security and data-residency requirements dictate. They also choose to adopt a model they can adapt, rather than one subject to a provider’s restrictions.
In insurance, for example, a customized agent can scan claims for fraud markers on repeat. In financial services, an agent can review credit scores and flag activity against an organization’s own lending criteria. The model stays on premises. The data stays private.
Customization is supported through NVIDIA NeMo, Python-based pipelines and open datasets.
Nemotron 3.5 Super VL was trained on about 26 trillion tokens across pretraining and continued pretraining, then post-trained with roughly 3.8 million samples and reinforcement learning across dozens of environments.
NVIDIA is also releasing open datasets on Hugging Face spanning agentic tool use, finance, instruction following, long context, fairness and vision-language understanding, along with the reinforcement learning environments in NeMo Gym.
NVIDIA NIM packages the model as a production-ready microservice with performance-optimized, validated configurations and enterprise-grade support, refreshed every two weeks with security patches and performance improvements.
And with the model running on NVIDIA Dynamo, organizations can serve up to 8x more users with 85% lower latency.
Nemotron 3.5 Super VL is available now on Hugging Face, Open Router, ModelScope community and as NVIDIA NIM.
Runs on DGX Spark, DGX Station, and RTX
Nemotron 3.5 Super VL runs across NVIDIA’s full hardware stack: on DGX Spark, DGX Station, RTX PRO and RTX systems for local intelligence at the desktop, on NVIDIA Jetson at the edge, and across data center and cloud environments.
Nemotron 3.5 Bolt 74B-A9B 24GB is available now on Hugging Face, with support for llama.cpp, Ollama, LM Studio, Unsloth, and vLLM. Built for NVIDIA RTX Spark laptops arriving Oct. 16, it also runs on GeForce RTX PCs, DGX Spark, DGX Station and RTX PRO workstations.
Download the open weights, explore customization resources with NVIDIA NeMo, or read the technical blog for the full architecture breakdown.
Stay up to date on agents, NVIDIA Nemotron and more by subscribing to NVIDIA news, joining the community, and following NVIDIA AI on LinkedIn, Instagram, X and Facebook.
Explore self-paced video tutorials and livestreams.
See notice regarding software product information.
