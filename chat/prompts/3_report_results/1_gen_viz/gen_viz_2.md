# gen_viz_2 — report_results

> Phase: `gen_paper_repo` · `gen_viz`
> Run: `run_MmmgOkQFZ5uI` — Does TCP-Style Reactive Caching Actually Beat Fitted Staleness Models?
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `gen_viz_2` (terminal_claude_agent)

### [1] SYSTEM-USER prompt · 2026-08-10 05:31:50 UTC

````
<research_methodology>
Create figures that belong in a top-venue paper.

- Every figure needs a clear takeaway visible at a glance.
- Choose chart types that match the data relationship (comparisons, trends, correlations, distributions).
- Include uncertainty (error bars, confidence intervals) when showing experimental results.
- Keep it clean — no clutter, clear labels with units, readable at print size.
</research_methodology>

<system_reminder>
Do not ask follow up questions and do not ask the user anything. Execute all steps independently.
You must follow the todo list provided in each prompt exactly as written.
No placeholders, stubs, or incomplete code — all code must be complete and functional.
</system_reminder>

<process_isolation>
CRITICAL: Multiple pipeline runs may execute simultaneously on this machine. `ps aux | grep method.py` matches ALL runs, not just yours.
- NEVER kill processes by name (`killall`, `pkill -f`, `ps aux | grep ... | xargs kill`). This kills OTHER runs' processes.
- NEVER monitor processes by name (`ps aux | grep method.py`). You will see other runs' processes and get confused.
- ALWAYS use PID-based process management:
  Run: `uv run method.py & PID=$!` or `timeout <seconds> uv run method.py & PID=$!`
  Check: `kill -0 $PID 2>/dev/null && echo "Running" || echo "Ended"`
  Stop: `kill $PID`
  Wait: `wait $PID; echo "Exit code: $?"`
  Monitor: `tail -f logs/run.log & TAIL_PID=$!` then `kill $TAIL_PID` when done
</process_isolation>

<workspace>
Your workspace: `/ai-inventor/aii_data/runs/run_MmmgOkQFZ5uI/4_gen_paper_repo/_2_gen_viz/gen_viz_2`

CRITICAL: Every file you create, write, or save MUST be inside this workspace directory (subdirectories OK). You MUST NOT write files anywhere outside this path — external paths are READ-ONLY. Use absolute paths for all file operations.

EVERY file write MUST start with `/ai-inventor/aii_data/runs/run_MmmgOkQFZ5uI/4_gen_paper_repo/_2_gen_viz/gen_viz_2/`:
GOOD: `/ai-inventor/aii_data/runs/run_MmmgOkQFZ5uI/4_gen_paper_repo/_2_gen_viz/gen_viz_2/file.py`, `/ai-inventor/aii_data/runs/run_MmmgOkQFZ5uI/4_gen_paper_repo/_2_gen_viz/gen_viz_2/results/out.json`
BAD: `/tmp/file.py`, `~/output.json`, `./file.py`, any path outside the workspace
</workspace>

<task>
Render a publication-quality DATA figure for a top-tier venue research paper.

This figure plots numbers, so it is RENDERED from those numbers — not drawn by an image model. Use the aii-data-fig-gen skill. The output is deterministic: run it once, look at it, fix the spec if the data or labels are wrong, run it again.

STEPS:
1. Read the skill: `.claude/skills/aii-data-fig-gen/SKILL.md`.
2. Pick the chart type that fits the specification below. `python <skill>/scripts/chart_gen.py --list-types` lists them; `--example <type>` prints a complete spec to copy.
3. Write your spec to `fig_frontier_spec.json` in your workspace. Put EVERY numeric value from the specification into it — the spec is the figure.
4. Render it:
   `python <skill>/scripts/chart_gen.py --spec fig_frontier_spec.json --out fig_frontier_v0`
   That writes `fig_frontier_v0.pdf` (the deliverable, vector) and `fig_frontier_v0.png` (for you to look at).
5. READ THE PNG BACK and check it against the checklist below.
6. If anything is wrong, edit the spec and re-render. Repeat until clean — this is cheap and deterministic, so there is no attempt limit and no reason to accept a flawed figure.

DELIVERABLE: `fig_frontier_v0.pdf` in your workspace root. Leave `fig_frontier_spec.json` there too — it is the figure's source, and the step files it next to the figure so the figure stays reproducible.

Verification checklist (after EVERY render) — these are the things only you can check, because they are about whether the figure says what you meant:
- Every number in the figure matches the specification — no invented or dropped values
- Axis labels state what is measured AND its units
- Axis ranges make the comparison readable rather than flattening it
- The chart type still makes the point once you can see it drawn
- The caption describes what is actually drawn

The generator already REFUSES the rest rather than shipping them, so a figure you can read back cannot have them: overlapping or cut-off labels, a legend covering the data, a series drawn without a name beside named ones, two series a reader cannot tell apart, and a fit or a scale that the data cannot support. When it exits non-zero the message names the exact key, index or label and what to change — do that rather than re-rolling.

Reach for a generator first, and hand-write only if none fits. Every type in `--list-types` already carries the house style, the data-integrity checks and the layout fixes, so using one is less work than plotting by hand and the result matches every other figure in the paper.

If nothing in the catalogue fits, writing matplotlib yourself is expected and supported — novel figures exist. When you do, import the house style AND its layout passes so the figure still belongs to the set — `apply_house_style`, `place_legend`, `place_point_label`, `fit_legends`, `clear_legends_of_data`, `fit_tick_labels`, `fit_titles`, `rasterize_dense_clouds`, `assert_legends_clear_of_data`, `assert_series_are_distinguishable`, `assert_axis_names_are_unique` from `chart_style`, and `fit_point_labels` + `assert_text_is_legible` from `chart_geometry`, the last of which raises if any label ends up printed over another or cut off at the edge. Build legends with `place_legend` and point names with `place_point_label` — a legend made with a bare `ax.legend` cannot be reflowed when it turns out too wide, and a name written with a bare `ax.annotate` will not be moved off the marker it landed on. The "Use a generator when one fits" section of SKILL.md has the exact snippet and the order to call them in. What you lose is the automatic checking that the picture agrees with the numbers, so verify every value yourself against the specification.
</task>

