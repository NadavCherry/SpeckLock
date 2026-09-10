#!/usr/bin/env python3
"""Reproduce the evidence that a single frame is not enough.

This exists to answer one specific criticism, which is worth stating plainly because it
is the most common objection to this project and it sounds reasonable:

    "You can see everything in the frame. You don't need a frame buffer.
     That is not the challenge in vision-based target finding."

If that were true, two things would follow: a single-frame detector would find the target,
and the remaining difficulty would be elsewhere. Both are testable on data in this
repository, and both fail. This script runs the test and prints the table.

    python tools/ablation_temporal.py                      # both experiments
    python tools/ablation_temporal.py --experiment birds   # just the discrimination one

**Experiment 1 — what does the temporal stack actually buy?**
Reported in two parts, because they answer different questions and were once conflated.
*1a* is the controlled ablation: same network, hyperparameters and seed, same 1280 px, same
pipeline. The intended difference is whether the three input channels carry three moments or
one frame's RGB; the temporal arm's training set also carries copy-paste instances the
single-frame arm's does not (realtime/tools/make_datasets_rt.py pastes only `if temporal:`),
and the report says so. *1b* is a cross-check against an off-the-shelf detector at 1760 px,
which differs in architecture, corpus AND resolution and therefore cannot attribute its gap
to the representation. 1b was previously published as though it were 1a.

**Experiment 2 — is finding it the challenge, or is telling it apart?**
07_05 carries 8 hand-labelled bird tracks, 934 instances, median 6.0 px against the
drone's 8.0 px. The distributions overlap almost completely, so *no* appearance model can
separate them by size, and a single frame carries almost nothing else at that scale. The
question is what does separate them. The answer is the only signal a single frame does not
have: how the thing moved.

Both experiments need artifacts that are produced elsewhere (a detector run over a video);
this script scores them and refuses to invent numbers for anything missing. `--help` lists
the commands that produce each input.
"""
from __future__ import annotations

import argparse
import sys
from pathlib import Path

REPO = Path(__file__).resolve().parent.parent
sys.path.insert(0, str(REPO))

from dronedet import metrics as M  # noqa: E402
from dronedet.detections import DetectionSet  # noqa: E402
from dronedet.gt import GroundTruth  # noqa: E402

#: THE CONTROLLED PAIR: (label, detections, how to produce it if absent).
#:
#: Same network, hyperparameters and seed (the two checkpoints' train_args differ only in
#: the data path), same 1280 px, same pipeline. NOT the same training corpus, as this
#: comment used to claim: realtime/tools/make_datasets_rt.py applies copy-paste only
#: `if temporal:`, so the temporal arm also trains on pasted drone and bird instances, and
#: realtime/README.md credits that augmentation with a large part of the gain. The report
#: states the confound instead of the old "only difference". The recipe-matched pair
#: WITHOUT pasting is the 8 px task's (configs/experiments/local_video.py, _LOCAL_AB).
#:
#: This replaces a pair that was not controlled: `tools/run_baseline.py` with an external
#: yolo26n checkpoint against `final/run_final.py --profile edge-rt`. Those differ in
#: architecture, training corpus AND resolution, yet the result was published under a
#: column headed "input representation" with only the resolution difference disclosed.
#: The uncontrolled comparison is still run below, because "does an off-the-shelf detector
#: find this at all" is a fair separate question -- it is just not this question.
SINGLE_VS_TEMPORAL = [
    ("single frame, RGB (rt-f-single1280)",
     "realtime/work/out/1006/rt-f-single1280/dets.json",
     "python realtime/tools/run_all.py rt-f-single1280"),
    ("3-moment temporal stack (rt-c-full1280)",
     "realtime/work/out/1006/rt-c-full1280/dets.json",
     "python realtime/tools/run_all.py rt-c-full1280"),
]

#: The uncontrolled cross-check, kept and LABELLED as such.
OFF_THE_SHELF = [
    ("off-the-shelf YOLO26n, single frame @1760 px",
     "work/ablation/singleframe_1006.json",
     "python tools/run_baseline.py --weights baseline/yolo26n-*.pt "
     "--video data/videos/10_06.mp4 --out work/ablation/singleframe"),
    ("this pipeline, EDGE-RT profile",
     "work/ablation/temporal_1006.json",
     "python final/run_final.py --video data/videos/10_06.mp4 --profile edge-rt "
     "--out work/ablation/edge"),
]

#: Both rows already use the temporal stack as *input*; what differs is whether a decision
#: is made per frame or per track. Labelling the first row "appearance" would overstate the
#: case -- it is a per-frame decision by a temporal detector, which is a stronger baseline
#: than a genuinely single-frame one and therefore a fairer comparison.
BIRD_METHODS = [
    ("per-frame decision (no track integration)", "work/det3/0705/pc-max.json"),
    ("+ track-level integration", "work/det3/0705/tracked-pcmax.json"),
]


