---
title: SkillsBench Skill Leaderboard
emoji: 🏆
colorFrom: orange
colorTo: red
sdk: gradio
sdk_version: 4.44.0
app_file: app.py
pinned: false
hf_oauth: true
---

# SkillsBench Skill Leaderboard — HuggingFace Space

A standalone, Hub-discoverable leaderboard for community-submitted SkillsBench
skills (the "pattern 1" / HF-native variant from
[`docs/skill-leaderboard-design.md`](../../docs/skill-leaderboard-design.md)).

This Space is **display + submission only**. It does not run evaluations. The
one write it makes to the board is the submitter's own claim: at submit time it
computes the lift from the uploaded `scores.json` (with `metrics.py`, a mirror
of the worker's module) and publishes the row **immediately** with
`attestation="self-reported"` — grey and unranked on both surfaces.

Every submission is keyed by a unique **`submission_id`** (uuid, minted here at
submit time) — the primary key of all its HF storage and of its board row.
`skill_hash` stays in the manifest as the integrity anchor; resubmitting the
same bundle is a new submission.

```
 ┌─ this Space (Gradio) ─────────────────┐      ┌─ Dataset: benchflow/skill-leaderboard ─┐
 │  Leaderboard tab  ── reads ──────────────────▶  board.parquet   (public, aggregated)  │
 │  Submit tab       ── enqueues (OAuth) ───────▶  queue/<submission_id>.json             │
 │     └─ publishes claim (self-reported) ──────▶  board.parquet (self-reported row)      │
 └───────────────────────────────────────┘      │  skills/<submission_id>/       (private)│
                                                 │  trajectories/<submission_id>/ (private)│
                                                 │  scores/<submission_id>/       (private)│
                                                 └───────────────────────────────────────┘
              a separate runner (you own) consumes the queue, REPLAYS the submitter's two
              trajectories in the sealed task containers, verifies, and REPLACES the row
              (same submission_id) with attestation="replayed" (the only ranked tier)
              — see integrations/skill-eval-worker/ + the design doc.
```

Tier rule: the Space may **only** write `self-reported` rows; `replayed` rows
and `results.parquet` are worker-only. Numbers use the same math in both tiers
(`metrics.py` mirror), so verification changes a row's provenance, not its
schema.

Name privacy: the submit form has a "show the skill name publicly" toggle.
When off, the board shows `skill-<submission_id[:8]>`; the real name lives only
in the queue record (never displayed), and the worker applies the same rule on
verification.

Two HF objects, the canonical leaderboard split:

- **The Space** (this dir) — the UI and the submit form. Its filesystem is
  ephemeral, so it holds no state.
- **The Dataset** `benchflow/skill-leaderboard` — the durable store: the
  aggregated board (`board.parquet`), the submission queue
  (`queue/<submission_id>.json`), and the private skill bundles + trajectories
  + self-reported scores (`skills/<submission_id>/`,
  `trajectories/<submission_id>/`, `scores/<submission_id>/`).

The board is **read pre-aggregated** from `board.parquet`. Aggregation (lift Δ,
normalized gain g, task-level CIs, significance) is computed by `metrics.py` —
one module, mirrored here and in the eval worker — so the math has a single
source of truth and matches the website's agent board
(`website/src/data/leaderboard-data.ts`). Verified (`replayed`) rows are
written only by the worker; this Space writes only `self-reported` rows at
submit time.

## Run locally

```bash
pip install -r requirements.txt
# optional overrides:
export DATASET_REPO=benchflow/skill-leaderboard
export HF_TOKEN=hf_...        # only needed to write (submit) or read a private dataset
python app.py
```

## Deploy to the Hub

```bash
huggingface-cli repo create skill-leaderboard --type space --space_sdk gradio
git init && git add . && git commit -m "skill leaderboard space"
git remote add hub https://huggingface.co/spaces/<org>/skill-leaderboard
git push hub main
```

`hf_oauth: true` in the metadata above gives the "Sign in with Hugging Face"
button used to attribute and rate-limit submissions.

## Environment

| Var | Default | Purpose |
| --- | --- | --- |
| `DATASET_REPO` | `benchflow/skill-leaderboard` | backing Dataset |
| `HF_TOKEN` | — | write token for enqueuing submissions / reading a private dataset |
| `DATASET_TAG` | `v1.1` | dataset tag stamped on self-reported rows' manifests |
| `TASK_COUNT` | `87` | suite size a `scores.json` must fully cover, both conditions (`0` disables — dev only) |
| `SITE_URL` | `https://skillsbench.ai/skill-leaderboard` | website board to cross-link |