<figure_specification>
Figure ID: fig_frontier
Title: Hit Rate vs Stale Rate on Real Corpus
Caption: Reduction-vs-staleness operating points for all six policy families on the real-content versioned corpus (mean over 20 replicate seeds at the 0.20 headline spot-check rate). AIMD's full 9-point knob grid is dominated outright by FreshCache (raw and pooled), and matched, not beaten, by the simpler EWMA-adaptive baseline.
Data and chart description: Scatter plot, x-axis 'Stale rate of served hits' from 0.08 to 0.19, y-axis 'Cache hit rate' from 0.65 to 0.95. Six series with distinct colors and markers: (1) 'Fixed TTL' (gray circles), 5 points: (0.113, 0.695), (0.107, 0.774), (0.124, 0.825), (0.143, 0.868), (0.173, 0.916). (2) 'd-TTL' (purple triangles), 3 points: (0.109, 0.721), (0.110, 0.716), (0.111, 0.707). (3) 'EWMA-adaptive' (yellow squares), 3 points: (0.107, 0.799), (0.106, 0.797), (0.106, 0.797). (4) 'AIMD' (blue diamonds, emphasized, larger markers), 9 points clustered tightly: (0.106, 0.794), (0.107, 0.795), (0.109, 0.796), (0.106, 0.795), (0.107, 0.796), (0.109, 0.797), (0.106, 0.801), (0.107, 0.802), (0.109, 0.803). (5) 'FreshCache (raw)' (green stars), 3 points: (0.112, 0.902), (0.116, 0.903), (0.121, 0.905). (6) 'FreshCache (pooled)' (dark green stars, emphasized), 3 points: (0.096, 0.898), (0.101, 0.902), (0.112, 0.906). Draw a dashed Pareto frontier line connecting the upper-left-most non-dominated points, which should visibly pass through the FreshCache points and above/left of all AIMD points, making clear FreshCache dominates AIMD. Legend in upper right. Title 'Real Corpus: Hit Rate vs Stale Rate by Policy Family'.
Aspect Ratio: 16:9
Summary: Shows FreshCache Pareto-dominating AIMD on the real corpus, with EWMA matching AIMD.
</figure_specification>


---

Output the result as JSON to: `./.terminal_claude_agent_struct_out.json`

JSON Schema:
```json
{
  "$defs": {
    "VizExpectedFiles": {
      "description": "Expected output files from viz generation.",
      "properties": {
        "image_path": {
          "description": "Path to the generated figure image file. Example: 'fig1_v0.jpg'",
          "title": "Image Path",
          "type": "string"
        }
      },
      "required": [
        "image_path"
      ],
      "title": "VizExpectedFiles",
      "type": "object"
    }
  },
  "description": "Structured output from viz figure generation agent.",
  "properties": {
    "title": {
      "description": "Figure title in plain, everyday language \u2014 short and jargon-free so a non-expert grasps it at a glance. Aim for about 4-8 words (~40 characters).",
      "maxLength": 90,
      "minLength": 12,
      "title": "Title",
      "type": "string"
    },
    "summary": {
      "description": "Brief summary of the generated figure: what it shows, style, any issues fixed",
      "maxLength": 5000,
      "minLength": 500,
      "title": "Summary",
      "type": "string"
    },
    "out_expected_files": {
      "$ref": "#/$defs/VizExpectedFiles",
      "description": "Output file you created. Must include the generated figure image path."
    }
  },
  "required": [
    "title",
    "summary",
    "out_expected_files"
  ],
  "title": "VizFigureOutput",
  "type": "object"
}
```

IMPORTANT: this task is NOT complete until `./.terminal_claude_agent_struct_out.json` exists and contains JSON matching the schema above.
````

### [2] HUMAN-USER prompt · 2026-08-10 05:31:50 UTC

```
Investigate whether a simple, well-specified caching strategy measurably reduces redundant LLM tool calls in an agent loop, and quantify the tradeoff against staleness.
```

### [3] SKILL-INPUT — aii-data-fig-gen · 2026-08-10 05:31:52 UTC

The agent loaded the **aii-data-fig-gen** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-data-fig-gen
description: Render publication-quality DATA FIGURES (figure_type='data') — bar, line, scatter, heatmap/confusion matrix, box, violin, beeswarm, histogram, ECDF, scaling law, stacked area, forest/CI, Pareto frontier, ROC/PR, volcano, bump/rank, joint scatter with marginals, dendrogram, clustermap, network graph, and multi-panel composites — deterministically from a JSON spec, as vector PDF plus a PNG. Use for any figure that plots numbers. For CONCEPT FIGURES (figure_type='concept') — conceptual artwork, architecture and flow diagrams, anything with no underlying data — use aii-concept-fig-gen instead.
---

# Data figures — charts rendered from their numbers

Deterministic figures from a JSON spec: the numbers go in, matplotlib draws
them, and the picture cannot disagree with the data. Nothing is generated by
a model, so a bar is the height of its value and every axis is computed.
Re-running a spec gives a byte-identical PNG; the PDF differs only in its
embedded creation timestamp.

## Data figure or concept figure?

| The figure is… | Use |
|---|---|
| A chart of numbers you have | **this skill** (data figure) |
| A confusion matrix, ablation grid, correlation | **this skill** (data figure) |
| A scaling law, training curve, Pareto trade-off | **this skill** (data figure) |
| Conceptual artwork, a metaphor, a cover image | `aii-concept-fig-gen` (concept figure) |
| An architecture or flow diagram | `aii-concept-fig-gen` (concept figure — see *Limits*) |

