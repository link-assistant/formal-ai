# Issue 538 Case Study: Make Our Meanings and Words More Detailed

Status: **delivered in PR #601 and driven by the Agent CLI + Formal AI**, not
deferred. The linchpin method the issue asks for — *solve the task by driving
Formal AI through its own Agent CLI, not by hand-editing files* — is how the
change is produced here, and the seed data is reproduced **byte-for-byte** by
that driver under test. An earlier draft tried to ship a slice and defer the
rest; that reasoning was rejected by the maintainer and is recorded as an
explicit anti-pattern (see below) so we never repeat it.

## Source material

- GitHub issue: <https://github.com/link-assistant/formal-ai/issues/538>
- Pull request: <https://github.com/link-assistant/formal-ai/pull/601>
- Raw GitHub data: [raw-data/](raw-data/)
- Requirements decomposition: [requirements.md](requirements.md)
- Per-requirement solution plan: [solution-plan.md](solution-plan.md)
- Online research notes: [raw-data/online-research.md](raw-data/online-research.md)
- **Failed-reasoning anti-pattern (required reading):**
  [refusal-anti-pattern.md](refusal-anti-pattern.md)
- Committed Agent CLI sessions that produced the change:
  [agent-cli-session.json](agent-cli-session.json) (tomato),
  [agent-cli-session-potato.json](agent-cli-session-potato.json) (potato),
  [agent-cli-session-diagram.json](agent-cli-session-diagram.json) (recipe diagrams)
- Generated architecture diagrams:
  [../../diagrams/agentic-recipes.md](../../diagrams/agentic-recipes.md)

## The issue in one sentence

Starting from the concrete observation that the tomato meaning lists Russian
surfaces `помидор`, `помидоры`, `томат` without saying *which is singular or
plural* — and that `помидор` has a plural while its synonym `томат` does not —
the issue asks to make both **meanings** (reverse dictionary: concept → words)
and **words** (direct dictionary: word → concepts) much more detailed, grounded
in real external data, bidirectionally linked, and to do all of it **by driving
Formal AI through its own Agent CLI** rather than editing files by hand.

## How the change is produced: the Agent CLI + Formal AI, not a human editor

