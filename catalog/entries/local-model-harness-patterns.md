---
name: local-model-harness-patterns
title: Local Model Harness Patterns
category: agent-pattern
summary: "Harness design patterns for running local LLMs as coding agents — subagent delegation, reasoning-level routing, loop detection with context cleanup, and speculative decoding"
tags: [local-llm, harness, subagents, loop-detection, llama-cpp]
workflows: []
reviewed: 2026-09-16
acquired: 2026-09-16
license: ""
security_flags: []
supersedes: []
overlaps: []
---

## What it says

Community-reported patterns from a 30-day experience running Qwen 3.8-27B locally as a coding agent (hardware: 5070 Ti + 4070 Super, Unsloth Q4_K_XL quant, 73-95 t/s generation). The source describes harness design choices found necessary to make a local reasoning model usable as an agentic coding backend, covering subagent delegation, reasoning-level configuration, loop detection, context cleanup, speculative decoding, and cache tuning.

## Key takeaways

- Subagents are described as mandatory for local model harnesses: without delegating sub-tasks to subagents, reasoning tokens from the main agent loop were reported to fill roughly 50% of the context window.
- Subagents need configurable reasoning levels: basic tasks (find, summarize, explain) were run without reasoning enabled, reserving reasoning for tasks that need it.
- Loop detection is described as essential: at 100k+ context, a bad tool call could cause the model to spam and loop. Naive detection strategies (time-based, count-based) were reported to fail.
- When loop detection triggers, the bad tool call(s) are deleted from context rather than merely halted, to prevent the malformed call from continuing to influence subsequent generations.
- Speculative decoding (MTP, n-gram, dflash2+ngram methods) was reported to provide roughly 20% speed gains.
- Cache settings require tuning: default llama.cpp settings were reported to cause full prompt reprocessing even on simple inputs, rather than reusing cached context.

## What to adopt

- Route "basic" tool-call-shaped tasks (find, summarize, explain) through subagents configured with reasoning disabled; reserve reasoning-enabled paths for tasks that require multi-step inference.
- Implement loop detection beyond simple time or count thresholds — the source notes both approaches failed to catch the loop pattern reliably at long context (100k+ tokens).
- On loop-detection trigger, remove the offending bad tool call(s) from the context window rather than just stopping generation, so the malformed call doesn't persist as conditioning for future turns.
- Evaluate speculative decoding variants (MTP, n-gram, dflash2+ngram) against a llama.cpp-based serving setup for throughput gains.
- Review llama.cpp cache configuration rather than relying on defaults, since default settings were observed to trigger full prompt reprocessing on simple inputs.

## Security

n/a — community knowledge, no code artifact.