The test is whether the figure has underlying numbers. If it does, an image
model will approximate them — bars that do not match their labels, axis
ticks that do not divide evenly, invented data points. That failure is
invisible to a reviewer of the prompt and obvious to a reviewer of the
paper.

## Use a generator when one fits — hand-write only when none does

The generators are a menu, not a fence. Every type below is a shortcut that
already has the house style, the data-integrity guards and the layout fixes
baked in, so reaching for one is almost always less work than plotting by
hand and the result is consistent with every other figure in the paper.

**Check `--list-types` first.** If a type matches what you need, use it.
Two-thirds of research figures are a bar, a line, a scatter or a heatmap,
and those are solved.

**If nothing fits, write matplotlib yourself** — that is expected and
supported, not a failure. Novel or one-off figures exist. When you do:

```python
import sys; sys.path.insert(0, "<skill>/scripts")
import matplotlib.pyplot as plt
from chart_geometry import assert_text_is_legible, fit_point_labels
from chart_style import (
    apply_house_style, PALETTE, literal, place_legend, place_point_label,
    fit_legends, clear_legends_of_data, fit_tick_labels, fit_titles,
    rasterize_dense_clouds, assert_legends_clear_of_data,
    assert_series_are_distinguishable, assert_axis_names_are_unique,
)

apply_house_style()                 # fonts, palette, grid, Type-42 PDF fonts
fig, ax = plt.subplots(figsize=(7, 3.94), layout="constrained")
...
place_legend(ax, loc="best")        # a legend fit_legends can reflow
place_point_label(ax, literal("Ours"), (1, 2))   # a name, nudged off the data
fit_legends(fig)                    # reflow a legend wider than its axes
clear_legends_of_data(fig)          # move it below the axes if it sits on data
fit_tick_labels(fig)                # wrap/tilt tick labels that would collide
fit_titles(fig)                     # wrap any title wider than its axes
clear_legends_of_data(fig)          # AGAIN — the two above reshaped the axes
fit_point_labels(fig)               # move point names off markers and curves
rasterize_dense_clouds(fig)         # >25k points as a bitmap, text stays vector
assert_text_is_legible(fig)         # raises if any text collides or is cut off
assert_legends_clear_of_data(fig)   # raises if a legend still hides its data
assert_series_are_distinguishable(fig)  # raises on two identical legend keys
assert_axis_names_are_unique(fig)   # raises if one name labels two positions
fig.savefig("figX_v0.pdf")          # vector, so LaTeX renders text at page res
```

Call the fitters in that order — the legend decides how much room the axes
has, whether it then has to move out of the data is only knowable once it is
placed, tick labels change the axes height, the title is measured against the
axes it ends up on, and a point's name can only be placed once nothing above
it will move the point again. `clear_legends_of_data` appears TWICE on
purpose: it decides by measuring, and the two passes between its calls shrink
the axes under a legend that is already placed and a fixed size. A wrapped
title took a lone chart from 179 px of axes height to 141, and a legend that
covered nothing before covered half a curve after — with the mover's turn
already past, so the figure was refused rather than fixed. The first call
still has to happen first, because the room the legend needs is an input to
the passes below it. Two further gates are warning-based and so are
not in the snippet: `assert_layout_applied` and `assert_all_glyphs_rendered`
read what matplotlib warned about during the draw, so they need the figure
built inside `warnings.catch_warnings(record=True)` — worth doing, since a
missing glyph is only ever a warning and ships as a hollow box.
`place_legend` and `place_point_label` are how
the fitters find what to fix: a legend built with a bare `ax.legend` cannot
be reflowed, and a name written with a bare `ax.annotate` will not be moved
off the marker it landed on.

That keeps a hand-written figure looking like the rest of the paper and
still gets you colourblind-safe colours, submission-compliant fonts, no
clipped labels and no overprinted ones. What you lose is the data-integrity
checking — so verify the numbers yourself.

**If you hand-write the same figure type twice, add a renderer instead.**
`chart_renderers*.py` — one function, `(ax, spec) -> None`, registered in
its family's dict. That is how this catalogue got here.

## Use it

```bash
SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-data-fig-gen"
G="$SKILL_DIR/scripts/chart_gen.py"

python "$G" --list-types            # the catalogue
python "$G" --example bar           # a complete spec to copy and edit
python "$G" --spec fig1.json --out figures/fig1
```

`python` here is the pipeline image's interpreter, which has matplotlib and
scipy installed system-wide. Outside the image use the project venv —
`.venv/bin/python` — since a bare `python3` will not have them.

Writes `figures/fig1.pdf` **and** `figures/fig1.png`. The PDF is the
deliverable — LaTeX renders vector text at page resolution, so it stays
sharp and selectable at any zoom. The PNG exists so you can read the figure
back and look at it.

`--format pdf`, `--format png`, `--format pdf,png,svg` narrows the output.
SVG keeps its labels as TEXT rather than paths, so it stays editable and
searchable. EPS is refused: the PostScript backend cannot draw transparency
and flattens it silently, which the house style uses on nine of every ten
figures — the file would not match the PNG you checked.
`--spec -` reads the spec from stdin.

Runs on `matplotlib` + `numpy`, both already `aii_pipeline` dependencies —
nothing to install.

## The catalogue

`--example <type>` prints a complete spec for any of these. The "instead of"
column is the useful one: most figures have two plausible types and the
choice between them is what decides whether a reviewer reads the point.

### Comparing categories

