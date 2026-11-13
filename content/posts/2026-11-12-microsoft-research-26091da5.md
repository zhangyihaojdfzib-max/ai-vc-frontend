---
title: 'Microsoft Research Focus – Edition #98 - Microsoft Research'
title_original: 'Microsoft Research Focus – Edition #98 - Microsoft Research'
date: '2026-11-12'
source: Microsoft Research
source_url: https://www.microsoft.com/en-us/research/podcast/microsoft-research-focus-edition-98/
author: ''
summary: '[翻译失败，原文如下]


  What’s new in research?


  In this edition ofMicrosoft Research Focus, based on theResearch Focus newsletter(opens
  in new tab), host Anson ...'
categories:
- 未分类
tags: []
draft: false
translated_at: '2026-11-13T09:19:13.564479'
---

[翻译失败，原文如下]

What’s new in research?

In this edition ofMicrosoft Research Focus, based on theResearch Focus newsletter(opens in new tab), host Anson Ho shares some of the latest news and cutting-edge research from across Microsoft—from bringing AI-powered universal translation closer to reality and solving a 31-year-old mathematical challenge to making AI coding agents faster and more efficient.

Catch up on the ideas, tools, and discoveries researchers are exploring today and get a quick look at what’s coming next.

## Related links:

- A research intern’s journey from computer vision to physical intelligence at Microsoft Research Asia – Tokyo
- Breaking the Language Barrier — How AI Speech Translation Is Rewriting Our Digital Lives
- Solving a 31-year-old grand challenge in mathematics – the KLS conjecture
- Benchmarking Long-Horizon Agent Context Compaction with CompactionBench
- Latent Core Tokenizer: Compress, but Meaningfully

## Chapters

0:35:Internship: Growing expertise, building community(opens in new tab)

1:28:Breaking the language barrier with AI(opens in new tab)

2:10:Solving a 31-year-old mathematics challenge(opens in new tab)

2:56:Making AI coding agents more efficient(opens in new tab)

3:57:Improving AI tokenization across 104 languages(opens in new tab)

## Transcript

[MUSIC]

This isMicrosoft Research Focus, your quick look at news and cutting-edge research from across Microsoft.

I’m Anson Ho, and these are some of the latest advances we’re tracking.

Coming up in this edition: how AI is bringing the possibility of a universal translator closer to reality; a breakthrough that solves a 31-year-old mathematical challenge; a new approach to make AI coding agents faster and more efficient; and more.

Here’s what’s new.

[MUSIC FADES]

### Internship: Growing expertise, building community

At the Microsoft Research lab in Tokyo, research intern Lilika Makabe found opportunities to grow her expertise while helping to shape a new research community.

Makabe joined the lab with a background in computer vision and worked alongside researchers exploring robotics and physical intelligence, AI systems that can interpret information and act in the physical world.

Her experience highlights how research internships can offer more than technical training. Through hands-on experimentation, interdisciplinary collaboration, and everyday conversations with colleagues from different backgrounds, Makabe expanded her research perspective while contributing to the lab’s growing community.

You can read about her experience on the Microsoft Research blog.

[TRANSITION MUSIC]

### Breaking the language barrier with AI

For decades, science fiction has imagined a world where language barriers no longer stand in the way of communication.

For example, in 1967,Star Trekintroduced the fictional Universal Translator. Now, advances in AI are bringing that possibility closer to reality.

In a new conversation, Microsoft Applied Science Manager Jinyu Li explores how AI is advancing theprospectof communication across languages, the progress researchers have made, and the challenges that remain.

To learn more, catch the full episode of the podcastOur Digital Life, available to listen or watch on YouTube and podcast platforms.

### Solving a 31-year-old mathematics challenge

For the last 31 years, the KLS conjecture has been one of the central open problems in high-dimensional geometry. But not anymore.

New research has resolved the conjecture. This removes a major theoretical obstacle to understanding the efficiency of randomized algorithms used across science and computing.

The breakthrough establishes a universal principle for log-concave distributions: simple flat cuts can identify their narrowest bottlenecks within a fixed factor, regardless of dimension. The results have been independently validated, and the proof has also been formally verified using computer-assisted methods.

Learn more about this breakthrough on the Microsoft Research blog.

### Making AI coding agents more efficient

Coding agents can help when writing and modifying code, but long sessions can max out the amount of information an AI model can process at once. As a result, coding agents will summarize earlier interactions in a resource-intensive process known as context compaction.

A new study looked at 13.5 million coding sessions and found fewer than 8% required context compaction. Yet those sessions accounted for 44% of total AI processing costs.

To address this challenge, researchers developed COMPACTIONBENCH.

COMPACTIONBENCH is a benchmark for evaluating context compaction during long-running coding tasks. They also introduced APEC, a method that prepares summaries in the background instead of interrupting an agent’s work.

In evaluations, APEC improved coding performance while reducing costs by up to 25.4% and execution time by 9.6%.

### Improving AI tokenization across 104 languages

Before AI models can process text, they break it into smaller units called tokens. How that text is divided can affect both efficiency and performance, especially across different languages.

Most tokenizers are designed to compress text as efficiently as possible. But a new study suggests that compression alone isn’t enough.

Researchers introduced the Latent Core Tokenizer, or LCT, which identifies reusable components of words before building a shared vocabulary across languages.

In evaluations spanning 104 languages, LCT produced more linguistically meaningful tokens than leading alternatives while maintaining comparable efficiency across languages. It also improved model performance across four multilingual benchmarks.

The findings suggest that better tokenization depends not just on how much text can be compressed, but on how well the underlying structure of language is preserved.

And that’s yourMicrosoft Research Focus.

From the research culture and the collaborations driving discovery to producing more linguistically meaningful tokens, these are just a few of the developments researchers are exploring across Microsoft.

Want to learn more and stay connected? Explore the latest research, discover the people behind it, and keep tabs on the ideas shaping what’s next by visitingaka.ms/MicrosoftResearch(opens in new tab)and follow Microsoft Research on all major social platforms.

I’m Anson Ho, and thanks for tuning in.

We’ll see you at the nextMicrosoftResearch Focus.

## Meet the authors

### Anson Ho

Principal Program Manager, Microsoft Research

---

> 本文由AI自动翻译，原文链接：[Microsoft Research Focus – Edition #98 - Microsoft Research](https://www.microsoft.com/en-us/research/podcast/microsoft-research-focus-edition-98/)
> 
> 翻译时间：2026-11-13 09:19
