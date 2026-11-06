---
id: "2846e03446f423d7"
title: "Axiom Math wants to keep AI slop out of mathematics"
url: "https://techcrunch.com/2026/11/05/axiom-math-wants-to-keep-ai-slop-out-of-mathematics"
link: "https://techcrunch.com/2026/11/05/axiom-math-wants-to-keep-ai-slop-out-of-mathematics"
source: "TechCrunch"
domain: "techcrunch.com"
source_type: "tech_press"
collector: "rss"
date: "2026-11-05T16:16:45Z"
published_date: "2026-11-05"
collected_at: "2026-11-06T13:04:08Z"
authors: ["Aditya Mehta"]
language: "en"
summary: "As AI floods math with unchecked proofs, Axiom Math is betting on verification. The startup’s AI agents just formally verified the Stacks Project, one of the field’s biggest libraries."
tags: ["AI", "Startups", "agents", "math"]
orgs: ["OpenAI"]
topics: ["agents & coding", "business & funding"]
content_source: "fulltext"
word_count: 930
paywalled: false
image: null
discussion_url: null
score: null
comments: null
community: null
---

# Axiom Math wants to keep AI slop out of mathematics

TechCrunch · Aditya Mehta · 2026-11-05

It feels like AI is cracking a new math problem every week. Last month, OpenAI released 719 manuscriptsclaiming solutions to some of the field’s hardest problems. But even the computer checks meant to confirm those results can slip. After years of AI slop, it’s fair to wonder whether math is next.
Axiom Math is betting math can avoid that fate, not by slowing down, but by standing on firmer ground. The $1.6 billion startup wants to build a verified foundation that AI agents can rely on to write software and, eventually, do science.
On Wednesday, the company announced it had formally verified the Stacks Project, one of the largest bodies of mathematics ever written by humans. Mathematicians often hold Stacks in rare regard — Columbia mathematician Peter Woit has claimed there’s “nothing else really comparable,” comparing the project to “the famous Bourbaki books,” a series that rebuilt math from its foundations in the 20th century.
Woit’s Columbia colleague Johan de Jong started the Stacks Project in 2005 as an open source reference. Mathematicians have contributed to it ever since, building out results from college-level algebra all the way up to the field’s most advanced ideas across algebra, geometry, and number theory.
The company’s fleet of AI agents translates the library’s roughly 7,654 pages into about 16 million lines of computer-checked code.
Formalizing math is a way of making sure the structure underneath it is sound. Mathematicians rewrite the proof as code in a programming language called Lean, and a program called a proof assistant checks the code line by line. If the proof passes, mathematicians can trust that it’s logically sound.
Engineers use the same idea, called formal verification, to confirm their chip designs work, while researchers in France have used it to catch bugs in software that calculates family benefits.
For a library like the Stacks Project, checking each theorem is only part of the job. The theorems and definitions in Stacks are interconnected, and each one builds on the ones before it. Like a family tree, many results in Stacks trace back to the ones that came before it.
That interconnectedness made Axiom unsure the project would work at first. The team had to keep every connection intact across about 16 million lines of Lean code.
“Things that are big and things that are delicate in life just don’t go together,” Axiom CEO Carina Hong told TechCrunch. “[Stacks] is a collection of mathematical results that is the foundation of mathematics. You want [theorems] to be consistent and not, like, paradoxical. You want the definitions to not fight with each other.”
The 25-year-old CEO dropped out of a Stanford math PhD program and founded the company in March 2025. In March, Axiom raised a $200 million Series A led by Menlo Ventures.
“We were not sure if vibe coding would be able to preserve the beauty of Stacks,” Hong said.
To pull off the project, the team gave its agents a loose structure and let them run in parallel. “With Stacks, we imposed a hierarchy … [but] it was not, like, a complete hierarchy of dictating what every single agent was doing,” said Ashvin Swaminathan, a member of Axiom’s technical staff. “The agents were finding tasks for themselves and identified things that they could work on in parallel.”
Axiom also trained its own models to be good at math, an approach Hong said most other verification startups haven’t taken. At first, the team relied on one of its in-house Lean experts to teach the agents a human sense of taste. Over time, Hong said, the agents have picked up taste on their own.
The result fills one of the biggest gaps in formalized math. “When you look at what has been formalized in mathematics, there’s this huge black hole. And that black hole covers algebraic geometry,” Swaminathan said.
Until now, researchers who wanted to check new work in algebraic geometry with Lean had little to build on, Swaminathan said. “Well, now they do.”
Axiom argues that each verified result becomes a building block, so future proofs can lean on checked math instead of starting from scratch. Terence Tao, the UCLA mathematician and Fields Medal winner, has made the general case more simply: “The more formalized proofs you have, the more formalized proofs you can make.”
Mathematicians aren’t Axiom’s only intended audience. Developers have long struggled to guarantee that their code is free of bugs and security holes. That problem grows as AI agents write more of the world’s code.
Axiom is betting that the software of the future will need to rest on verified foundations, the way Stacks now does.
“We believe that mathematics is the domain where you start building these things and that it’s a transferable skill,” Swaminathan said. “Agents can read our code, understand it, and build new infrastructure on top of it. Our Lean formalization is now the substrate that agents can build upon.”
The way Axiom’s agents built Stacks, working in parallel and picking their own tasks, is how Hong expects much of AI’s future work to happen. AI agents, she argues, will need a well-built, reusable body of knowledge to keep from producing slop.
“You want [agents] to have a reusable library for them to build on and keep pushing the frontier,” Hong said. “If you slop drop in a way that’s bad engineering choices in the beginning, then it’s very hard for them to grow that boundary.”
Hong is confident enough in that approach to issue a dare. “I openly challenge all the coding companies to work on formalization at this scale.”