| type | draws | choose it over |
|---|---|---|
| `bar` | Vertical bars, grouped or stacked, optional error bars. | The default. `barh` if names are long. |
| `barh` | Horizontal bars — labels on the y-axis with room to run. | `bar`, whenever names exceed ~40 chars, or for a ranking. |
| `lollipop` | A stem and a dot per category. | `barh`, past ~20 categories, where bars become a picket fence. |
| `dumbbell` | Two markers per row joined by a line. | Paired bars, when the GAP between them is the story. |
| `slope` | One line per item from a before value to an after value. | Paired bars, when which items changed RANK is the story. |
| `bump` | Rank against time, one line per item; the crossings are the finding. | `slope`, which shows a reordering for exactly TWO time points and cannot show the path between more. |
| `volcano` | Effect size against significance, with both thresholds drawn. | A `bar` of effects, which cannot show what survived correction, or a table of p-values, which cannot show what was big enough to matter. |
| `diverging` | Signed bars either side of zero, sorted. | `bar`, for deltas — direction reads instantly. |
| `waterfall` | Steps from a starting total to a final total. | `bar`, for an ablation — it shows contributions compounding. |
| `bar_sig` | Grouped bars with significance brackets and stars. | `bar`, when the comparison being claimed is pairwise. |
| `forest` | Point estimates with confidence intervals and a null line. | `bar`, when whether an interval crosses zero is the question. |
| `radar` | A closed polygon per method over 3+ metrics. | Several bar charts, for a multi-metric profile at a glance. |
| `parallel` | One polyline per configuration across independently scaled axes. | A table, for a hyperparameter sweep — trends across axes show up. |
| `funnel` | Stage attrition with retention vs. previous and vs. intake. | `barh`, when the stages are sequential and losses compound. |
| `stacked_pct` | Composition as percentages; every bar full height. | Stacked `bar`, when categories have very different totals. |
| `treemap` | Nested rectangles with AREA proportional to value. | `bar`, only when there are too many parts for one axis — length beats area for precise reading. |
| `upset` | Set intersections as sorted bars over a membership matrix. | A Venn diagram, past 3 sets — circles cannot stay area-true and stop reading as sets. |

### Trends and relationships

| type | draws | choose it over |
|---|---|---|
| `line` | Multi-series lines with optional uncertainty bands. | The default for anything against time or steps. |
| `fan` | A median with nested quantile bands around it. | `line` with a band, when the spread is skewed or bounded — a symmetric ± band on an accuracy near its ceiling implies scores above 100%. |
| `step` | A piecewise-constant series — value holds, then jumps. | `line`, for schedules — a slope implies values that never occurred. |
| `scatter` | Points with an optional least-squares fit and R². | `line`, when x is not ordered and the relationship is the point. |
| `joint` | Scatter with the marginal distribution of each variable beside it. | `scatter`, when "and how is each one distributed?" is the obvious next question — which for a headline correlation it always is. |
| `splom` | Every pair of variables as its own scatter, distributions down the diagonal. | `corr`, when the SHAPE of each relationship is the claim — one number cannot tell a straight line from two clusters or an outlier. |
| `bubble` | Scatter with a third variable as marker AREA, plus a size key. | `scatter`, when a third quantity matters but not enough for its own axis. |
| `scaling` | Log-log points with a fitted power law and its exponent. | `line`, for scaling laws — the exponent is computed and annotated. |
| `speedup` | Measured speedup against worker count, with the ideal line. | `line`, for parallel results — the ideal reference is what the claim is measured against. |
| `pareto` | Scatter with the non-dominated frontier drawn through it. | `scatter`, for trade-offs where the frontier is the finding. |
| `area` | Stacked areas — a total and how it divides. | `line`, when the total matters as much as the parts. |
| `residual` | Residuals against fitted values, with the zero line. | Predicted-vs-actual, where heteroscedasticity hides on the diagonal. |
| `bland_altman` | Difference between two methods against their mean, with limits of agreement. | A scatter of A against B, where the diagonal reads as agreement and r = 0.99 hides a 10% offset. |
| `acf` | Autocorrelation per lag as stems, with the significance band. | `line`, which shows the level and hides whether each point predicts the next. |
| `sankey` | Flows between stages at proportional widths. | `area`, when what matters is what became what. |
| `timeline` | Gantt-style spans, one row per task. | A table of timestamps, when overlap and duration are the point. |

### Model evaluation

Give these raw `labels` and `scores` rather than a precomputed curve wherever
you can: the renderer sweeps the threshold itself, so the AUC or AP in the
legend is integrated from the points actually drawn and cannot drift from
the curve beside it.

When only the curve survives — it came from a paper, or from a logged
artefact — pass it directly instead: `fpr`/`tpr` for `roc`, `recall`/
`precision` for `pr`, `probabilities`/`labels` for `calibration`. The
summary statistic is still integrated from the plotted points, so a PR curve
that stops short reports `AP = 0.375 up to recall 0.60` rather than quietly
extrapolating the rest. One evaluation set per figure: `pr`'s baseline and
`calibration`'s bins both move with class balance, so curves from different
test sets cannot share axes honestly.

| type | draws | choose it over |
|---|---|---|
| `roc` | ROC curves with AUC in the legend, plus the chance diagonal. | `pr`, when the classes are roughly balanced. |
| `pr` | Precision-recall curves with average precision and the prevalence baseline. | `roc`, when positives are rare — ROC flatters a rare-class model. |
| `calibration` | Reliability diagram with the ideal diagonal, ECE, and per-bin counts. | `roc`/`pr`, when whether to TRUST a probability is the question. |
| `learning_curve` | Score against training-set size, train and validation with ±std bands. | `line`, to show whether more data or a better model is the bottleneck. |
| `qq` | Sample quantiles against theoretical normal quantiles, with a reference line. | `hist`, for judging normality — the eye reads a straight line far better than a bell. |
| `cd_diagram` | Mean ranks over many datasets, joining methods a test cannot separate. | `bar_sig`, which compares pairwise on ONE dataset — this is the many-datasets headline figure. |

