# Phase 11 Compliance A/B Report

**Date:** 2026-05-11
**Run mode:** offline subagent harness (no Anthropic API; Claude Code subagents acted as the test runners)
**Arms:** 2 — v0.2.x rules (HTML-comment, 10450 bytes) vs v0.3.x rules (XML contract, 4480 bytes)
**Prompts:** 15 structure-tagged prompts across 9 classes

## Headline

Both rule-sets achieve **15/15 = 100% lint compliance**. v0.3.x produces **+31% longer responses** for the same prompts. No compliance regression from the v0.3.0 XML rewrite, but the token-economy benefit predicted by the smaller rules file did NOT materialize in model output.

```
        rules-file size   total response chars   compliance
v0.2.x  10450 bytes       6653 chars             15/15 pass
v0.3.x   4480 bytes (-57%) 8683 chars (+31%)      15/15 pass
```

## Compliance per class (WIN / HURT / NEUTRAL)

| class | v0.2.x clean | v0.3.x clean | verdict |
|---|---|---|---|
| sequence (×2) | 2/2 | 2/2 | NEUTRAL |
| hierarchy (×2) | 2/2 | 2/2 | NEUTRAL |
| comparison (×2) | 2/2 | 2/2 | NEUTRAL |
| status (×2) | 2/2 | 2/2 | NEUTRAL |
| priority (×1) | 1/1 | 1/1 | NEUTRAL |
| branching (×1) | 1/1 | 1/1 | NEUTRAL |
| state-machine (×1) | 1/1 | 1/1 | NEUTRAL |
| mapping (×1) | 1/1 | 1/1 | NEUTRAL |
| none — suppress (×3) | 3/3 prose-only | 3/3 prose-only | NEUTRAL |

Suppression worked perfectly in both arms — all 3 `none` class prompts (definition, pattern name, recommendation) produced pure prose without diagram characters. This validates the `<contract>` suppress logic introduced in v0.3.0.

## Verbosity per class

Response chars (v0.2.x → v0.3.x, delta %):

| class | v0.2.x avg | v0.3.x avg | delta |
|---|---|---|---|
| sequence | 401 | 512 | +28% |
| hierarchy | 441 | 517 | +17% |
| comparison | 527 | 734 | +39% |
| status | 321 | 452 | +41% |
| priority | 422 | 553 | +31% |
| branching | 486 | 516 | +6% |
| state-machine | 503 | 684 | +36% |
| mapping | 598 | 879 | +47% |
| none (suppress) | 422 | 541 | +28% |

The +31% increase is uniform across structural and non-structural prompts alike — including the `none` class where no diagram is produced. This suggests the v0.3.x rules' more elaborate XML phrasing leads to longer responses overall, not just where diagrams are present.

## Why v0.3.x produced longer responses (root cause analysis)

The v0.3.x rules:
- Are 57% smaller in BYTES (10450 → 4480)
- Are more semantically precise (named XML elements: `<triggers>`, `<patterns>`, `<contract>`, `<intensity>`)
- Add three-faced behavior (amplify/channel/suppress)
- Add classify-first CoT (reasoning step before drawing)

But they do NOT include:
- **Smallest-visual-first instruction.** Nothing in the v0.3.x contract tells the model "pick the cheapest visual that conveys the structure". The `<patterns>` block names alternatives but doesn't establish a preference order.
- **Width-budget guidance.** No explicit "keep frame width under N chars" or "prefer dot-leader for status ≤5 items as a hard rule" (L11 catches this post-hoc, but the model doesn't know about L11 at draft time).

Result: v0.3.x produces *correctly compliant* visuals, but consistently picks the heavier form when both lighter and heavier would convey the same structure. Frame blocks for ≥6 status items; trees with all levels expanded; comparison tables with 3 columns when 2 would suffice; etc.

## Recommendation

Phase 11-followup (v0.4.0 candidate, post-this-report): add one `<contract>` line per intensity:

```
4. Smallest visual that fits — before drawing, ask: what is the cheapest form
   that still conveys the structure? prose < glyph < dot-leader < tree <
   md-table < frame. climb only when the lighter form loses information.
```

Byte cost: ~150 bytes per intensity × 3 intensities = ~450 bytes. Budget is 4480 (currently exhausted); compaction elsewhere required (the research note `.planning/notes/token-economical-ascii-research-2026-05-10.md` suggests dropping redundant `<examples>` lines OR sharing a single `<ladder>` element across all three intensities — saving the ~300 bytes the dual would otherwise consume).

After the rule extension, expected impact:
- v0.3.x + smallest-visual-first → expected response chars near v0.2.x baseline OR shorter (since the rule actively prefers lighter forms)
- L11/L12/L13 detection rate should drop (the model produces fewer overdecorated frames in the first place)
- Suppress class (none) likely unchanged (no diagram → no economy lever)

This becomes a falsifiable hypothesis for v0.4.1 measurement: a 3rd arm of the harness running v0.3.x+ladder rules should show 15-25% reduction in response chars vs current v0.3.x.

## Methodology notes & caveats

**Methodology:**
- 2 Claude Code subagents (sonnet model) acted as test runners — one per rule arm
- Each subagent received its rule-set text inline as the active diagram-injection rules
- Subagents generated responses in Russian (matching project context), then ran feynman-lint via spawnSync on each response
- Aggregates returned as JSON to the orchestrator (this file)

**Caveats:**
- N=15 is small. Per-class samples (1-3 prompts) are below the statistical-significance threshold for differential claims
- Subagents simulate rule injection via prompt text, NOT via the live `UserPromptSubmit` hook. This is *close to* but not identical to the production system
- Both arms were generated by the same model family (Claude sonnet); the comparison is rules-vs-rules at fixed model
- The `response_has_diagram` heuristic (looks for `┌`, `├`, `→`, markdown table) misses `▲▼` priority scale and dot-leader visuals; the `priority` class registers as `diagrams: 0` for both arms despite both producing valid priority scales
- Single run per arm; no variance estimation. A repeat run could shift per-prompt sizes ±10-15% from sampling noise alone

**Reproducibility:**
- All inputs: `eval/v0.4.0-compliance/{prompts.json, rules-v02.md, rules-v03.md}`
- All outputs: `eval/v0.4.0-compliance/{results-v02.json, results-v03.json, REPORT.md}`
- Subagent prompts captured in autonomous-log notes
- Lint binary: `bin/feynman-lint.js` at commit reachable from this report

## Requirements satisfied

- **EVAL-01:** 15-prompt structured corpus in `eval/v0.4.0-compliance/prompts.json` with `class` tags
- **EVAL-02:** 2-arm A/B run with feynman-lint pass/fail per response and aggregate compliance %
- **EVAL-03:** WIN/HURT/NEUTRAL classification per class (all NEUTRAL on compliance); HURT-class regression identified (+31% verbosity) with concrete follow-up proposal

3 of 3 Phase 11 requirements satisfied.

## Next

Phase 11-followup: extend `rules/feynman-activate.md` with smallest-visual-first ladder per intensity. Estimated impact: token-economy improvement that L11/L12/L13 would normally catch post-hoc becomes baked into generation. To be implemented immediately after this report ships.
