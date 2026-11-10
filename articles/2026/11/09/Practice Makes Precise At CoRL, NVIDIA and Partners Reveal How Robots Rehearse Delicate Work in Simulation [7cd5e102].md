---
id: "7cd5e10290710b74"
title: "Practice Makes Precise: At CoRL, NVIDIA and Partners Reveal How Robots Rehearse Delicate Work in Simulation"
url: "https://blogs.nvidia.com/blog/robotics-simulation-advancements-corl"
link: "https://blogs.nvidia.com/blog/robotics-simulation-advancements-corl"
source: "NVIDIA Blog"
domain: "blogs.nvidia.com"
source_type: "company_blog"
collector: "rss"
date: "2026-11-09T14:00:01Z"
published_date: "2026-11-09"
collected_at: "2026-11-10T13:04:10Z"
authors: ["Sasa Docca"]
language: "en"
summary: "Simulation, which has long been the proving ground for robots learning to walk, roll and hop, is now helping researchers teach robots tasks that require a finer touch: aligning gears, connecting cables and assembling small components.  \n The shift from locomotion to manipulation is taking center stage at this week’s Conference on Robot Learning (CoRL) in Austin, Texas, alongside the rise of…"
tags: ["Robotics", "Agentic AI", "Artificial Intelligence", "Cosmos", "Events", "Industrial and Manufacturing", "Isaac", "NVIDIA Research", "Omniverse", "Open Source", "Physical AI", "Simulation and Design"]
orgs: ["Nvidia", "Hugging Face"]
topics: ["robotics & autonomy", "models & research", "chips & infrastructure", "agents & coding"]
content_source: "fulltext"
word_count: 1531
paywalled: false
image: "https://blogs.nvidia.com/wp-content/uploads/2026/11/corl-corp-blog-promo-pack-1920x1080-1.png"
discussion_url: null
score: null
comments: null
community: null
---

# Practice Makes Precise: At CoRL, NVIDIA and Partners Reveal How Robots Rehearse Delicate Work in Simulation

NVIDIA Blog · Sasa Docca · 2026-11-09