### Distributions

| type | draws | choose it over |
|---|---|---|
| `box` | Median, quartiles, whiskers, outliers per group. | The compact default for a few groups. |
| `violin` | Full mirrored density per group. | `box`, when a distribution may be multi-modal — a box hides that. |
| `strip` | Every raw observation, jittered, with the mean marked. | `box`, when n is small enough that each point should be visible. |
| `beeswarm` | Every observation, packed sideways so none hides another. | `strip`, whose random jitter still overlaps at any real n — the eye reads the clumps as density and they are partly collision. |
| `ridgeline` | Stacked density curves, one row per group. | `violin`, past ~6 groups, where a violin grid gets too wide. |
| `raincloud` | Half violin, box and jittered points together, with n. | `violin`, when the reader must see the observations — twelve seeds look as smooth as twelve thousand. |
| `hist` | Binned counts or density. | `ecdf`, only when the shape of ONE distribution is the point. |
| `ecdf` | Empirical cumulative distribution, stepped. | `hist`, for comparing distributions — no bin width to argue about. |
| `survival` | Kaplan-Meier curves with censoring ticks and confidence bands. | `ecdf`, when some subjects have not finished — an ECDF must drop or invent those. |
| `hexbin` | Hexagonal density bins with a colourbar. | `scatter`, past ~2000 points where it becomes a solid blob. |
| `hist2d` | A joint distribution as a rectangular binned grid. | `hexbin`, when the axes are naturally rectangular. |

### Matrices and fields

| type | draws | choose it over |
|---|---|---|
| `heatmap` | Annotated matrix with a colourbar. | A table, when the pattern matters more than the digits. |
| `seqheat` | A per-token quantity drawn on the tokens themselves. | `heatmap`, for anything measured per token — it puts indices on an axis and leaves the reader rebuilding the sentence from a legend. |
| `corr` | Correlation matrix, diverging map centred at zero. | `heatmap`, for correlations — sign reads from colour direction. |
| `contour` | Filled contours of a 2-D field, levels labelled. | `heatmap`, for a smooth field like a loss surface. |
| `clustermap` | Heatmap with rows and columns reordered into their clusters, trees drawn beside. | `heatmap`, whenever the row order is arbitrary — block structure that is obvious once reordered is invisible in the order the log happened to emit. |
| `catmap` | A grid whose cells hold a CATEGORY, with a discrete legend and no scale. | `heatmap`, for any nominal cell — expert IDs, pass/fail/timeout, which variant won. A ramp asserts that expert 4 is more than expert 1 and that 2 lies between them, and a reader takes the ordering as real. |
| `quiver` | A field of arrows: where each sample is, and where it went. | A `scatter` of the before and after positions, which carries the same numbers and leaves the reader pairing points up by eye. |

### Structure

| type | draws | choose it over |
|---|---|---|
| `dendrogram` | Hierarchical clustering as a tree, branch heights the real merge distances. | `corr`, which shows every pairwise relationship and no grouping. |
| `tree` | A rooted tree from a parent/child structure you already have. | `dendrogram`, which computes its own linkage from a matrix and cannot be given a tree — and `network`, whose force layout loses depth. |
| `network` | A graph as nodes and links, node area and edge width from the data. | A concept figure, for anything with REAL edges — an image model draws a plausible graph, not yours. Use `sankey` for flows between ordered stages and `heatmap` for a dense graph. |

### Composites

| type | draws | choose it over |
|---|---|---|
| `panel` | Any of the above in a lettered grid, `(a)`–`(p)`. | Several separate figures, when they are read together. |

## Spec shape

```json
{
  "type": "bar",
  "title": "Accuracy by benchmark",
  "xlabel": "Benchmark",
  "ylabel": "Accuracy (%)",
  "aspect": "16:9",
  "categories": ["ARC", "GSM8K", "HumanEval"],
  "series": [
    {"label": "Baseline", "values": [41.2, 55.8, 33.1], "errors": [1.8, 2.4, 2.9]},
    {"label": "Ours",     "values": [48.9, 67.3, 45.6], "errors": [1.5, 2.0, 2.6]}
  ]
}
```

Keys every type takes: `title`, `aspect` (`"W:H"`), `width_in` (default 7.0
— a full text-width figure), `font_pt`, `font_family`.

Keys that depend on what the type actually draws. Passing one to a type that
never reads it is REFUSED by name — *"nothing read this key"* — rather than
dropped quietly, so a figure never comes back missing what the spec asked
for. "Applies to" below is therefore the set that is accepted, not a hint:

| key | applies to |
|---|---|
| `xlabel`, `ylabel` | every type with axes, which is all of them but `panel` — a panel has none of its own, so put the labels on the sub-specs and a label at panel level is refused. `radar`, `treemap`, `sankey`, `parallel` and `upset` do read the key, but draw their own geometry with the axis turned off, so the label is accepted and never painted. |
| `xlim`, `ylim` | every type — the shared layer applies them whatever the geometry, so these two are never refused as unread. Limits that would crop data are refused rather than applied. |
| `legend_loc` | only the types that actually draw a legend, i.e. two or more named series. A one-series chart gets none, because a one-entry legend restates the y-label — and asking to place a legend that is not drawn is refused. Takes matplotlib's in-axes placements (`best`, `upper right`, `lower left`, …) and NOT `outside …`: that is what the layout pass itself uses when it moves a legend off the data, and matplotlib accepts it only on a figure legend. You do not need to ask for it — the move happens on its own. |
| `cmap` | only the eight types that encode a value as colour — `heatmap`, `clustermap`, `corr`, `hist2d`, `hexbin`, `contour`, `quiver`, `seqheat`. Anywhere else it is refused: a bar chart given a colour map is a spec expecting colour to carry a meaning that chart never encodes. The default is already perceptually uniform (`cividis`, or `RdBu_r` where the scale has a meaningful zero), so reach for this only with a reason. Rainbow and cyclic maps are refused: `jet` puts a bright band in the middle of a run that is monotonic in the data, and a reader takes the band for a boundary in the result. |

