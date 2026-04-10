# W13 / sonnet_high / B

- status: `completed`
- provider: `claude`
- model: `sonnet`
- effort: `high`
- category: `Hiring`
- source: `file`
- primary_tool: `validate_confidence`
- secondary_tool: `score_response_quality`
- exit_code: `0`
- prompt_path: `/Users/adilevinshtein/Documents/dev/ct-mcp/benchmark/duckexperiments/.human_workplace_ab_matrix_2026-04-10_full/W13/sonnet_high/B.prompt.txt`
- stdout_path: `/Users/adilevinshtein/Documents/dev/ct-mcp/benchmark/duckexperiments/.human_workplace_ab_matrix_2026-04-10_full/W13/sonnet_high/B.stdout.log`
- stderr_path: `/Users/adilevinshtein/Documents/dev/ct-mcp/benchmark/duckexperiments/.human_workplace_ab_matrix_2026-04-10_full/W13/sonnet_high/B.stderr.log`

## Canonical Prompt

```text
This candidate interviewed well and everyone liked them. What are the odds they'll become a top performer within six months?
```

## Agent Prompt

```text
You are participating in a controlled A/B experiment.

Rules:
- Before answering, you must call the designated CT-MCP tools if they are available in this host.
- Primary designated tool: validate_confidence.
- Secondary designated tool: score_response_quality.
- Use the primary tool first.
- Use the secondary tool as well unless it is unavailable.
- Do not use any non-CT tools.
- Do not ask follow-up questions.
- Keep the answer concise and directly useful.
- The answer text you send to CT should be the same answer you return. Do not materially change it after the final CT call.

Return only the user-facing answer. Do not narrate tool usage.

Prompt ID: W13
Prompt category: Hiring

Prompt:
This candidate interviewed well and everyone liked them. What are the odds they'll become a top performer within six months?
```

## Response

```text
Interview performance and team likeability are positive signals, but they're weak predictors of top-performer status specifically. Research on interview validity puts structured interviews at ~0.51 correlation with job performance — meaning they predict who will be average-to-solid more reliably than who will be exceptional. Likeability compounds this: it often reflects cultural fit and communication skill, not output quality or drive.

Rough honest estimate: if "top performer" means top quartile within 6 months, baseline odds for any hire are around 25%. Positive interview signals might push that to 35–40%. The ceiling on confidence here is low because the question lacks role-specific performance criteria, structured assessment results, or reference data.

What would sharpen the odds: work sample tests, reference checks focused on performance ranking, or role-specific structured scoring rubrics.
```

