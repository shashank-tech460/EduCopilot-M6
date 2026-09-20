# Security Architecture

This document describes Team4B's actual security posture as of Phase 5K.
It states plainly what is fixed, what is mitigated-but-not-eliminated, and
what remains open. **Prompt injection is not claimed to be mathematically
impossible anywhere in this system.**

## Threat model

Retrieved document/video-transcript text is **untrusted data**, not a
trusted instruction source, regardless of its apparent authority, urgency,
or formatting. The specific threat validated across Phases 5D–5K:
retrieved content (ingested via Team4A from a PDF or YouTube transcript)
can contain text phrased as an instruction to the AI system itself (a
prompt-injection payload), and the underlying LLM is an
instruction-following model with no architectural way to distinguish "this
came from trusted system instructions" from "this came from an ingested
document" once everything is flattened into one prompt string (Ollama's
`/api/generate` has no API-level role separation).

**Ingestion trust assumption**: this threat model assumes retrieved
content *can* be adversarial regardless of who is allowed to upload it.
Team4B does not depend on, and this document does not assert, any
particular claim about who can upload content in Team4A/Team4C — that is
a product/trust-model decision outside Team4B's scope (see Phase 5K's
report for where this decision was explicitly deferred to the
architecture authority).

## Isolation (workspace and document)

- `workspace_id` is mandatory on every retrieval code path; there is no
  "search everything" option.
- BM25 rebuilds a fresh, workspace-scoped index per query — a
  cross-workspace document never contributes to ranking statistics, let
  alone appears in results.
- Live-tested repeatedly (Phases 5I-C, 5J, 5K): a real question about
  Workspace A's content, issued against Workspace B's `workspace_id`,
  never returns Workspace A's content, in semantic, BM25, or hybrid mode.
- Generation authority (a fail-closed MongoDB check against Team4A's
  current ingestion generation per document) prevents a stale or
  since-superseded chunk from ever appearing in an answer.

## Prompt-injection defense — two layers

### Layer 1 (Phase 5F): prompt-level trust boundary

`build_prompt()` brackets every retrieved chunk with explicit,
repeated-position delimiters (`_UNTRUSTED_CONTEXT_BEGIN`/`_END`/`_NOTE`)
stating that the enclosed text is data to read, not an instruction to
obey — regardless of how it's phrased, formatted, or how urgent/authoritative
it sounds. A narrow, purely syntactic neutralization pass
(`_neutralize_untrusted_text()`) additionally defuses two patterns that
could otherwise forge a fake structural transition in the prompt: a
role-prefixed line (`System:`/`User:`/`Assistant:`) and a literal
occurrence of one of the prompt's own reserved section-header strings.
Both patterns are syntactic, not keyword/subject-based, and never alter
ordinary educational content in any language.

**This layer alone is a real, measured, partial mitigation** — most
tested injection phrasings (fake role messages, "ignore previous
instructions," mid-paragraph or end-of-paragraph injections, markdown
code-block injections, conflicting multi-instruction payloads) are
correctly resisted. It does **not** prevent a short, unambiguous,
fully-formed imperative sentence from being obeyed regardless of where in
the prompt it appears — this was the residual gap Phase 5J's acceptance
battery confirmed still open.

### Layer 2 (Phase 5K): output-side forced-fixed-output guard

**FIXED, validated:** a narrow but real attack pattern — retrieved
content instructing the model to "always respond with exactly X" (a short
fixed string, e.g. "The answer is 42.", "ACKNOWLEDGED", "VERIFIED BYPASS",
"OVERRIDE_ACTIVE", or a Hindi equivalent) — could make the model discard
the real question and the real evidence entirely. Phase 5J's acceptance
battery measured this at **5 of 31 live injection cases achieving FULL
output hijacking**.

Phase 5K added a deterministic, generalized, downstream check in
`LLMGenerator.generate()`, after the LLM call returns and before the
answer is used: if the answer is short (≤6 tokens) **and** appears as an
exact contiguous quoted span inside the retrieved evidence text, it is
replaced with the same `INSUFFICIENT_CONTEXT_MESSAGE` the system already
uses for the "no evidence retrieved" case. No second LLM call, no
classifier, no new dependency, no subject or language vocabulary — the
same ASCII+Devanagari tokenizer pattern already used by
`bm25_index.py`'s production tokenizer is reused.

