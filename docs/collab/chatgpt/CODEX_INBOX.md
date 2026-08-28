# ChatGPT → Codex Inbox

This file is the **single append-only handoff entrypoint** for messages that ChatGPT wants Codex/other project agents to see.

## Usage

- Before starting or continuing implementation/review work, read the **latest entry at the bottom of this file**.
- Do not rewrite or delete previous entries.
- Substantive reviews may have a detailed file under:
  `docs/collab/chatgpt/reviews/`
- The Inbox entry remains the authoritative short handoff: verdict, blockers, required next action, and link to detailed review.
- If a newer entry supersedes an older one, it must say so explicitly.
- Codex does not need to edit this file to acknowledge; record execution status in the normal `SESSION.md` / `TODO.md` workflow.

---

## 2026-08-28 — R08 Gate-0 diagnostic review @ a3d11a8

**Verdict: REQUEST_CHANGES**

**Do not run Gate-0 GPU yet.**

Target:
- root: `a3d11a8ccae47e93df61655b0b2f5d959cd87f9a`
- submodule: `10bc41085de448d60d2f71b342c03a4cfcca9ee1`

Required fixes before GPU:
1. HIGH: wrap Wan VAE encoding in `torch.inference_mode()` / no-grad and detach CPU sidecars; current code can retain autograd graphs across 64×2 VAE forwards.
2. MEDIUM: enforce deterministic VAE runtime and preferably add same-input repeat control.
3. MEDIUM: make task/episode coverage real, not only episode-first selection with a task-diversity comment.
4. MEDIUM: freeze canonical PASS threshold at <=1e-6; CLI must not be able to loosen the Gate arbitrarily.

Recommended:
- persist first-frame/suffix input fingerprints and changed-pixel counts;
- optional runtime-A-z0 vs existing cache-z0 sampled parity.

Detailed review:
`docs/collab/chatgpt/reviews/2026-08-28_R08_Gate0_a3d11a8.md`

Next:
- CPU/static-only fixes
- new commit SHA
- re-review by ChatGPT/mm/Kimi
- GPU Gate-0 only after approval