`font_family` REPLACES the font, it does not add a fallback. matplotlib uses
the first family it can find and only that one, so the font you name has to
cover everything on the figure — the script AND the Latin labels, digits and
axis numbers around it. Needed only for a script the default cannot draw —
CJK, Devanagari, Thai — and picking a script-only face (e.g. "Noto Sans Thai",
which has no Latin) trades one set of hollow boxes for another. Measured: with
that font the missing-glyph gate refuses again, naming `l`, `p` and the
digits. See *Legibility*.

Per-type keys are documented by `--example <type>`; start from the example
rather than the schema.

### Multi-panel

```json
{"type": "panel", "title": "Overview", "ncols": 2, "panels": [
  {"type": "bar", "categories": ["A", "B"], "series": [{"values": [3, 5]}]},
  {"type": "line", "series": [{"values": [1, 2, 4, 8]}]}
]}
```

Any chart type nests inside `panels`. Sub-panels are lettered `(a)`, `(b)`…
automatically — do not put the letter in the panel's own `title`, which is
how panel labels end up collided with their titles.

`ncols` and `aspect` both default from the panel count: the grid is squared
(capped at three columns, which is the most that fits at the 7-inch text
width) and the canvas is sized so each cell is about 4:3. Pinning `ncols: 4`
is allowed but leaves each cell 1.75 inches wide, which is narrower than a
labelled chart needs — it will be refused rather than drawn on top of
itself.

## How long text may be

Hard caps, checked before anything is drawn, so an over-long string is a
message rather than a figure with its labels cut off. Each was set by
growing that slot until the figure broke, then backing off:

| key | max | what happened past it |
|---|---|---|
| `title` | 120 | Never refused, never collided — it just ate the canvas. At 600 characters the chart was 38% of its own figure. |
| `xlabel`, `ylabel`, `cbar_label` | 80 | Silently CLIPPED. An x-label ran off both edges from ~90 characters, a y-label from ~50, cut mid-word, at exit 0. |
| `series[].label` | 60 | Legend entries collided at 80 and collapsed the layout at 100. |
| `categories[]`, any other text | 80 | Under a *vertical* bar the limit is 40, with a pointer to `barh` — see *Legibility*. |

A title is a heading; an axis label is a quantity and its unit. Detail
belongs in the caption, which has the full column width and as many lines as
it needs.

These are coarse budgets that cannot know the figure's real width — a
3.5-inch column fits about half as much — so the drawn result is measured
too, and anything that still does not fit is refused with the same kind of
message.

## It refuses rather than lying

The generator exits non-zero, writing nothing, when the figure would not
match its data or a reader would not be able to read it. These were live
defects, each of which exited 0 and produced a confident, plausible, wrong
picture:

- **Length mismatches.** Five categories against three values used to render
  three bars and silently drop two categories. Ragged series were zero-filled,
  inventing measurements nobody made.
- **NaN / Infinity / null / strings in values.** matplotlib draws NaN as
  *nothing*, so the gap reads as a measured zero.
- **Right-to-left text.** matplotlib does no bidi reordering and no Arabic
  joining, so Hebrew and Arabic draw left to right in isolated forms —
  reversed and unjoined. Every glyph exists, so the missing-glyph gate above
  sees nothing; the reader who can read the script is the first to know.
- **Glyphs the font cannot draw.** A missing glyph renders as a hollow box
  and matplotlib only warns. It is machine-dependent too: CJK looks right on
  a laptop with a CJK font and ships as boxes from the pipeline image.
- **Labels printed over each other.** Measured on the drawn figure, on the
  ORIENTED box of each label so a tilted tick is judged on its ink rather
  than on the much larger box around it. A 7x7 correlation matrix forced to
  `21:9` rendered its cells as `0.290.360.581.00`.
- **Labels running off the canvas.** A 300-character x-label was drawn with
  30% of itself visible, cut mid-word at both ends, with no warning.
- **A legend sitting on the data it explains.** The legend is opaque by
  design, so whatever is under it is gone rather than faint. A lone chart's
  legend is measured after layout and moved below the axes; a panel cell has
  nowhere to move it and is refused. A `timeline` in a two-column grid drew
  its legend over eight of its nine bars, and the `bar` cell beside it had
  its bar TOPS masked — GSM8K reading as ~40 where the spec said 55.8.
- **Keys nothing reads.** `x_label`/`y_label` instead of `xlabel`/`ylabel` is
  a natural guess; it used to be accepted in silence and the figure came back
  with no axis labels at all — failing the first item on your own checklist,
  visibly only if you look closely. Every key is now checked against what the
  render actually looked up, at every level, so a typo inside a series or a
  panel is caught too, and the message suggests the real spelling.
- **A series drawn without a name while its neighbours have one.** The
  legend names only the series that carry a `label`, so the rest are drawn
  and left unidentified — three series with two labelled shows blue, amber
  and green bars and names two colours. Nothing about the picture looks
  wrong, which is what makes it worth refusing. Naming none of them is fine:
  that is a chart with one meaning, and the y-label carries it.