def _missing(path: Path, how: str) -> None:
    print(f"  MISSING {path}\n    produce it with:  {how}", file=sys.stderr)


def _score_rows(gt, rows, block: int, resamples: int, lines: list) -> bool:
    any_row = False
    for label, rel, how in rows:
        p = REPO / rel
        if not p.exists():
            _missing(p, how)
            lines.append(f"| {label} | — | — | — | — | — | — | *artifact missing* |")
            continue
        any_row = True
        ds = DetectionSet.load(p)
        ev = M.evaluate(gt, ds, rule="centre", tau=12.0)
        s = M.summarise(ev, M.pick_threshold(ev))
        # Every detection the model emits, not only those above the best-F1 threshold: the
        # most it can ever find, and the precision that costs. The README once said a
        # single-frame detector could not see this drone "at any confidence"; this column
        # is the measurement that replaced the sentence.
        s_all = M.summarise(ev, 0.0)
        lo, hi = M.bootstrap_ci(ev, block=block, n_resamples=resamples)
        n = sum(len(v) for v in ds.frames.values())
        ci = f"[{lo:.3f}, {hi:.3f}]"
        # A degenerate interval on one video is not a tight measurement, it is a sample
        # size of one. Say so in the cell rather than letting [1.000, 1.000] read as
        # certainty.
        if hi - lo < 1e-9:
            ci += " ⚠️"
        lines.append(f"| {label} | **{s.ap:.3f}** | {ci} | {s.recall:.3f} "
                     f"| {s.precision:.3f} | {s_all.recall:.3f} | {s_all.precision:.3f} | {n} |")
    return any_row


def experiment_single_vs_temporal(gt_path: Path, block: int, resamples: int) -> str:
    gt = GroundTruth.load(gt_path)
    lines = [
        "## Experiment 1 — what does the temporal stack actually buy?",
        "",
        "### 1a. Controlled: the input representation, and nothing else",
        "",
        "Same network, hyperparameters and seed, same **1280 px**, same pipeline, same "
        "video, same ground truth. The intended difference between these two rows is whether "
        "the three input channels carry three moments or one frame's RGB. **One confound "
        "remains:** only the temporal arm's training set carries copy-paste instances "
        "(`realtime/tools/make_datasets_rt.py` pastes only `if temporal:`), so the gap is "
        "the representation together with that augmentation. This is the ablation; 1b "
        "below is not.",
        "",
        "| input representation | AP | 95% CI | recall† | precision† "
        "| recall, every detection‡ | precision, every detection‡ | detections |",
        "|---|---|---|---|---|---|---|---|",
    ]
    ok_a = _score_rows(gt, SINGLE_VS_TEMPORAL, block, resamples, lines)
    lines += ["", "† Everywhere in this report, recall and precision sit at the best-F1 threshold "
              "swept on the same video -- an oracle operating point, which `dronedet/metrics.py` "
              "says in writing is not an achievable one. AP is threshold-free.",
              "",
              "‡ Counting every detection the model emits: the most it can ever find, and the "
              "precision that costs. Precision counts only detections in frames the ground truth "
              "scores; the detections column counts every one. Each labelled frame of `10_06` holds "
              "one drone, so this recall is the share of labelled frames in which the drone is "
              "found at all."]

    lines += [
        "",
        "### 1b. Uncontrolled cross-check: versus an off-the-shelf detector",
        "",
        "⚠️ **These two rows differ in architecture, training corpus AND resolution**, so "
        "the gap between them is *not* attributable to the input representation. It answers "
        "a different and still useful question — whether a competent off-the-shelf detector "
        "finds this target at all — and it is reported separately for that reason. This "
        "pair was previously published as though it were 1a.",
        "",
        "| system | AP | 95% CI | recall† | precision† "
        "| recall, every detection‡ | precision, every detection‡ | detections |",
        "|---|---|---|---|---|---|---|---|",
    ]
    ok_b = _score_rows(gt, OFF_THE_SHELF, block, resamples, lines)

    if ok_a or ok_b:
        lines += [
            "",
            "Where the off-the-shelf single-frame row has **precision near 1.000 and recall "
            "near zero**, it is not a tuning failure: nearly everything it emits is correct, "
            "and it emits almost nothing -- counting every detection (‡) does not raise its "
            "recall. That is a property of this model, not of single frames. The controlled "
            "single-frame arm in 1a, trained on this project's data, reaches a much higher "
            "recall when every detection counts, at the precision printed beside it; what it "
            "lacks is the ranking, which is what AP measures.",
            "",
            "⚠️ marks a confidence interval of zero width. Both arms here run on **one "
            "video with one drone**, so a degenerate interval reflects a sample size of "
            "one, not a precise measurement.",
        ]
    return "\n".join(lines)


