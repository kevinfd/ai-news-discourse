---
id: "4e0db7fb75d010dc"
title: "Dueling proofs from OpenAI and Anthropic astound scientists"
url: "https://scientificamerican.com/article/dueling-proofs-from-openai-and-anthropic-astound-scientists"
link: "https://scientificamerican.com/article/dueling-proofs-from-openai-and-anthropic-astound-scientists"
source: "Scientific American"
domain: "scientificamerican.com"
source_type: "tech_press"
collector: "rss"
date: "2026-10-27T14:30:00Z"
published_date: "2026-10-27"
collected_at: "2026-10-28T12:05:24Z"
authors: ["Joseph Howlett", "Peter Hall"]
language: "en"
summary: "The results resolve major problems in math, physics and computer science. But like other recent AI-generated “slop drops,” the releases are already controversial"
tags: []
orgs: ["OpenAI", "Anthropic", "US government"]
topics: ["health & science", "models & research", "products & launches", "business & funding"]
content_source: "fulltext"
word_count: 1065
paywalled: false
image: null
discussion_url: null
score: null
comments: null
community: null
---

# Dueling proofs from OpenAI and Anthropic astound scientists

Scientific American · Joseph Howlett, Peter Hall · 2026-10-27

Just a few weeks after dropping hundreds of artificial-intelligence-generated math breakthroughs on a field that’s already in crisis, OpenAI is piling on more.
Yesterday the company dropped three massive proofs that touched on math, physics and computer science, sending shockwaves rippling through those fields. Experts are still staggering.
These latest releases from OpenAI continue to contradict the recommendations of the Advisory Group on Mathematics and Artificial Intelligence (AGMAI), the expert panel the company organized in response to widespread criticism from mathematicians. The large language model (LLM) that produced the new proofs remains proprietary, and the exact prompts used, time spent computing and “chain of thought outputs” involved have not been made public. Two of the results coincide with closely related work involving OpenAI’s competitor Anthropic.
On supporting science journalism
OpenAI’s approach to two of the three results also directly violates a clarifying statement AGMAI issued just a day before they were released by designating specific experts to shepherd the results into the public sphere. Among the work of such experts, a paper relating to the “million-dollar” Yang-Mills problem (one of seven Millennium Prize Problems set by the Clay Mathematics Institute in 2000) has still not been made public. Writing that “there is no scientific reason for delaying ... any further,” AGMAI has already called on OpenAI to release the paper.
Here’s a quick breakdown of what the three new results are and why they matter.
Kakeya
The Kakeya conjecture is about swirling a needle or stylus around in the air cleverly—so that it points in every direction once but sweeps out as little volume as possible. Specifically, the conjecture says that the volume cannot be less than a certain number. Surprisingly, this simple geometry problem is one of the most important conjectures in harmonic analysis, the study of how all kinds of mathematical objects can be built from waves.
Last year mathematicians Hong Wang and Joshua Zahl proved the conjecture in three dimensions in one of the biggest math breakthroughs of this century. The feat won Wang a Fields Medal—math’s highest honor—at this summer’s International Congress of Mathematicians in Philadelphia. But the problem remained open in higher-dimensional spaces.
In last month’s “slop drop,” OpenAI’s internal model solved the four-dimensional Kakeya problem. Now it’s solved the problem in every dimension, proving that there’s a limit to how small a space a high-dimensional stylus can take up.
Yang-Mills
The Yang-Mills problem, one of Clay’s five million-dollar Millennium Prize Problems that remain open, is about particle physics. Specifically, it asks whether the mathematics that underpins the “Standard Model” of particle physics is actually sound.
This question comes down to two parts, referred to as “existence” and “mass gap.” The Clay Mathematics Institute’s definition of the problem asks for answers to both. Today OpenAI claimed to prove the first of the two—that the “Yang-Mills theory” is mathematically consistent in all relevant cases: in other words, it “exists.” The part of the Clay problem that remains open is more quantitative, asking whether a certain number in the theory, called the “mass gap,” is always bigger than zero.
In the late 1980s, a little more than a decade before the Clay Mathematics Institute existed, mathematician Tadeusz Balaban published a series of massive, dense papers that sketched out a path to prove the “existence” part of the problem. As voluminous as “Balaban’s program” is, it only codifies the problem’s broad contours—filling in the gaps to construct a mathematically rigorous proof would demand far more laborious and exhaustive calculations. The project is so immense—and Balaban’s papers are so difficult to parse—that no one has carried it out more than three decades later. “He basically did it,” says Roland Bauerschmidt, a mathematician at New York University. “But I think there’s no one who understands these papers and can tell whether they’re correct or not.”
Recently, sensing that a race was on to finish Balaban’s program, some experts began using LLMs to churn out the necessary tomes of tedious mathematical steps. Working with Anthropic employee Levent Alpöge, Ethan Sussman, a mathematician at Northwestern University, created and publicized a public GitHub repository to do just that. They were making considerable progress and believed they were near to finishing the program. OpenAI’s claim—with no publicly available proof—appears to have beaten them to the finish line.
Exponential Time Hypothesis
The exponential time hypothesis (ETH) is about computational complexity—the science of ranking computer science problems by how hard they are.
Specifically, ETH suggests that a famous task called the 3-satisfiability, or 3-SAT, problem cannot be solved in less than exponential time. This means that as the number of variables in the problem increases, any algorithm that solves it will run exponentially slower. OpenAI’s proof provides an algorithm to solve 3-SAT that is just a tiny bit faster than exponential time, refuting ETH.
ETH is important because of its relationship to “P versus NP,” which is another of the Clay institute’s Millennium Prize Problems and widely considered to be one of the most difficult, with major implications for modern encryption.
First suggested in 1999, ETH can be thought of as an even stronger version of P ≠ NP (the conjecture that P does not equal NP, which the majority of people in the field believe) and has been treated as a bedrock tenet of computer science by most experts. Because 3-SAT is a problem computer scientists know to be central to the debate, ETH would show that there were problems that were not only fundamentally hard to solve but that would also scale up so brutally that they would be effectively unassailable.
Although the new result doesn’t necessarily translate to a transformative breakthrough about P versus NP, the potential effects are so sweeping that OpenAI has tapped outside experts to vet its claim. Russell Impagliazzo and Ramamohan Paturi, two computer scientists at the University of California, San Diego, who first suggested ETH, as well as Ryan Williams, a computer scientist at the Massachusetts Institute of Technology, are now working with OpenAI to perform an independent investigation of the result. The company will also sponsor a computer science conference about the proof as part of this investigation, according to Williams.
The result hasn’t been without controversy, either. Mere hours after OpenAI’s announcement, Anthropic posted its own independent result disproving ETH, based on work by an internal Anthropic model.
Editor’s Note (10/27/26): This is a breaking news story and will be updated.