- **A stated limit that crops the data.** `xlim`/`ylim` outside the values,
  `vmin`/`vmax` outside the matrix, or an explicit `levels` list narrower than
  `z`. Each one hides part of the finding while the axis or colourbar states a
  range the data does not have: `vmax: 0.3` on a matrix running 0.10..0.95
  painted 0.30 and 0.95 the identical yellow under a bar labelled
  0.100..0.300, and `levels: [2.6..3.2]` over a field of 2.3..4.6 left 70% of
  the plot area as bare page — the basin holding the optimum included, drawn
  exactly like no-data. Cropping is a legitimate wish; it just has to be a
  stated one, so widen the limit or drop it and let the axis fit.
- **Non-positive values on a log axis.** matplotlib MASKS them rather than
  complaining, so the figure comes back with fewer points than the data. Five
  points drawn trending up carried a fit annotation reading `y = -1.75x +
  53.2`, because the slope was still computed over the two at `x = 0` that the
  reader cannot see. Applies wherever `logx`/`logy` does — `line`, `scaling`,
  `scatter`, `pareto`.
- **A negative band in a stacked chart.** Bands and segments are drawn end to
  end, so a negative one folds back over the one beneath it and every height
  stops matching its value: 10 / -8 / 5 drew as three bands of 10 / 8 / 5,
  with a top edge of 10 where the total is 7. Use `line` with one line per
  part for signed quantities. Same for stacked `bar` and `stacked_pct`.
- **Tied scores in a `bump` chart.** It has one row per rank, so a tie can
  only be broken by the order the series happen to appear in — two models
  level at 80.0 drew as a permanent one-rank gap, and moving them past each
  other in the spec, numbers unchanged, showed a crossing that is not in the
  data. Crossings are what this chart type is read for. Use `line`, or
  `slope` for two periods, which draw the scores themselves.
- **Two series a reader cannot tell apart.** The palette holds eight colours
  and wraps; the dash pattern is a second channel and multiplies that to 32
  for line charts, but a solid shape has no dash. A twelve-series `bar`
  shipped four PAIRS of identical swatches and a fifty-series `line` wrapped
  both channels at series 32. Measured on the drawn legend, so it holds for
  bars, lines and markers alike — and `bubble`'s size key, whose entries
  share a colour on purpose, is judged on size as well and passes.

Errors name the offending key and index (`series[1].values has 2 entries but
5 were expected`), so a bad spec is one edit from correct. Nothing partial is
ever written — a half-file would pass the downstream existence check.

## Legibility

- **Non-Latin scripts.** The default font covers Latin, Greek and Cyrillic —
  all three verified, not assumed. Hebrew and Arabic are refused even though
  the glyphs are there: matplotlib does no bidi reordering and no Arabic
  joining, so it draws the characters left to right in isolated forms and the
  label comes out reversed and unjoined, with every glyph present and nothing
  else noticing. Transliterate, or write the label in the paper's own script.
  For any other script set
  `font_family` (e.g. `"Noto Sans CJK JP"`) — matplotlib uses the *first*
  resolvable family and does no per-glyph fallback, so the covering font has
  to go first. Without it the figure is refused rather than shipped full of
  boxes.

  **`font_family` only helps where that font is installed, and the pipeline
  image has none.** It ships 23 families, not one of which covers CJK, Indic
  or Thai — so inside the image the escape hatch resolves to nothing and the
  figure is refused either way. The refusal now names the FONT rather than
  the script: a name that does not resolve is caught before anything is
  drawn, with the closest installed families listed, because matplotlib
  otherwise falls back in silence and the glyph gate then blames the text.
  Label it in Latin script, or add the font to
  `Dockerfile.pipeline` (Noto Sans CJK is ~20 MB). On a developer machine
  with the font present it works: verified rendering a Japanese title and
  Japanese category labels with no missing glyph.
- **Dense categories.** Labels wrap when long, tilt at 30° when that isn't
  enough, and stand up at 90° when even that collides — where neighbours
  cannot touch however long they get. Which of the three applies is decided
  by MEASURING the drawn labels against the axes after layout, so a panel
  cell gets the treatment its own width needs rather than the one the whole
  figure's width would suggest. Names past ~40 characters do not fit under a
  vertical bar at all and are refused with a pointer to `barh`, which puts
  the label on the y-axis where the full width is available.
- **Column-width figures.** `width_in: 3.5` works for the ordinary types —
  bar, barh, line, scatter, box, hist, ecdf, heatmap — provided the spec is
  written for that size: about four categories, two or three series, and a
  title under ~45 characters. These of the catalogue's own examples are
  refused at 3.5 inches, because each is written for the full text width —
  the list is pinned by a test that measures it, so it cannot go stale:

  > `bar_sig`, `bland_altman`, `bubble`, `bump`, `catmap`, `cd_diagram`,
  > `clustermap`, `contour`, `corr`, `dendrogram`, `dumbbell`, `fan`,
  > `funnel`, `panel`, `parallel`, `radar`, `sankey`, `seqheat`, `slope`,
  > `speedup`, `survival`, `timeline`, `treemap`, `upset`, `volcano`

  A leaner spec fits for every one of them — measured, including the
  label-dense ones (`corr`, `upset`, `sankey`, `treemap`, `parallel`,
  `radar`, `cd_diagram`), which only refuse above a lower ceiling than the
  ordinary types. Three one-letter categories draw at 3.5 inches; `upset`
  is the tightest, taking two sets before its own "Intersection size" axis
  label runs off the edge. What the list above says is that the SHIPPED
  EXAMPLES do not fit, because each is written for the full text width.
  Every refusal names what is in the way, and `upset` and `cd_diagram`
  quantify it ("the method names need 4.2 inches of margin") rather than
  shipping something unreadable.
- **Many series.** Past eight the palette wraps, so the line style becomes a
  second channel — otherwise series 1 and 9 were the same colour. Past six,
  the legend moves below the axes. Inside, it
  covered the data at twelve series and hid a tick label; outside, layout
  reserves real space for it.
