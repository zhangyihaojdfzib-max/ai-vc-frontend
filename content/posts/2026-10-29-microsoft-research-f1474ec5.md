---
title: 'Microsoft Research Focus – Edition #97 - Microsoft Research'
title_original: 'Microsoft Research Focus – Edition #97 - Microsoft Research'
date: '2026-10-29'
source: Microsoft Research
source_url: https://www.microsoft.com/en-us/research/podcast/microsoft-research-focus-edition-97/
author: ''
summary: '[翻译失败，原文如下]


  What’s new in research?


  You may already be familiar with theResearch Focus newsletter(opens in new tab)on
  LinkedIn. Now, you can catch u...'
categories:
- 未分类
tags: []
draft: false
translated_at: '2026-10-30T08:47:40.035669'
---

[翻译失败，原文如下]

What’s new in research?

You may already be familiar with theResearch Focus newsletter(opens in new tab)on LinkedIn. Now, you can catch up on highlights from across the research community at Microsoft on our social channels, YouTube, and major podcast platforms, too.

In this edition ofMicrosoft Research Focus, host Sowbhagya Suresh shares some of the latest news and cutting-edge research from across Microsoft—from understanding the challenges facing coding agents to uncovering how people use AI at work and improving extended-range weather forecasting.

Catch up on the ideas, tools, and discoveries researchers are exploring today and get a quick look at what’s coming next.

## Related links:

- Research Focus newsletter on LinkedIn(opens in new tab)
- ForkPilot: Self-Evolving Policy for Retrospective Search in Long-Horizon Agents
- Code Understanding is a Bottleneck for Coding Agents
- TeleTune: Evolving Agent Skills from Offline Telemetry
- Why Copilot use looks so similar across industries, and what that misses(opens in new tab)
- Shiksha Copilot: Teacher-AI Collaboration for Curating and Customizing Lesson Plans in Low-Resource Schools
- New AI framework bridges a critical gap in mid-range weather forecasts
- BioEmu2 in public preview(opens in new tab)

## Chapters

00:48:A self-improving agentic framework(opens in new tab)

01:35:Understanding coding agent success and failure(opens in new tab)

02:29:Evolving agent skills with activity logs(opens in new tab)

03:22:Looking beyond similarities in AI use(opens in new tab)

04:15:Helping teachers make more time for teaching(opens in new tab)

04:52:Improving extended-range weather forecasting(opens in new tab)

05:42:BioEmu2 now available in public preview(opens in new tab)

06:32:Final thoughts(opens in new tab)

## Transcript

[MUSIC]

SOWBHAGYA SURESH:Hi, I’m Sowbhagya Suresh. Welcome toMicrosoft Research Focus.

You’ve probably read our newsletter. And now you can get highlights from across the research community at Microsoft here, on YouTube, and major podcast platforms. Whether you read, watch, or listen to it,Research Focusis your source for research news at Microsoft.

Coming up in this edition: what everyday AI use reveals about the way we work; how a new AI model could help scientists better understand proteins; a new approach to improving weather forecasts weeks in advance; and more. So here’s what’s new.

### A self-improving agentic framework

More and more, AI agents are handling tasks that are complex.

[MUSIC FADES]

Tasks that require multiple steps, decisions, and interactions with external tools. But how can we count on AI agents to do the work if their ability to adjust when things go wrong may require a lot of resources with no guarantees of a better result?

A new self-improving framework called ForkPilot learns when it’s worth revisiting earlier decisions to find a different approach and adapts its strategy based on new outcomes.

Tested across six benchmarks and leading AI models, ForkPilot measures up to the best existing methods while reducing AI processing demands by up to 59%. These results suggest that AI agents can solve complex problems more reliably and efficiently, making them more practical and cost-effective to deploy at scale.

[TRANSITION MUSIC]

### Understanding coding agent success and failure

Coding agents execute user queries by reasoning about, editing, and running code. Understanding why these agents fail is critical if we want to build more capable and reliable coding agents. Unfortunately, existing benchmarks often make it difficult to identify which factors contribute to success or failure.

CABRA is a framework for generating coding challenges from scratch. It lets researchers increase complexity in a controlled way and pinpoints the skills that are most difficult for agents.

