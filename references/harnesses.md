# Harness evidence and degradation

Load this when reporting on any harness other than Claude Code, or when a field
comes back unavailable and you need to explain why.

The rule behind every entry below: **each field uses only evidence that harness
actually exposes.** Unsupported fields degrade to "not available". Never
substitute install time or file mtime for a missing trigger count. A report
without the trigger column is still useful; a report with a fabricated one is not.

## What each harness can prove

| Check | Claude Code | Codex | OpenClaw | WorkBuddy | Hermes | DeepSeek Harness |
|---|---|---|---|---|---|---|
| Context cost, structure, overlap, security | ✅ | ✅ | ✅ | ✅ | ✅ | ✅ |
| Description budget (SV001/SV002) | configurable estimate | official 2% / 8k fallback | configurable cap | unavailable | unavailable | unavailable (SV004 truncation) |
| Loaded vs. on disk | `enabledPlugins` | app-server catalog | eligible runtime catalog | manifest + welcome mode | filesystem only | session log + registry snapshot |
| Scope / dependencies | partial | runtime metadata | runtime eligibility metadata | package metadata | unavailable | registry snapshot |
| Trigger data (SV201/SV202) | `skillUsage` | unavailable | unavailable | unavailable | unavailable | session log |

When a row reads "unavailable", `doctor` emits **SV901 CAPABILITY_UNAVAILABLE**
rather than a zero. Report that as a gap in evidence, not as a finding about the
skills.

## Claude Code

Plugin state and lifetime per-skill usage come from `~/.claude.json`.

`skillUsage` is **lifetime** data, not a rolling 30-day window. Say so when
quoting it — users routinely read a low number as "unused recently".

Bundled skills shipped inside the CLI may not exist as standalone files, so
actual description budget use can be higher than the filesystem estimate.
State that caveat whenever you report a budget percentage.

## Codex

Use the app-server runtime catalog for enabled state, scope, interface, and
dependencies.

Its 2% / 8,000-character budget is an **official estimate, not measured prompt
usage**. Label it as policy, not measurement.

Codex runtime evidence is *additive*: it can reveal skills the filesystem scan
did not find, and those are merged into the inventory.

## OpenClaw

Use `openclaw skills list --eligible --json` for per-instance eligibility, model
visibility, source, disabled/allowlist state, and missing dependencies. Include
workspace, plugin, shared, and npm-bundled roots.

`openclaw_instances` is the **grouping authority**. Never report a cross-instance
duplicate as a shadowing conflict — conflicts hold only inside one
`conflict_domain`.

OpenClaw runtime evidence is *exclusive*: if the CLI succeeds, only records it
returns as model-visible count as loaded. If the CLI fails or times out, fall
back to filesystem candidates and do **not** call them loaded.

Runtime visibility means the compact metadata is eligible and model-visible. It
does not prove the full `SKILL.md` body was loaded.

## WorkBuddy

Derive active top-level skills from the builtin manifest, the installed cache
version, and the welcome mode. Do not promote plugin internals or connector
catalog entries to top-level skills.

Activity is inferred from manifest/cache/mode evidence, never from invocation
records — WorkBuddy exposes none.

## Hermes

Use configured `external_dirs` and filesystem roots. Mark runtime state and
trigger counts unavailable unless the harness exposes stronger evidence.

## DeepSeek Harness

Use `--harness dsh`. Static measurement — context cost, structure, overlap, security —
is identical to the other harnesses; what differs is the budget and evidence model.

There is no global description budget. The catalog truncates each description at
`catalogDescriptionMaxLength` (default 500), so SV001/SV002 are replaced by SV004
(truncation) and the budget row reports unavailable rather than a guessed total.

Loaded-vs-disk and trigger evidence come from two sources, never filesystem alone:
the session log (`evidence_recency=log`) and the registry snapshot
(`--runtime-json`, `evidence_recency=probe`). The skill directory is a previous
round's product, not a mirror of disk (DSH_INTEGRATION §2.4), so disk discovery is
discoverable-only. When neither evidence source is present, trigger data reports
unavailable — never a fabricated zero count.

## Last-resort trigger evidence

For harnesses with no native usage source only:

```bash
python3 scripts/probe_logs.py --harness openclaw --deep
```

It deduplicates observed `read` calls to `SKILL.md`. Those reads may come from
inspection or debugging rather than automatic activation. Report them as
indirect `observed_skill_reads`. Never copy them into `usage_count`, and never
decide a zombie verdict from them alone.