- **Long titles** are measured after layout and wrapped. On a chart whose
  axes is a narrow strip (a `barh` with long names) the title is promoted to
  a figure heading, since an axes title would centre on the strip and run
  off the page.
- **`$` is safe.** A matched pair used to be read as mathtext, so
  "Cost $5 to $9" rendered as "Cost 5to9". All user text is now escaped, so
  dollars print verbatim. The trade: mathtext is unavailable — write
  superscripts in Unicode (`R²`, `10⁻³`), which the fits already do.

## What the house style already handles

Do not re-solve these; they are set globally in `chart_style.py`.

- **Colourblind-safe palette** (seaborn's `colorblind` set). Never override
  it with a red/green pair. The separations are measured, not assumed: the
  closest pair is ΔE*ab 14.0 under protanopia and 10.3 under deuteranopia,
  against a just-noticeable difference of ~1. **Greyscale print separates
  the first three series and no more** — past that the lightnesses cluster,
  and violet against grey is ΔL* 0.3, the same shade in print. If the paper
  will be read in B&W, keep it to three series or give the extras a second
  channel of your own.
- **Sans-serif**, sized for the figure's final print size.
- **No chartjunk** — no 3D, gradients, shadows, coloured plot background;
  faint horizontal grid behind the data only.
- **Constrained layout**, so an axis label can never be clipped off the
  canvas. This was the single most common defect across every library
  surveyed, including in otherwise flawless output. Layout alone does not
  cover TITLES — it reflows axes but cannot wrap a line — so titles wider
  than their axes are measured after layout and wrapped.
- **TrueType (Type 42) fonts, never Type 3.** matplotlib emits Type 3 by
  default and **IEEE and ACM submission systems reject PDFs containing
  it**, so every default matplotlib figure is non-compliant.
- **Legend headroom** — the y-range is widened before an inside legend is
  placed, because `loc="best"` lands on the data when nothing is free. Where
  headroom cannot help — a horizontal chart, whose free space is on the
  x-axis, or a plot area that is full by construction — the placed legend is
  MEASURED against the drawn bars and moved below the axes if it covers any.
- **Very dense point clouds are drawn as a bitmap inside the vector file.**
  A scatter writes every marker as its own path — 360,000 points is a 5.7 MB
  PDF, and six of those do not fit a venue's upload limit. Past ~25,000
  points in one series the cloud alone is rasterized; the axes, ticks,
  labels and legend stay vector, so the text is still selectable and sharp
  at any zoom. Below that threshold the bitmap would be the *larger* of the
  two, so nothing changes.
- **Cell annotations are outlined against their own fill.** A heatmap's
  numbers take near-black or near-white, whichever contrasts better with the
  cell — and over a continuous colour map the better one is not always
  enough: cividis bottoms out at 4.18:1 and RdBu_r at 4.19:1, against the
  4.5:1 the rest of the style holds itself to, in exactly the mid-range cells
  that make up most of a matrix. A hairline in the opposite ink fixes that
  without touching the map, which is the part that cannot change.
- **Sub-decade log axes keep their tick labels.** A log axis spanning less
  than one decade — a loss curve from 2.90 to 2.05, say — contains no power
  of ten. matplotlib ticks only at powers of ten, so it places 10⁰ and 10¹,
  *both outside the view*, and the visible axis carries no label at all.
  Silently. Handled.

## Verify what you generated

Read the PNG back and look at it. The generator prevents the structural
defects above, but it cannot know that your data was wrong. Check:

- every number in the figure matches the number you meant to plot;
- axis labels state units;
- the caption describes what is actually drawn;
- the chart type still says what you meant once you can see it.

Two things that used to be on this list are now refused instead, so a figure
you can read back cannot have them: overlapping category labels, and a
series drawn without a name while its neighbours have one.

If a figure is crowded, widen `aspect` (`"21:9"`) or split it into a
`panel` — do not shrink the font.

## Limits

- **Hand-drawn architecture diagrams** (a pipeline, a block diagram, a
  flowchart with prose in the boxes) are out of scope: they have no
  underlying numbers and a layout engine has nothing to compute from. Those
  go to `aii-concept-fig-gen`. A graph whose edges ARE data — citations,
  message counts, co-occurrence — is a `network` here, because the picture
  has to match the edge list.
- **No LaTeX-native output.** PGFPlots produces the best camera-ready
  result of anything surveyed, because the figure text is typeset by the
  paper's own engine in the paper's own font. What is missing is a second
  backend behind 60 renderers, not the toolchain: `texlive-pictures` is
  already in the pipeline image, pulled in as a dependency of
  `texlive-latex-extra`, and a pgfplots document compiles there at exit 0.
  (This entry used to say the package was absent and would cost +81 MB.
  Measured in the built image, both halves were wrong.)
- **The legibility gate reads TEXT.** It refuses a label printed over another
  label or cut off by the canvas. A label printed over the DATA is only
  handled where a renderer registers it with `place_point_label`, which four
  types do: `pareto`, `network`, `tree` and `volcano`. If you hand-write a
  figure, call `fit_point_labels` too.
  `bubble` is the known exception. It names each bubble itself — centred
  inside when the name fits, just above when it does not — and does not
  register, so a name on a small bubble can land on a LARGER neighbour's
  face and nothing refuses it. Registering it would not currently help:
  the nudger models an axes' markers with one radius, the largest drawn, so
  on a chart whose bubbles run from 4 px to 88 px no candidate position ever
  measures clear and every name would simply stay where it started. Fixing
  it properly means per-marker radii in the clearance test. Until then, give
  a crowded bubble chart its names in a legend, or space the points.
- Still uncovered: geographic/choropleth (needs a basemap and boundary data,
  neither of which is in the image). Add a renderer to its family's
  `chart_renderers*.py` rather than hand-writing matplotlib at the call site
  — that is what keeps every figure in a paper looking like a set.
````