Simulation, which has long been the proving ground for robots learning to walk, roll and hop, is now helping researchers teach robots tasks that require a finer touch: aligning gears, connecting cables and assembling small components.
The shift from locomotion to manipulation is taking center stage at this week’s Conference on Robot Learning (CoRL) in Austin, Texas, alongside the rise of agentic robotics — a new paradigm that integrates frontier agents to create interpretable code for physical robotics systems.
At CoRL, NVIDIA is introducing new open robotics technologies, including world action models, simulation tools, benchmarks and agentic workflows.
Two NVIDIA papers are among six finalists out of thousands of submissions for the Best Paper Awards at CoRL:
- GRAIL (Generating Humanoid Loco-Manipulation from World Models), which presents a digital generation pipeline for 3D assets and simulator-ready scenes for robot learning.
- RoboTTT: Context Scaling for Robot Policies, which introduces a robot model and training recipe that scales visuomotor context three orders of magnitude beyond state-of-the-art policies without growing inference latency.
These advancements help researchers train robots on complex tasks, evaluate their performance across changing conditions and use failures to guide further learning — building the precision, adaptability and autonomy needed to move from lab demonstrations to industrial deployment.
NVIDIA is working with partners like Ambi Robotics, Bosch Research, Dexmate, Dyna Robotics, FieldAI, Flexion, Noitom Robotics, Siemens, Skild AI, RLWRLD, UC Berkeley, Walden Robotics and the University of Washington to bring these advancements to the broader robotics community.
World Action Models Enable Next Level of Robot Autonomy
The next level of robot autonomy requires robots to perceive their surroundings, anticipate how their actions will change the environment and execute complex, multistep tasks with a high degree of precision. World action models enable exactly that.
At CoRL, NVIDIA is introducing GR00T 2, an open frontier world action model built on NVIDIA Cosmos. Trained on diverse robot and human data, including 100,000 hours of NVIDIA open source human egocentric data, the model enables robots to learn dexterous manipulation skills. Key features include:
- Out-of-the-box performance: Completed 40 of 50 evaluated tasks at least once without task-specific demonstrations.
- Skill transfer: Learns from human demonstrations and transfers skills between different robot bodies without robot demonstrations
- Generalization with little data: Achieved 71% average success across 50 tasks with just one demonstration per task, increasing to 95% with five.
- Agent control: AI agents can use GR00T 2’s application programming interface and supporting tools to run skills in sequence and recover from errors.
GR00T 2 currently ranks among the top three models across all vision language action and world action model categories for the RoboCasa365, RoboLab, RoboDojo and MolmoSpaces benchmarks, with multiple leaderboard wins.
Nexuni is testing it for robotic laundry handling, Foxconn is applying GR00T 2 to factory automation for server manufacturing and Siemens is evaluating it across industrial use cases.
MicroAGI is using GR00T 2, post-trained through reinforcement learning, to perform Ethernet cable swapping with a YAM robotic arm. Its agentic robotics approach automates the creation and calibration of simulation environments using Isaac Lab 3.0 and Newton, where the policy is trained.
Training capable robots requires diverse data. Open NVIDIA workflows and models equip researchers with better tools for data collection and annotation:
- For researchers building robot-training datasets, NVIDIA’s new open Video to Data workflow turns human video into simulated robot demonstrations, with a challenge inviting researchers to advance it.
- The NVIDIA EgoHand open model — being demoed at CoRL and with over 40,000 Hugging Face downloads in the two weeks since launch — reconstructs 3D hand motion, trained with data from Noitom Robotics.
Where the Training and Scaling Happens — in Simulation
A pretrained model gives robots a core set of skills. Simulation lets researchers train, refine and evaluate skills at scale before deploying them on physical robots.
NVIDIA Isaac Lab, an open source robot-learning framework, provides the foundation for that work. Its latest release, Isaac Lab 3.0, allows researchers to use agents to quickly set up training environments with simulation-ready assets, switch between NVIDIA PhysX and Newton physics solvers, choose renderers for perception-based training and apply a new reinforcement post-training library to foundation models like GR00T.
Accurate physics is critical to transferring learned skills from simulation to the real robot. Tighter integration with Newton, an open source physics engine, now allows Isaac Lab to model deformable objects such as cables and cloth, along with complex articulated systems such as robotic hands with many interacting joints.
Integration with Newton simulates how a strawberry deforms under a robot’s grip.
Together, Isaac Lab and Newton combine accurate physics with scale to enable researchers to train thousands of simulated robots in parallel. In a vision-based dexterous manipulation benchmark, Isaac Lab 3.0 with Newton achieved up to 2.5x the training throughput of Isaac Lab 2.3 with PhysX.
Isaac Lab supports robot simulation with Newton and NVIDIA PhysX.
Developers are extending Newton’s capabilities. At CoRL, Skild AI announced Scalable Throughput-optimized Engine for Embodied Learning, or STEEL, a new rigid-body physics solver built on Newton to accelerate robot training with Isaac Lab.
Skild AI’s STEEL Solver.
Flexion showcased how Isaac Lab and Newton help train Reflect, its robot-intelligence model combining reasoning and whole-body manipulation.
Flexion uses Newton for RL with Isaac Lab.
FieldAI is using Newton — as well as Isaac Lab and Isaac Sim, built on NVIDIA Omniverse libraries — to train and validate robot policies for deployment in unstructured real-world environments. Dyna Robotics will demonstrate how parallel simulation in Isaac Lab helps train whole-body controllers for its semi-humanoid Taku robot for work in warehouses, hotels and food services.
Walden Robotics is using Isaac Sim’s photorealistic rendering to train and evaluate its general-purpose robot in virtual environments for manufacturing and logistics, while Dexmate is exploring how coding agents can rehearse and refine manipulation strategies in Isaac Sim before executing them on its Vega robot.
AlphaNIST, built in Isaac Lab, demonstrates how efficient practice can translate into precision. A single policy learns all 20 tasks on the NIST Assembly Task Board, manipulating millimeter-scale parts using only a yes-or-no success signal. It achieves more than 98% training success, compared with 81% for separate per-task policies, using roughly 39x less GPU time.
AlphaNIST uses Isaac Lab to train a single robot policy across 20 precision tasks on the NIST Assembly Task Board.
Behind those results is Success-Guided Sampling, or SGS, from the University of Washington and NVIDIA. The method focuses practice on tasks a policy succeeds at about half the time, directing training toward skills it’s still learning. With SGS, robot training can scale beyond a million parallel environments.
The University of Texas at Austin’s School of Computing and Texas Robotics uses Isaac Sim and Isaac Lab to train robotic skills in simulation, letting students start developing before physical hardware is available.
New Industrial Benchmarks for Robot Evaluation
Learning a skill is one challenge. Performing it reliably across changing conditions is another.
NVIDIA Isaac Lab-Arena, an open source framework for scaled policy evaluation, enables developers to compose diverse and repeatable evaluations, then run policies across thousands of variations in parallel. Analyses expose which conditions cause failures, so researchers know what to fix in their next training run. The developer preview of its latest version, 0.4, is arriving at CoRL.
DexBench and VABAR, two new open benchmarks, are among the first designed to measure robot dexterity and adaptability across industrial tasks using Isaac Lab-Arena and Newton.
DexBench, developed by RLWRLD in collaboration with NVIDIA, takes dexterity evaluation off the tabletop and into real-world workflows. Built using NVIDIA Isaac Lab-Arena, it features 15 tasks across four scenes spanning retail, logistics, manufacturing and hospitality, testing generalization across object, spatial and physics variations.
Genesis AI, mimic robotics and other industry partners are evaluating DexBench through early access.
Teams can run DexBench on Manifold, Bifrost’s evaluation platform for scaling robotics simulations, with no setup required, built-in failure analysis and free credits for initial evaluations.
VABAR — the Variational Automation Benchmark for Agentic Robotics — from UC Berkeley and NVIDIA, evaluates robots across six industrial tasks. Each carries standardized variations, difficulty tiers and success metrics.
A simulated tool-sorting task demonstrates how VABAR evaluates robot manipulation skills for industrial workflows.
Agents Turn Skills Into Robot Programs
Successful task completion requires robots to coordinate multiple skills and adapt when something goes wrong. Building reliable programs for these multistep tasks remains a challenge.
Agentic robotics helps solve that challenge.
UC Berkeley’s new Graph-as-Policy (GaP) framework uses agents to connect individual skills into robot programs. Agents test these programs using NVIDIA Isaac open simulation technologies and refine them based on failures. This helps researchers scale development with less data while keeping the programs interpretable for engineers to review and verify before deployment.
GaP uses agents and simulation to turn individual robot skills into coordinated actions, such as wiping a bar.
“To me, agentic robotics is the most exciting technological development since the internet in 1995,” said Ken Goldberg, professor of robotics at UC Berkeley and a lead on the VABAR and GaP projects.
Ambi Robotics, Bosch Research and Siemens are all exploring GaP for its agentic robotics workflows across diverse industrial scenarios.
Learn more by joining NVIDIA at CoRL.
