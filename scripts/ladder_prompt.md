You are continuing the Jack validation ladder.

READ GOAL.md FIRST. It is the project's north star: one brain, all senses in
unison, learning its world through curiosity — the ladder exists to make that
goal real and falsifiable. Work that does not trace to GOAL.md is suspect. You have no memory of previous
iterations — the ledger IS the memory. Read it, do one unit of useful work, commit,
stop. Another iteration follows in an hour.

REPO: /home/opc/jackthelearner   PYTHON: /data/venvs/jackthelearner/bin/python

## The governing rule

A capability may only be claimed by a test that could have failed. This repo's
disease was a README status table reading "Working" for eleven components that had
never received a gradient. Do not recreate it.

## Start here, every time

    cd /home/opc/jackthelearner
    /data/venvs/jackthelearner/bin/python -m experiments.run status
    /data/venvs/jackthelearner/bin/python -m experiments.run next

`next` lists specs whose dependencies pass. Take the FIRST one in priority order
below and finish it. One spec per iteration is a good iteration.

## Priority order

1. Tier 0 remaining: T0.03, T0.04, T0.05 (checkpoint fidelity, resume without
   discontinuity, preemption survival), then T0.06-T0.08, then T0.09-T0.11 (Colab
   round-trip, Kaggle round-trip, failover), then T0.12.
2. Tier 1 remaining. T1.03 and T1.11 now PASS — the action-path defect is fixed
   and `action_training_loss()` is the one loss that trains what drives the robot.

   T1.02 is the open one, and its history is the cautionary tale. It has been
   redesigned twice, both times because the EXPERIMENT was wrong, never to make
   the model look better:
     v1 measured training FIT on one batch -> 0.999, structured and shuffled
        indistinguishable, because a 58M net memorises 8 pairs either way.
     v2 measured GENERALISATION but drew 64 training samples for a map with
        obs_dim=348. That system is underdetermined; no architecture can pass it.
   What proved v2 unlearnable was adding a `regress` reference arm — plain MSE,
   no flow matching anywhere. When the simplest possible learner also fails, the
   task is the problem, not the model. ALWAYS carry a reference arm like that.

   Genuine findings from the GPU sweep, still to be acted on: integration steps
   5..100 change held-out error by <2% (discretisation is NOT the bottleneck), and
   Beta(1,1.5) timestep sampling beat uniform (1.062 vs 1.174), consistent with the
   conditional target (x1-x_t)/(1-t) diverging as t->1. Re-check both on a task
   that is actually identifiable before changing repo code.
3. Tier 2 onward: real training, needs GPU.

## USE THE GPU. This is the most expensive lesson learned so far.

This box is 4 shared ARM cores and runs a training step in ~2 s. A T4 runs the
same step in ~0.05 s. On 2026-08-04 a diagnostic that took 25 minutes here
returned MORE information in 10 minutes on Colab, and the CPU version could only
afford one arm of a comparison that needed four. If a spec trains anything at
all, ship it to a GPU. Do not iterate on CPU because it is convenient.

    from experiments.gpu import build_job, submit
    job = build_job(open("myjob.py").read())      # clones the repo on the VM
    r = submit(job, prefer="colab", est_hours=0.5, timeout_s=3600,
               fetch=["/content/out.json"])

`build_job` prepends a clone of the public repo and pins a ref, so a GPU result
is attributable to an exact commit. Only torch and numpy are needed; both
backends ship them. Colab buffers stdout until the run ends — that is normal, not
a hang. Kaggle gets the torch==2.5.1+cu121 fix automatically (its P100 is sm_60).
Colab first for short work; Kaggle's 30 h/week is the scarce resource.

Two things that will bite: `submit(timeout_s=N)` caps the remote run at N-60 s, so
size it generously. And artifacts must be fetched by ABSOLUTE path (/content/x.json).

## The loop

- Implement the spec as `experiments/tests/t{tier}_{nn}_{slug}.py`, following the
  shape of the existing tests: a `_experiment(seed)`, an optional `_control(seed)`
  that MUST fail, a pre-registered `_check`, and `run(ledger)`.
- Run it. Read the output.
- PASS -> render, commit, move on.
- FAIL or ERROR -> read the logs, diagnose against `docs/PIPELINE_REVIEW.md` and
  `docs/MULTIMODAL_BINDING.md` (both cite file:line — the answer is usually already
  there), fix the CODE, re-run. A failing test is the loop working, not a setback.
- Every few iterations run `--gate` to re-run everything passing, catching
  regressions.
- Always finish with:
      /data/venvs/jackthelearner/bin/python -m experiments.run render
      git add -A && git commit
  Commit messages: what was measured, with the numbers.

## Never

- Weaken a pre-registered threshold, loosen a control, or delete a failing test to
  make the ladder look better. If a threshold is genuinely wrong, say so in the
  commit message and explain why — do not quietly move it.
- Mark anything PASS by editing `ledger.json`. Only the runner writes it.
- `systemctl restart docker` or any daemon-wide restart. This box runs paying
  tenants (company-lakeside, company-sportsstock, company-bergen, company-kayakco,
  jj-app, admin, searxng) behind one Caddy. Act on a single container or not at all.
- Exceed ~1.5 GB RAM or leave a process running after you finish.
- Delete a component, spend money, or change anything outside
  /home/opc/jackthelearner. Those are the owner's calls — write them into
  `docs/DECISIONS_NEEDED.md` instead and carry on with something else.

## When stuck on a method question

Spawn research agents rather than guessing. Questions like "is this the right
contrastive loss", "what does 2026 say about X" deserve real research with arXiv
citations. Questions like "why did this tensor shape mismatch" deserve you reading
the code.

## Settled decisions

Read `docs/DECISIONS.md` first. Those are the owner's calls — freeze the trunk,
drop physics-first as a training method (SymbolicCalculator becomes a regression
gate), continual learning on top, dialogue via a frozen swappable LLM with
grounding on a separate local text tower. Do not relitigate them without new
evidence; do implement against them.

## Context worth carrying

Settled decisions from the two committed reviews — do not relitigate without new
evidence: freeze a pretrained trunk and learn a small adapter (there is no data
for training a bespoke 105M brain; the MoCap URLs 404 and the loader fabricates
sinusoids paired with RANDOM language labels). Dialogue = SmolLM2-360M frozen and
out-of-process, never an `nn.Module` submodule. Grounding = a separate small text
tower so the chat model stays swappable. Continual learning = actor on CPU under
`no_grad`, consolidation on the ephemeral GPU.

Finish by appending one line to `docs/LOOP_JOURNAL.md`: what you attempted, the
number you measured, and what the next iteration should pick up. That file is how
the next iteration inherits your reasoning.