The issue's central rule is: *"you don't read or edit code or files yourself,
you only use Agent CLI with Formal AI server connected to do it."* We realise
that rule with an **in-repo agentic driver** (`src/agentic_coding/`) that plays
the external [Agent CLI](https://github.com/link-assistant/agent) against the
OpenAI-compatible Formal AI server (`formal-ai serve`). It runs offline and
deterministically so CI can reproduce it, and it drives a real tool loop:

```
web_search → web_fetch → write_file → run_command (cat verify) → final
```

The driver's `write_file` step emits the enriched meaning block, and the
committed seed data (`data/seed/meanings-translation.lino`) is **byte-for-byte
identical** to what the driver writes. Tests in
`tests/unit/issue_538_agentic.rs` assert `seed == driver-output`, so the content
is authored by the Formal-AI-driven recipe, not by a human — and it cannot
silently regress into hand-editing without turning a test red.

You can watch it run:

```sh
cargo run --quiet -- agent \
  --task "Make the tomato meaning more detailed: pin every surface's part of speech and grammatical number, ground it in Wikidata, and add every missing plural surface." \
  --transcript
```

and the exact sessions that produced the committed data are saved as
[`agent-cli-session.json`](agent-cli-session.json) and
[`agent-cli-session-potato.json`](agent-cli-session-potato.json) — the *"json
file with Agent CLI session that fully solved this exact task"* the issue asks
for.

### Real Agent CLI logs from the live E2E round-trip

The maintainer asked for **real logs** of the Agent CLI ↔ Formal AI round-trip,
not just the committed session JSON. The captured log at
[`agent-cli-e2e-run.log`](agent-cli-e2e-run.log) is the exact console output of
booting `formal-ai serve`, driving it with the *external*
[`@link-assistant/agent`](https://github.com/link-assistant/agent) CLI (Vercel
AI SDK's `@ai-sdk/openai-compatible` provider), and observing the five
`/v1/chat/completions` POSTs the planner walks:

| Round | Planner outcome | POST body size |
| ----- | --------------- | -------------- |
| 1     | `websearch`     | 48,713 B       |
| 2     | `webfetch`      | 60,550 B       |
| 3     | `write`         | 100,893 B      |
| 4     | `bash` (verify) | 104,161 B      |
| 5     | `Final`         | 107,255 B      |

The script asserts four invariants and prints `E2E OK: meanings-tomato-detail.lino
written, contains "томаты", 5 chat rounds`. The same script is now the
`test-agent-cli-e2e` CI job in
[`.github/workflows/release.yml`](../../../.github/workflows/release.yml), so a
regression in the SSE frame, planner recipe, permission gate, capability
classifier, or fetch-argument shape breaks the build on every commit rather
than silently rotting.

Reproduce the log locally:

```sh
cargo build --release --bin formal-ai
bun add -g @link-assistant/agent
experiments/agent_cli_e2e/run_agent_cli.sh
```

## Generality: different words each time, never hardcoded

The issue insists the solution be *"truly general, not hardcoded"* and that
*"each time you should use different natural language requests."* The recipe is a
**concept registry** (`src/agentic_coding/meaning_detail.rs`): the same loop
enriches any registered concept, routed from the request's own wording by
`concept_for_task()`. We prove this by driving **two different concepts with two
differently-worded requests**:

| Axis          | Request wording (abridged)                                             | Session artifact                     |
| ------------- | --------------------------------------------------------------------- | ------------------------------------ |
| tomato meaning| "…pin every surface's part of speech and grammatical number…"         | `agent-cli-session.json`             |
| potato meaning| "…record the singular/plural of each surface, add the missing plural…"| `agent-cli-session-potato.json`      |
| recipe diagram| "…generate the mermaid diagrams of our agentic recipes, split into parts…"| `agent-cli-session-diagram.json` |

A test (`routes_different_requests_to_different_concepts`) asserts the two
meaning requests route to the two distinct concepts, and the third request drives
an entirely different, **non-lexeme** axis (see below), so a passing run is
evidence the recipe generalises rather than pattern-matching one hardcoded
answer.

## Beyond meanings: the same method generates architecture diagrams

To show the "drive the Agent CLI" method is not special-cased to editing meaning
data, a third recipe (`src/agentic_coding/diagram.rs`) makes the *same* Agent CLI
**generate the mermaid diagrams of its own agentic recipes** — the issue's
*"generated mermaid diagram split into parts"* axis (R15/R16). The diagrams are
rendered from the planner's own recipe table (not hand-drawn), so they cannot
drift from the code; the Agent CLI writes
[`docs/diagrams/agentic-recipes.md`](../../diagrams/agentic-recipes.md) from a
differently-worded request, and both the document and its
[session JSON](agent-cli-session-diagram.json) are reproduced byte-for-byte under
test. This is the strongest generality evidence in the PR: the loop authored a
different *kind* of artifact from a different *kind* of request.

## What the enriched data looks like

Every surface now pins its part of speech and grammatical number, references its
real Wikidata lexeme form, and recovers the plural surfaces the source lists.

**tomato** (Q23501):

| Surface     | Language | Part of speech | Grammatical number | Grounded via          |
| ----------- | -------- | -------------- | ------------------ | --------------------- |
| tomato      | en       | noun           | singular           | `L7993-F1`, `Q110786` |
| tomatoes    | en       | noun           | plural             | `L7993-F2`, `Q146786` |
| помидор     | ru       | noun           | singular           | `L3526-F1`, `Q110786` |
| помидоры    | ru       | noun           | plural             | `L3526-F3`, `Q146786` |
| томат       | ru       | noun           | singular           | `L170542-F1`, `Q110786` |
| томаты (new)| ru       | noun           | plural             | `L170542-F7`, `Q146786` |

**potato** (Q10998):

| Surface       | Language | Part of speech | Grammatical number | Grounded via          |
| ------------- | -------- | -------------- | ------------------ | --------------------- |
| potato        | en       | noun           | singular           | `L3784-F1`, `Q110786` |
| potatoes (new)| en       | noun           | plural             | `L3784-F2`, `Q146786` |

Every surface still denotes its meaning (bidirectional word ⇄ meaning), and the
existing surface ordering is preserved so the translation tests (issue #221) stay
green.

## When the tool couldn't do something, we extended the tool

Per the issue's rule, hitting a wall is a signal to *extend the Agent CLI /
Formal AI so it can*, then retry — never to hand-finish and defer. In this PR:

- the recipe was **tomato-specific**, so it was refactored into a concept
  registry that generalises to any concept (this is what made potato a
  different-wording run rather than a copy);
- `AgentWorkspace::for_prompt` had a **TOCTOU race** (parallel runs with the same
  prompt shared a deterministic temp dir); it was fixed in the tool with a
  per-instance unique workspace id.

## The reasoning we explicitly reject

An earlier solution draft (maintainer's gist `95b1e919`) chose to *"deliver the
concrete verifiable core … honestly framing large research items as tracked
follow-ups"* and shipped a PR led by a *"what did not ship"* section. The
maintainer rejected it: *"That is opposite of my requirements … no refusals, no
delays, no deferral, no follow ups."* That failed reasoning is dissected in
[refusal-anti-pattern.md](refusal-anti-pattern.md) and is required reading before
contributing — see [`CONTRIBUTING.md`](../../../CONTRIBUTING.md), which now makes
this Agent-CLI-driven, no-deferral method the standing way we develop Formal AI.

## Reproduce

```sh
# the Agent-CLI-driven recipe: routing, byte-for-byte seed parity, end-to-end run
cargo test --test unit -- issue_538_agentic

# the grammatical-detail data facets
cargo test --test unit -- issue_538

# the grounding-closure and data-floor guards the new data must satisfy
cargo test --test unit -- semantic_grounding
cargo test --test unit -- data_files
```

Run one binary at a time (the issue asks for single-repository test runs to keep
the cargo cache from filling the disk).
</content>