def experiment_birds(gt_path: Path, recalls: tuple[float, ...]) -> str:
    gt = GroundTruth.load(gt_path)
    n_bird = sum(len(o.frames) for n, o in gt.objects.items() if n.startswith("bird"))
    lines = [
        "## Experiment 2 — is finding it the challenge, or telling it apart?",
        "",
        f"07_05 carries **8 bird tracks / {n_bird} instances**, median 6.0 px against the "
        "drone's 8.0 px. The size distributions overlap, so nothing separates them by "
        "scale. Each row is the same detector held at a fixed drone recall, so the "
        "columns are comparable.",
        "",
        "Note what is *not* being compared: both rows already consume the temporal stack, "
        "so this is per-frame versus per-track decision-making, not appearance versus "
        "motion. The per-frame row is therefore a **stronger** baseline than a genuinely "
        "single-frame detector would be, which makes the gap below a conservative one.",
        "",
        "| method | drone recall | threshold | bird false alarms | other FP/frame |",
        "|---|---|---|---|---|",
    ]
    for label, rel in BIRD_METHODS:
        p = REPO / rel
        if not p.exists():
            _missing(p, "see docs/guides/methods.md for the run that produces it")
            continue
        ds = DetectionSet.load(p)
        ev = M.evaluate(gt, ds, rule="centre", tau=12.0, targets={"far"})
        scores = sorted({r.score for r in ev.records}, reverse=True)
        for target in recalls:
            hit = None
            for thr in scores:
                s = M.summarise(ev, thr)
                if s.recall >= target:
                    hit = (thr, s)
                    break
            if hit is None:
                lines.append(f"| {label} | {target:.2f} | — | *recall unreachable* | — |")
                continue
            thr, s = hit
            birds = sum(1 for r in ev.records if r.outcome == "distractor"
                        and r.obj and r.obj.startswith("bird") and r.score >= thr)
            lines.append(f"| {label} | {target:.2f} | {thr:.3f} | **{birds} / {n_bird}** "
                         f"| {s.fp_per_frame:.3f} |")
    lines += [
        "",
        "Read the two blocks against each other at matched recall. Per-frame decisions "
        "cannot hold both ends: pushed past 0.90 recall the detector starts calling birds "
        "drones, and the clutter rate goes with it (0.09 → 6.39 FP/frame). Track-level "
        f"integration holds ~1.00 recall at **0 / {n_bird}** bird false alarms and "
        "0.002 FP/frame, because a track carries the one thing a frame cannot: how the "
        "thing moved.",
        "",
        "⚠ **The honest limit of this table:** 8 bird tracks, one flock, one afternoon, one "
        "camera. It is an existence proof that the mechanism works, not a measurement of "
        "how well it generalises. Halmstad (CC0, video, labelled birds, 203k frames) is "
        "what turns it into a result — see `docs/research/PLAN.md`.",
    ]
    return "\n".join(lines)


def main(argv=None) -> int:
    ap = argparse.ArgumentParser(description=__doc__,
                                 formatter_class=argparse.RawDescriptionHelpFormatter)
    ap.add_argument("--experiment", choices=["single", "birds", "both"], default="both")
    ap.add_argument("--gt-1006", type=Path, default=REPO / "realtime/work/gt_1006_v2.json")
    ap.add_argument("--gt-0705", type=Path, default=REPO / "work/gt_user.json")
    ap.add_argument("--recalls", type=float, nargs="+", default=[0.80, 0.90, 0.95, 0.99])
    ap.add_argument("--block", type=int, default=30, help="bootstrap block length, frames")
    ap.add_argument("--resamples", type=int, default=2000)
    ap.add_argument("--out", type=Path)
    a = ap.parse_args(argv)

    parts = ["# Is a single frame enough?", "",
             "Generated by `tools/ablation_temporal.py`. Every number below is recomputed "
             "from committed artifacts; nothing is transcribed.", ""]
    if a.experiment in ("single", "both"):
        parts += [experiment_single_vs_temporal(a.gt_1006, a.block, a.resamples), ""]
    if a.experiment in ("birds", "both"):
        parts += [experiment_birds(a.gt_0705, tuple(a.recalls)), ""]

    report = "\n".join(parts)
    ### WRITE BEFORE PRINT. The file is the deliverable; stdout is a convenience.
    ### Printing first meant that on a console whose encoding cannot represent the
    ### report -- cp1255 on the author's own machine -- the script died on the print and
    ### never reached the write, so regenerating appeared to fail while producing
    ### nothing. The published REPORT.md drifted from its generator for exactly that
    ### reason, and kept publishing a comparison the generator had already corrected.
    if a.out:
        a.out.parent.mkdir(parents=True, exist_ok=True)
        a.out.write_text(report, encoding="utf-8")
        print(f"wrote {a.out}", file=sys.stderr)
    try:
        print(report)
    except UnicodeEncodeError:
        print("(written to file; this console cannot display it)", file=sys.stderr)
    return 0


if __name__ == "__main__":
    raise SystemExit(main())
