# 0026: Tuning

Status: accepted

nib corrects model habits with prompt patches: each has an id, applies to a set of
[Profiles](0025-model-profiles.md), can be turned off with `NIB_PATCHES_OFF`, and is
recorded in the Session log so `scripts/stats.py` can compare periods with and without it.
That discipline is what lets nib tune per model family without the prompt turning into
an untestable pile. It has three gaps:

- A patch is a single sentence that is either on or off. Real questions have several
  answers: Codex does well with "finish everything, then validate once", while on
  DeepSeek the same sentence makes the model write test scripts and install toolchains,
  doubling tool calls against Pi. Expressing alternatives as combinations of on/off ids
  is clumsy and lets incompatible combinations exist.
- Patches are appended after the base prompt. A sentence that belongs in the middle of
  a bullet has to be split out and reworded to stand alone.
- Prompt text is only one kind of model-specific choice. The auto-background threshold
  (`run_background_after_ms`), compaction timing, and runtime nudges differ by family
  too, but they are plain constants or configuration with no switch, no log record and
  no evidence trail.

## Decision

Introduce **Tuning**: every model-specific choice nib makes is a named tuning with a
small set of variants, and a Profile is a choice of variant for each tuning. Prompt
patches become one kind of tuning.

- **Kinds.** A *prompt* tuning fills a named slot in the system template
  (`{validation}`, `{background}`); each variant is the slot's text, possibly empty.
  A *value* tuning is a number or enum read by runtime code
  (`run_background_after_ms`). Further kinds are added when a real tuning needs one.
- **Defaults.** Each tuning has a default variant; a Profile overrides only where its
  family differs. Unmatched models get the defaults, which hold only what helps every
  model.
- **Overrides for experiments.** `NIB_TUNE=<tuning>=<variant>[,...]` replaces variants
  for one process and its child Sessions. It exists for measurement and diagnosis, not
  for users: tuning is not part of `config.toml`; users choose a model and nib follows.
- **Fixed per Session.** Variants are resolved once when a Session starts and stored in
  the log header; resumed Sessions keep them. The system prompt therefore never changes
  mid-Session and never breaks the prompt cache.
- **Recorded and grouped.** The log header records every tuning's variant, so
  `stats.py --group-by tuning` and Harbor comparisons group runs without bookkeeping
  outside the log.
- **Evidence.** A variant becomes a default only with a recorded comparison: the
  problem, the experiment (model, task set, runs), and the result. Each default records
  the model it was measured on; when the resolved model differs, tests or `stats.py`
  flag the tuning for recheck. Variants without a measured effect are removed.
  `docs/compromises.md` keeps the register.

`NIB_PATCHES_OFF` stays as an alias that selects the empty variant of the named prompt
tunings until existing measurements no longer need it.

## Rollout

1. Land the `validation` slot from the current experiment (variants: `single`,
   today's wording; `existing-only`; `none`) and make the winning variant the DeepSeek
   default.
2. Move the existing patches (`json-escape`, `no-shell-search`,
   `expected-continuation`) into prompt tunings with on/empty variants.
3. Make `run_background_after_ms` the first value tuning, with the DeepSeek variant
   settled by experiment.
4. Add the model-change recheck.

## Not decided

Whether tool descriptions and request parameters (thinking mapping, output limits)
become tuning kinds is decided when the first family needs a different value.
