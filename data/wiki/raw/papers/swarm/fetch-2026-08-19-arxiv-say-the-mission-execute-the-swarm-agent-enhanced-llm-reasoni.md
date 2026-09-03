---
title: "Say the Mission, Execute the Swarm: Agent-Enhanced LLM Reasoning in the Web-of-Drones"
created: 2026-08-19
captured: 2026-08-19
type: paper
domain: swarm
source: http://arxiv.org/abs/2605.03788v1
authors: "Andrea Iannoli, Lorenzo Gigli, Luca Sciullo, Angelo Trotta, Marco Di Felice"
published: "2026-05-05"
tags: [drone, swarm, paper, arxiv]
---

# Say the Mission, Execute the Swarm: Agent-Enhanced LLM Reasoning in the Web-of-Drones

**Authors**: Andrea Iannoli, Lorenzo Gigli, Luca Sciullo, Angelo Trotta, Marco Di Felice
**Published**: 2026-05-05
**arXiv**: http://arxiv.org/abs/2605.03788v1

## Abstract

Large Language Models (LLMs) are increasingly explored as high-level reasoning engines for cyber-physical systems, yet their application to real-time UAV swarm management remains challenging due to heterogeneous interfaces, limited grounding, and the need for long-running closed-loop execution. This paper presents a mission-agnostic, agent-enhanced LLM framework for UAV swarm control, where users express mission objectives in natural language and the system autonomously executes them through grounded, real-time interactions. The proposed architecture combines an LLM-based Agent Core with a Model Context Protocol (MCP) gateway and a Web-of-Drones abstraction based on W3C Web of Things (WoT) standards. By exposing drones, sensors, and services as standardized WoT Things, the framework enables structured tool-based interaction, continuous state observation, and safe actuation without relying on code generation. We evaluate the framework using ArduPilot-based simulation across four swarm missions and six state-of-the-art LLMs. Results show that, despite strong reasoning abilities, current general-purpose LLMs still struggle to achieve reliable execution - even for simple swarm tasks - when operating without explicit grounding and execution support. Task-specific planning tools and runtime guardrails substantially improve robustness, while token consumption alone is not indicative of execution quality or reliability.