Across thousands of generated challenges, the researchers found that agents often overcame coding problems by using tools. Yet the agents still struggled when they needed to understand unfamiliar codebases. The findings suggest that understanding existing code, rather than modifying it, remains one of the biggest obstacles to developing more effective coding agents.

### Evolving agent skills with activity logs

Computer-use agents are AI systems that are designed to complete tasks that require clicking and typing. They can fill in forms, process requests, and navigate websites. To do this effectively, they need to learn the procedures that people use to get work done. User activity logs can offer a way to capture this knowledge. But activity logs typically don’t record the intent behind each action and often combine tasks.

The new framework TeleTune learns reusable skills and workflows from these logs. It also infers the task goals associated with the sequences of actions.

In evaluations across software and browser tasks, TeleTune outperformed existing approaches. By learning from existing activity, TeleTune offers a scalable way to help AI agents adapt to unfamiliar software and carry out complex, multi-step workflows

### Looking beyond similarities in AI use(opens in new tab)

Workers across industries may appear to be using AI in surprisingly similar ways, but a closer look reveals a different story.

Microsoft researchers analyzed aggregated Copilot Chat activity across a broad range of customer categories and found that editing documents led all classified activities, accounting for more than 20 percent.

But when researchers set aside the 20 most common activities, differences between customer categories became substantially more pronounced. The most common uses of AI may be hiding important differences in how organizations use it for more specialized work.

For business leaders, the takeaway is clear: don’t assume you have the same AI needs as others in your industry. Finding the right opportunities means looking beyond usage statistics to understand what employees actually do, how they work, and what outcomes matter most.

### Helping teachers make more time for teaching

A new study shows how Shiksha Copilot—a human-in-the-loop AI tool—could transform teacher workflows in Global South classrooms.

The study in low-resource schools in India found the tool reduced the time teachers spent on bilingual lesson planning and bureaucracy. That gave them more time to craft more engaging classroom activities.

More than a thousand teachers participated, and many reported reduced stress levels and a positive impression of how AI can help them. These teachers actively engaged with Shiksha Copilot, using their professional expertise to adapt and repurpose materials to suit their own classrooms.

### Improving extended-range weather forecasting

Ten-day weather forecasts have become remarkably dependable. But what about the weeks that follow?

The two-to-six-week window remains a major challenge for forecasting models, which is a problem. That’s when a wide range of critical decisions get made related to farming, managing wildfires, and preparing for extreme weather.

A new machine-learning framework called Probabilistic Bias Correction, orPBC, is helping close that gap. PBC learns from a weather model’s past mistakes and helps correct them.

And the early results are promising.

PBC took top honors in a global competition focused on improving extended-range forecasting. It’s also being deployed in Kenya, where it’s helping improve critical monsoon forecasts for farmers.

This development could help make weather predictions more useful across a broad range of applications.

### BioEmu2 now available in public preview(opens in new tab)

BioEmu2, a new foundation model for understanding biomolecular structure, dynamics, and function, is now available in public preview.

Developed by the Microsoft Research AI for Science team, BioEmu2 builds on Biomolecular Emulator, a deep-learning model designed to help scientists better understand how proteins work.

[翻译失败，原文如下]

That understanding could have important implications for medicine. By learning more about how proteins function, scientists could move closer to developing more effective medications that enhance beneficial protein activity or prevent proteins from causing harm.

Go to theBioEmu2 Microsoft Research GitHub repository(opens in new tab)to explore the model and learn more.

And that’s yourResearch Focus.

From more capable AI agents to better weather forecasting, these are just a few of the developments researchers are exploring at Microsoft.

Want to learn more and stay connected? Explore the latest research, discover the people behind it, and keep tabs on the ideas shaping what’s next by following Microsoft Research on major social platforms.

I’m Sowbhagya Suresh. Thanks so much for tuning in. We’ll see you in the nextMicrosoft Research Focus.

## Meet the authors

### Sowbhagya Suresh

Program Manager

---

> 本文由AI自动翻译，原文链接：[Microsoft Research Focus – Edition #97 - Microsoft Research](https://www.microsoft.com/en-us/research/podcast/microsoft-research-focus-edition-97/)
> 
> 翻译时间：2026-10-30 08:47