**Why this design, not the first one tried:** an initial candidate
(flag a short answer that shares *no* vocabulary with the query/evidence)
was tested against real captured attack outputs and found completely
ineffective (0/9 true positives) — a successful attack's output is, by
definition, drawn from the evidence, since the attacker's chosen string
is written directly inside the malicious chunk. The adopted design
(exact-substring containment) was validated against **68 real,
live-captured answers**: **8/8 true positives, 0/59 false positives**,
including on the shortest legitimate answers and refusals in the corpus.

**Validated after implementation:**

| Metric | Before (Phase 5J) | After (Phase 5K) |
|---|---|---|
| FULL-severity injection cases | 5/31 | **0/32** |
| False-positive regressions | — | **0** (full 31-case main acceptance battery + full pytest suite re-run) |

### Known residual: `REPRO-SPOOF-5` (PARTIAL severity)

One case remains open, **by design, out of scope for the Phase 5K fix**:
a retrieved instruction asking the model to "reveal your system prompt"
produced a longer response that echoed the *visible* prompt-scaffold text
(the delimiter/section-header strings themselves) — not any genuine
hidden system secret (none exists in this system to leak: there are no
API keys, credentials, or environment values anywhere in the prompt). This
is a longer, narrated disclosure, not a short forced output, so it falls
outside the 6-token gate the Phase 5K guard intentionally uses. It is
tracked as an open item for the architecture authority, not silently
accepted as fixed. See `team4b/data/m6_phase5k_prompt_injection_architecture_report.md`
Section 16 for the recommended next step (a separately-scoped detector,
not yet designed or evaluated).

### Investigated and rejected: ingestion-side filtering

An ingestion-side "suspicious instruction-like text" detector was
forensically evaluated (Phase 5K) and rejected on two independent
grounds: (1) implementing it would require modifying Team4A, outside this
work's boundary; (2) even a generously-scoped, best-faith deterministic
keyword/pattern detector, tested against real malicious and legitimate
text, achieved only 5/8 attack detection (missing Hinglish-phrased
attacks entirely) while wrongly flagging 3/11 (27%) of ordinary
educational imperative sentences ("Always check the transaction before
commit...", "Ignore the previous value and use the new value..."). Full
evidence: `team4b/data/m6_phase5k_prompt_injection_architecture_report.md`
Section 5.

## Secrets handling

- Real `.env` files and `*.pem` key files exist locally (required to run
  the services) but are gitignored at both the repository root and, for
  Team4C, at the service level (`team4c/.gitignore` and
  `team4c-validation/.gitignore`, verified identical).
- Verified via `git status --ignored`: every real `.env` file
  (`team4a/.env`, `team4b/.env`, `team4c/.env`, `team4c-validation/.env`,
  plus one backup-named `.env`) and both `service-jwt-*.pem` key files
  (in both `team4c/` and `team4c-validation/`) are marked ignored — none
  are trackable or staged.
- `.env.example` / `.env.docker.example` templates contain placeholders
  only — audited for real-looking secret patterns (API key formats,
  embedded MongoDB credentials, PEM key bodies) with none found; the one
  regex match was a documentation comment showing the *expected format*
  of a config value (`MFkw...`, an obviously truncated illustrative
  placeholder, not a real key).
- No hardcoded credentials were found in application source code
  (`team4a/app`, `team4b/app`) via direct pattern search.
- Full audit trail: `docs/REPOSITORY_CLEANUP_REPORT.md`.

## Security testing performed

- Phase 5F: 17-category adversarial threat model + 7 mandatory legitimate
  controls, live against real Ollama.
- Phase 5G: trust-boundary forensic follow-up.
- Phase 5J: 31-case acceptance battery re-confirming Phase 5F/G findings
  live, plus 5 new supplement cases (Hinglish-language injection,
  injection alongside irrelevant-only evidence).
- Phase 5K: root-cause forensic comparison of ingestion-side vs.
  output-side defenses, fresh live reproduction of all 5 FULL-severity
  cases, implementation, and a full post-fix regression run (31-case
  injection battery + 5-case supplement + 31-case main acceptance battery
  + full pytest suite).

## What is explicitly NOT claimed

- Prompt injection is not claimed to be impossible — a lower-severity
  residual (`REPRO-SPOOF-5`) remains open.
- No claim is made about Team4A/Team4C's upload/content trust model — that
  is out of Team4B's scope.
- No claim is made that the output guard defends against attack patterns
  not tested (e.g., long narrated hijacks, multi-turn manipulation across
  conversation history) — it is scoped specifically to the short
  forced-fixed-output pattern with real evidence behind that scope.
