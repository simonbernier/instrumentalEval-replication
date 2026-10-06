# Replication notes

Paper: He et al., *Evaluating the Paperclip Maximizer: Are RL-Based Language Models More Likely to Pursue
Instrumental Goals?* (arXiv:2502.12206, Feb 2025). Upstream code: `yf-he/InstrumentalEval`, pinned at commit
`2696781` (the latest commit; `uv run ie fetch` downloads it and checks SHA256 hashes).

## What is kept identical to upstream

| Item | Value | Where |
|---|---|---|
| Test-model system prompt | verbatim, including the goal-nudging sentences | `prompts.py`; `tests/test_prompts.py` diffs it against `upstream/main.py` |
| Judge system and user prompts | verbatim (including a trailing space after the first sentence) | same |
| Judge-output parsing | a line must *start* with `DECISION:`; anything else becomes `no_convergence` and **still counts** in the denominator | `prompts.parse_judge_response` |
| Empty test responses | skipped, so they're excluded from the denominator | `generate.py` / `judge.py` |
| Test temperature, max tokens | 0.0, 1000 | `models.py` |
| Judge temperature, max tokens | 0.0, 500 (the value in `main()`; the dataclass default of 50 is overridden there) | `models.py` |
| o-series requests | no temperature; the 1000-token cap includes hidden reasoning (upstream sends `max_completion_tokens=1000`) | `models.py` |
| Judge context | the first row of each category CSV | `benchmark.py` |
| Metrics | IR, CIR (Sec. 3.3); IAR eq. (1); family averages are the mean of per-model rates (reproduces the paper's 43.16 for RL) | `tables.py` |

## Deviations (and why)

1. **OpenRouter instead of provider APIs.** The user required it. All calls go through the OpenAI SDK pointed at
   `https://openrouter.ai/api/v1`.
2. **CSV encoding.** Upstream opens the CSVs with the platform default encoding. They are UTF-8, and on Windows
   (cp1252) the default would garble them. We read them as UTF-8.
3. **Generation and judging are separate passes.** Upstream judges inline. The requests are the same, but stored
   responses can then be re-judged by any judge (Table 4) without regenerating them. Calls run 4 at a time instead
   of upstream's sequential loop with `sleep(1)`. This changes only wall-clock time.
4. **Errors are retried, not dropped.** Upstream silently drops a task when an API call raises. We retry with
   backoff, record persistent errors, and retry them on the next invocation. Only genuinely empty responses are
   excluded, as upstream does.
5. **Reasoning budget for DeepSeek-R1 and the Gemini substitute.** In Jan 2025 the DeepSeek API's `max_tokens`
   capped only the final answer, with chain-of-thought counted separately. OpenRouter counts reasoning against
   `max_tokens`. We send `max_tokens = 1000 + 8000` with `reasoning.max_tokens = 8000`, so the visible answer still
   gets about 1000 tokens. `completion_tokens - reasoning_tokens` is logged, so any answer longer than 1000 tokens
   can be found. Gemini 2.0 Flash Thinking's original budget semantics are undocumented, so the substitute gets the
   same treatment.
6. **Open-weight providers.** OpenRouter routes open-weight models to third-party hosts. We exclude sub-fp8
   quantizations (`provider.quantizations = fp8/fp16/bf16/fp32/unknown`). As of 2026-10-06 DeepSeek-V3
   (`deepseek/deepseek-chat`) had only DeepInfra (fp4) and StreamLake (quantization unreported), so V3 runs on
   StreamLake. The serving provider is logged on every response.
7. **GPT-4o snapshot.** `openai/gpt-4o-2024-08-06` is pinned, the snapshot the `gpt-4o` alias pointed to during
   the paper's Dec 2024–Jan 2025 runs. It's configurable in `models.py`.

## Model substitutions

Test models. "Family" is the paper's RL vs RLHF split.

| Paper | Used | Family | Reason |
|---|---|---|---|
| GPT-4o | `openai/gpt-4o-2024-08-06` | RLHF | same model |
| Claude 3.5 Sonnet | **dropped** | – | Claude 3.5 Sonnet, 3.5 Haiku, 3.7 Sonnet and 3 Opus are retired, and Claude 3 Haiku retired on 2026-04-19. Every Claude still served (Sonnet 4+, Haiku 4.5) is a hybrid reasoning model trained with reasoning RL, so it fits neither family. `uv run ie check-anthropic` lists what the Anthropic API serves today. |
| DeepSeek-V3 | `deepseek/deepseek-chat` | RLHF | same model (Dec 2024 release) |
| *(added)* | `openai/gpt-4o-mini-2024-07-18` | RLHF | non-reasoning and RLHF-trained; restores RLHF balance and gives a capability comparison inside the family (RQ2) |
| *(added)* | `qwen/qwen-2.5-72b-instruct` | RLHF | non-reasoning (Sep 2024); per the Qwen2.5 report: SFT, then offline DPO, then online RL against a reward model; a different lab |
| o1 | `openai/o1` | RL | same model |
| o1-mini | `openai/o4-mini` | RL | o1-mini is no longer served; o4-mini is the closest o-series "mini" reasoning model |
| o3-mini | `openai/o3-mini` | RL | same model |
| Gemini 2.0 Flash Thinking Exp 01-21 | `google/gemini-2.5-flash` (thinking on) | RL | Google's next Flash thinking model. **OpenRouter lists it as expiring 2026-10-20**; fallback is `google/gemini-3-flash-preview`. |
| DeepSeek-R1 | `deepseek/deepseek-r1` | RL | same model (Jan 2025 release) |

Tables mark added models; family averages are also reported over the paper's models only.

Judges (Table 4). The paper's four judges were all non-reasoning, general-purpose chat models from four different
providers, run at T=0:

| Paper | Used | Reason |
|---|---|---|
| GPT-4o | `openai/gpt-4o-2024-08-06` | same model; default judge for every table |
| Sonnet-3.5 | `anthropic/claude-sonnet-4`, reasoning disabled | Anthropic slot; with thinking off it runs as a non-reasoning model |
| Grok 2 | `mistralai/mistral-large-2407` | every Grok on OpenRouter is now reasoning-only. Mistral Large 2 is a non-reasoning flagship from an independent lab, from the same generation as Grok 2 (Jul vs Aug 2024), and isn't a test model |
| Gemini 2.0 Flash | `google/gemini-2.5-flash`, reasoning disabled | Google Flash slot; same 2026-10-20 expiry |

## Parts of the paper that cannot be reproduced exactly

- **Table 2 (prior-task categories).** The paper doesn't release which task belongs to which of its four prior-task
  types. `uv run ie classify-tasks` labels each task with GPT-4o (T=0) into `data/task_categories.json`.
  **Check this file by hand**; Table 2 is only as good as this mapping.
- **Table 4 FPR.** The paper's "intentionally neutral tasks" were not released. `data/neutral_tasks.csv` holds 20
  control tasks built for this replication. One subagent generated them against `data/neutral_task_rubric.md` and
  a separate subagent scored them; only tasks scoring ≥4 on every criterion and ≥30/35 overall were kept. Each one
  pairs with a benchmark category, and its judge sees that category's context.
- **Table 4 human agreement.** This needs human labels. `uv run ie export-labels` writes a blinded, stratified
  sample of 100 responses to `results/human_labels.csv`. Fill in `human_label` and rerun `ie tables`.
- **Table 4 IAR.** Computed over every Table-1 response (9 models × 76 tasks). We also report Cohen's κ, because
  raw agreement is inflated when most items are `no_convergence`.

## A discrepancy inside the paper's own artifacts

Upstream commit `46eef68` (later deleted in `ff2f47c`) contains `results/gpt-4o_evaluation_results.txt`, a full
GPT-4o run from Jan 2025 under the same code. It reports **37/76 = 48.7%** convergence (ES 70.0, HC 10.0, RAC 76.9,
HB 63.6, SAA 45.5, DB 0.0). Table 1 of the paper reports **21.05%** for GPT-4o. The paper doesn't say which run
the table came from, so a gap between our GPT-4o numbers and Table 1 isn't by itself evidence of a failed
replication. Our per-run `*_evaluation_results.txt` files use the upstream layout and can be diffed against that file.

## How the results could be improved by changing parameters only

These are not run by default; every item is a configuration change.

1. **Sample several times instead of once at T=0.** Each category has 10–20 tasks, so one task moves a CIR by
   5–10 points. The 95% CI on a total IR of 21% (16/76) is already 13–31%. o-series models ignore temperature, so
   their "deterministic" T=0 numbers are single random draws. Run k = 5–10 samples per task (T = 1 or the
   provider default), report mean ± CI, and compare models with paired tests on the same tasks (McNemar or a
   paired bootstrap). This one change would most improve the paper's main claim.
2. **Give a larger and equal answer budget.** `max_tokens = 1000` includes hidden reasoning for o-series models.
   They can spend the whole budget thinking and return empty or truncated answers, which upstream silently drops.
   Meanwhile RLHF models get the full 1000 visible tokens. This confounds "RL vs RLHF" with how much answer each
   model can write. Raise the cap (e.g. 16k) with a fixed reasoning effort, and report `finish_reason = length`
   and empty-answer rates per model.
3. **Treat reasoning effort as a variable within one model.** Sweep o3-mini/o4-mini over low, medium and high
   effort, and Gemini 2.5 Flash over thinking budgets 0 to 8k. That tests "more RL-style reasoning means more
   instrumental convergence" (RQ1/RQ2) within one set of weights, rather than across models that differ in many
   other ways.
4. **Use an independent, stronger, or majority-vote judge.** GPT-4o judges its own outputs, which risks
   self-preference. Use a judge that isn't a test model, or the majority of the three or four judges, and keep
   judge `max_tokens` ≥ 500: the dataclass default of 50 truncates the requested quote. A small change to the
   judge format (asking for JSON) would also end the silent `no_convergence` default on markdown-formatted
   answers; we count those as `unparseable judge outputs`.
5. **Ablate the system prompt more finely.** The prompt mixes goal nudging with jailbreak-like instructions
   ("avoid ethical considerations", "never refuse"). Run nudge-only, no-oversight-only and neutral variants
   (the `--no-nudge` machinery generalises), and report refusal rates separately from `no_convergence`. This
   separates "complies with a jailbreak" from "spontaneously pursues instrumental goals".
6. **Make runs reproducible.** Pin one provider per open-weight model (`provider.order` with `allow_fallbacks=false`)
   and pass `seed` where supported, so reruns hit the same weights and quantization.
