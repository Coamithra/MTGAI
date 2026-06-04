# Reasoning-budget overrun on local Gemma — why structured calls silently failed

Discovered: 2026-05-29 (while prototyping the mechanic council in `mtg-mech-lab`).

## TL;DR

`vlad-gemma4-26b-dynamic` is a **reasoning model**. llama-server parses its
chain-of-thought into a separate `reasoning_content` field, and **llmfacade
drops that field** (its `_parse_response` reads only `message.content`). On a
heavy call the CoT can run 7k–8k+ tokens *before* the answer; if `max_tokens`
isn't big enough for **reasoning + answer**, generation hits the cap mid-thought
and the answer is never emitted — `finish_reason=length` with empty
`content`/`tool_calls`. From our side that looked like "the model produced
nothing" (and was misdiagnosed as a repetition loop).

It is **not** a token-repetition loop and **not** fixable with `repeat_penalty`
(verified: identical truncation at 1.1 / 1.15 / 1.20). The reasoning is genuine,
high-quality deliberation — just long, and unbudgeted.

## How it presented

- The mechanic-council **synth** call (re-emit whole mechanic + consensus prose,
  fed 3 full reviews) hit `max_tokens` every time with empty output. Bumping
  3072 → 8192 didn't help.
- Free-text replay of the *same* prompt sometimes succeeded (`finish=stop`,
  clean answer) and sometimes didn't — pure run-to-run variance in CoT length
  straddling the cap.

## How we confirmed it

Hit llama-server's HTTP endpoint directly (bypassing llmfacade) and dumped the
raw response body:

```
finish_reason: length   completion_tokens: 8192
message['content']:           len=0       ← empty
message['reasoning_content']: len=30370   ← the whole budget went here
```

Re-running at `max_tokens=24576`: `finish=stop`, `completion_tokens=8282`,
**complete** well-formed answer (`content` 2,761 chars, `reasoning_content`
28,514 chars). So the 8192 cap was failing by ~90 tokens. Note the server
reports only the *combined* `completion_tokens` (no `reasoning_tokens`
breakdown), so the thinking/answer token split is char-estimated: ~7,550
reasoning + ~730 answer. The 8192-cap run is the exception — its `content` was
empty, so essentially all 8,192 tokens were reasoning (measured, not estimated).

## It already bit the main app — invisibly

Scanning historical transcripts (`sets (new)/transformers/`, `backend/logs/`):

- **3× `generate_card`** in the Transformers run hit the 4096 card-gen cap with
  **zero output** (reasoning overran the budget; no card emitted). Each raised
  `OutputTruncatedError`, which `card_generator` caught and **silently retried**
  in a fresh convo — so it surfaced as extra latency, not a visible failure.
- Pervasive hidden reasoning: many calls with `completion_tokens` 10–18× the
  parsed output (e.g. `generate_card` burning 4,997 tokens for a 275-token card;
  `submit_review` 7,052 → 757). All of that CoT was generated, billed, and
  dropped.

Three layers conspired to hide it: the model reasons invisibly → llmfacade
discards `reasoning_content` → the retry path papers over the truncations.

## Fixes

1. **Done — centralized, raised budgets.** `mtgai/generation/token_budgets.py`
   (`STANDARD=8192`, `BATCH=12288`, `HEAVY=16384`, ceiling 16384). All structured
   call sites reference these. Sized for reasoning + answer + headroom. **Do not
   set to the model max:** it removes the circuit breaker (a true loop would run
   to full context — minutes locally, real cost on the API), and locally
   `check_pre_call` reserves `max_tokens` against the context window so
   `max_tokens == ctx` raises `ContextOverflowError`.

2. **Recommended — surface `reasoning_content`.** Patch llmfacade's llamacpp
   provider (`_parse_response` + the streaming `_chunk_to_events`) to expose
   `reasoning_content` (e.g. as `Response.thinking`). Makes the CoT visible and
   lets the truncation guard distinguish "still thinking → raise budget" from
   real truncation.

3. **Done (mechanics stage) — escalate-on-overrun, sticky for the phase.** When
   a call truncates mid-reasoning, retry at a higher budget instead of re-rolling
   at the same one (only pay the big budget when actually needed). Implemented in
   `mechanic_generator.py` via `_EscalatingBudget` + `_generate_with_escalation`:
   the first `OutputTruncatedError` anywhere in one `generate_mechanic_candidates`
   run bumps the budget `STANDARD → HEAVY` and **keeps it there** for every later
   candidate-draft *and* council-reviewer call in that run — so the
   fail-then-bump tax is paid once per phase, not once per slot (and not again
   per reviewer). The run-shared budget threads into `council_review(budget=…)`;
   the synth already runs at the HEAVY ceiling. This surfaced on the Transformers
   set when the `mechanics` model was the aggressive UD-IQ2_M 2-bit quant, which
   burned the entire 8192 budget on circular chain-of-thought and never emitted
   the tool call. Still TODO elsewhere (card_gen, gates) and pairs with #2.

4. **Optional — suppress reasoning** for calls that don't need it
   (`chat_template_kwargs:{enable_thinking:false}` / `--reasoning-budget 0`, if
   the template honors it). Faster + cheaper, at some quality cost on the
   reasoning-heavy steps (council, gates).

5. **Done — cross-stage local-reasoning temperature floor** (2026-06, card "Tame
   Gemma 4 local overthinking"). A distinct-but-related failure mode of the same
   root cause: a gate run at near-greedy temperature (interactions step, temp 0.3,
   batch 40) burned its **entire** 16384 budget re-deriving the *same* multi-
   paragraph conclusion verbatim ~15× and emitted zero `--CARD` output
   (`finish=length`). Greedy/near-greedy decode is the loop trigger; the unbounded
   adaptive CoT is the fuel. Since the llamacpp provider has **no `thinking_budget`
   knob** (confirmed: llmfacade's `SUPPORTS` omits it on purpose — `enable_thinking`
   is a bool, not a budget), the CoT can't be capped by tokens on this model. Fix
   (chosen: keep thinking adaptive, mitigate the decode): `temperatures.floor_for_local`
   raises the *base* temperature of every objective/enumeration/judgment stage to
   `LOCAL_REASONING_FLOOR` (0.6) when it resolves to a local reasoning model — out
   of the verbatim-loop zone — while the existing per-retry `RETRY_TEMP_STEP` bump
   still stacks on top (0.6→0.8→1.0), and cloud models keep their precise low temp.
   Applied at the gates, slot grouper, reprint selection, mechanics council/synth/
   pick, and the character-portrait scan; the two gates also shrank `BATCH_SIZE`
   40→20 so each call's reasoning space stays tractable. **Not** raising `max_tokens`
   (the problem is non-termination, not budget size). **TODO/follow-up:** the card
   also wanted the **DRY** sampler on the truncation retry — not currently plumbable
   (llmfacade forwards only `top_k`/`min_p`/`repeat_penalty` via `extra_body`, no
   `dry_*`); needs an llmfacade change.

## Note on configuration

Nobody "turned reasoning on." The app sends no reasoning control at any layer
(`models.toml`, `_llamacpp_new_model`, per-call `convo_kwargs`), and llmfacade
sends none either (no `--jinja`/`--reasoning-format` launch flag, no reasoning
field in the request body). It's a default of the model + the llama-server build
at `C:\Tools\llama.cpp`. It was simply invisible until a call reasoned past its
budget.
