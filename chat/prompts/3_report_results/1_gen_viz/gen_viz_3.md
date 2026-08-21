# gen_viz_3 — report_results

> Phase: `gen_paper_repo` · `gen_viz`
> Run: `run_dX5VwxrQ9qyp` — The Founder Fade Curve: Trajectory Shape as a Complementary Predictor of OSS Project Survival
>
> Full, verbatim record of every prompt the AI Inventor pipeline gave this agent — system-user, human-user and skill-input — in the order they landed. Nothing truncated.

## Task: `gen_viz_3` (sdk_openhands_agent)

### [1] SYSTEM-USER prompt · 2026-08-21 01:53:55 UTC

````
<workspace>
Your workspace: `/ai-inventor/aii_data/runs/run_dX5VwxrQ9qyp/4_gen_paper_repo/_2_gen_viz/gen_viz_3`

CRITICAL: Every file you create, write, or save MUST be inside this workspace directory (subdirectories OK). You MUST NOT write files anywhere outside this path — external paths are READ-ONLY. Use absolute paths for all file operations.

EVERY file write MUST start with `/ai-inventor/aii_data/runs/run_dX5VwxrQ9qyp/4_gen_paper_repo/_2_gen_viz/gen_viz_3/`:
GOOD: `/ai-inventor/aii_data/runs/run_dX5VwxrQ9qyp/4_gen_paper_repo/_2_gen_viz/gen_viz_3/file.py`, `/ai-inventor/aii_data/runs/run_dX5VwxrQ9qyp/4_gen_paper_repo/_2_gen_viz/gen_viz_3/results/out.json`
BAD: `/tmp/file.py`, `~/output.json`, `./file.py`, any path outside the workspace
</workspace>

<task>
Generate a publication-quality figure for a top-tier venue research paper that exactly follows the provided specification.

Use the aii-concept-fig-gen skill to generate the figure in the aspect ratio from the spec. ALWAYS pass `--model flash --style neurips` to EVERY concept_fig_gen.py call (this run uses the **flash** Gemini image tier). `--style neurips` appends the paper style — white background, sans-serif labels, no 3D or shadows or gradients — so the tool carries it on every call instead of you having to remember it in every prompt. Be as detailed as possible in your image generation prompt: include all data values, axis labels, ranges, legend entries, preferred colors, and describe where each element should be positioned. Then END the prompt with a separate sentence listing the words that must appear, verbatim — "The boxes read Tokenizer, Transformer, Classifier." Naming them inside the layout sentence instead is what turns Encoder into `Enc:der`; every measured run that stated them as their own closing sentence spelled all of them correctly, and word length made no difference either way.

IMPORTANT — Two-phase workflow: explore cheaply at 1K, then finalize at 2K. Create a subfolder `fig3_all/` in your workspace for ALL attempts.

PHASE 1 — Explore at 1K (HARD LIMIT: 5 attempts):
- Generate at `--model flash --image-size 1K` (fast and cheap). Save attempts as `fig3_all/fig3_v0_it1.jpg`, `fig3_all/fig3_v0_it2.jpg`, … up to `_it5.jpg`.
- After EACH attempt, read the image back and verify it against the checklist below. If it has issues, regenerate with a corrected prompt.
- Do AT MOST 5 generations in this phase — stop early as soon as one is clean. Then pick the single best 1K attempt (the "chosen base").

PHASE 2 — Finalize at 2K (EXACTLY 2 upscale passes of the chosen base):
- Run EXACTLY TWO generations at `--model flash --image-size 2K`, each in edit mode passing the chosen base as the input image (`--edit` the chosen base .jpg). Instruct it to upscale and sharpen while preserving the exact layout, data values, labels, and composition — and to fix any remaining issues from the checklist.
- Save them as `fig3_all/fig3_v0_2k_1.jpg` and `fig3_all/fig3_v0_2k_2.jpg`.
- Read both back, verify both, and choose the better of the two as the final figure.
- IF THE GENERATOR REFUSES EDIT MODE — on a $0 run the free image provider has no
  edit endpoint at all, and the tool says so ("the free image variant cannot edit
  an existing image") before spending anything — then SKIP this phase entirely and
  deliver the best PHASE 1 attempt. Do NOT pass `--paid` to get around it: that puts
  paid image spend on a run chosen to be free, which is the single largest line item
  a "free" run has ever been billed.

DELIVERABLE:
- Copy the chosen final image to your workspace root as: fig3_v0.jpg — the
  chosen 2K upscale when phase 2 ran, and the chosen 1K attempt when it could not.
- The file `fig3_v0.jpg` is the deliverable — everything in `fig3_all/` is reference only.

Verification checklist (apply after EVERY generation in BOTH phases). Check for:
- Layout issues (e.g. text too close together, figure looks cluttered, elements crammed into corners)
- Overlapping or touching labels, legends, or annotations
- Cut-off or truncated text, axis labels, or titles
- Wrong or missing data values, bars, lines, or data points
- Incorrect axis ranges, tick marks, or scales
- Missing or misplaced legend entries
- Blurry text, unreadable font sizes, or poor contrast
- Wrong font family (MUST be sans-serif like Helvetica/Arial — reject any serif fonts like Times New Roman)
- MISSPELLED labels. Read every word in the image letter by letter against the word you asked for. This is the most common defect by a wide margin — `erooder` for Encoder, `routter` for Router, `conveged?` for converged? — and it is the one that survives a glance, because the shape of the word is right
- Invented text you never asked for. A prompt ending "no text of any kind" came back lettered with `Kat q` and fake axis ticks, so absence has to be checked too, not assumed
- A box, arrow or panel that is duplicated, missing, or pointing nowhere, even when every word in the image is spelled correctly

In Phase 1, if ANY issue is found — even minor — do another attempt (within the 5-attempt limit). Do NOT accept a figure with problems as the chosen base.

Change the prompt only when the prompt is what was wrong — a word you never specified, an element you forgot to name. For a defect the prompt already rules out, re-run it UNCHANGED: the same prompt sent twice gave a correct three-box chain once and four boxes with one label repeated the other time. Rewriting a prompt that was already right spends one of five attempts on a variable that was not the cause.
</task>

<figure_specification>
Figure ID: fig3
Title: Case Study Fade Curves
Caption: Representative founder fade curves for surviving (top row) and collapsed (bottom row) projects. Surviving projects (node, Homebrew, bootstrap) show gradual decline over 12-24 months. Collapsed projects (request, grunt, component) show plateau-then-cliff patterns. These qualitative observations are consistent with the scaffolding fade hypothesis but require larger samples for statistical confirmation.
Image Generation Description: Two-row grid of six small line plots. Top row (surviving projects): Three plots labeled 'node', 'Homebrew', 'bootstrap', each showing a green line starting high (0.7-0.9) and declining gradually over 12-24 months to near zero. X-axis: 'Months before departure', Y-axis: 'Founder commit share'. Bottom row (collapsed projects): Three plots labeled 'request', 'grunt', 'component', each showing a red line staying flat at 0.6-0.8 for most of the timeline then dropping sharply in the final 2-3 months. Each plot has the same axis labels. A legend at the bottom: green = survived, red = collapsed. Clean sans-serif font, white background, no 3D effects.
Aspect Ratio: 16:9
Summary: Six case study plots showing actual fade curves for surviving vs collapsed projects
</figure_specification>

<critical_requirements>
1. Accurately represent ALL data values described above — include every number mentioned
2. Do NOT invent additional data points beyond what is described
3. Include clear axis labels only if the figure has axes (not for diagrams/flowcharts)
4. FONT: ALL text MUST use sans-serif font (Helvetica/Arial). NO serif fonts (Times New Roman). Always include "Sans-serif font throughout (Helvetica/Arial style, NOT Times New Roman)" in your image generation prompt. This is the #1 most common issue — check it first during verification
5. Publication camera-ready style: white backgrounds, properly formatted axes, no 3D effects/shadows/gradients. Follow aii-concept-fig-gen skill for image generation, prompting best practices, and figure type templates
6. TEXT SPACING: Ensure generous spacing between ALL text labels. Labels MUST NOT overlap or touch. Use large readable font sizes (minimum 12pt equivalent). If labels would overlap, stagger them vertically, use leader lines, or abbreviate. For multi-panel figures, add clear padding between panels
7. RESOLUTION: Explore at 1K (Phase 1), then finalize with two 2K upscale passes of the chosen base (Phase 2) — see the two-phase workflow above. Do NOT use 4K. For multi-panel or detail-heavy figures, use wider aspect ratios to give elements room
8. MANDATORY VERIFICATION: After EVERY generation attempt, read the image and check font first (sans-serif?), then layout, data accuracy, and readability. If anything is wrong, regenerate. Do NOT stop at the first attempt
</critical_requirements>


---

Output the result as JSON to: `/ai-inventor/aii_data/runs/run_dX5VwxrQ9qyp/4_gen_paper_repo/_2_gen_viz/gen_viz_3/.sdk_openhands_agent_struct_out.json`

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

IMPORTANT: this task is NOT complete until `/ai-inventor/aii_data/runs/run_dX5VwxrQ9qyp/4_gen_paper_repo/_2_gen_viz/gen_viz_3/.sdk_openhands_agent_struct_out.json` exists and contains JSON matching the schema above.
````

### [2] HUMAN-USER prompt · 2026-08-21 01:53:55 UTC

```
What determines whether an open-source project survives its founder stepping away?
```

### [3] SKILL-INPUT — aii-concept-fig-gen · 2026-08-21 01:54:13 UTC

The agent loaded the **aii-concept-fig-gen** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-concept-fig-gen
description: AI image generation and editing via OpenRouter's images API on Gemini models (gemini-3.1-flash-image-preview / Nano Banana 2 by default; `--model pro` for gemini-3-pro-image-preview / Nano Banana Pro), with aspect ratio control, retries, and parallel batch support. Use for CONCEPT FIGURES (figure_type='concept') — conceptual artwork, architecture and flow diagrams, cover images, anything with no underlying dataset. For DATA FIGURES (figure_type='data') that plot numbers — bars, curves, scatter, heatmaps, confusion matrices, scaling laws, distributions — use aii-data-fig-gen instead — it renders from the data, so the figure cannot disagree with it.
---

# Image Generation & Editing (nano_banana)

> **Not for data figures.** An image model approximates numbers: bars come
> back close to but not equal to their labels, and axis ticks do not divide
> evenly. Nothing downstream detects it. If the figure has numbers behind
> it, use `aii-data-fig-gen`, which renders them deterministically.

Generate images via OpenRouter's dedicated images API (`/api/v1/images`) through the ability server, on the two Gemini "Nano Banana" tiers. The `OPENROUTER_API_KEY` lives on the ability server — this skill routes requests through `call_server()`.

## Setup

```bash
SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-concept-fig-gen"
G="$SKILL_DIR/scripts/concept_fig_gen.py"
PY="$SKILL_DIR/../.ability_client_venv/bin/python"
```

## Generate Image

```bash
$PY $G --prompt "prompt describing the image" --output output.jpg --aspect-ratio 16:9
```

## Free vs paid — check before you generate

Two billing paths. **You do not normally choose**: the run's backend already
set the default, and the flags below only override it.

| Path | Provider | Cost | Editing |
|---|---|---|---|
| paid (default) | OpenRouter · `gemini-3.1-flash-image-preview` (Nano Banana 2) | ~$0.067/image @1K | yes |
| `--free` | Cloudflare Workers AI (FLUX / SDXL), then Hugging Face (SD3) | $0 | no |

`--free` serves inside Cloudflare's 10,000-neuron **daily** free allocation.
Gemini has no free image tier at all, so this is the only genuinely $0 route.

**`flash` is not one price.** ~$0.067/image at 1K but ~$0.101 at 2K, measured
live at $0.1017 for a 2K edit. It matters because the figure step deliberately
uses both: it explores at 1K and then makes exactly TWO 2K passes per figure,
so those two passes alone cost ~$0.20 a figure rather than the ~$0.134 the 1K
number implies. `pro` is flat at ~$0.134 across 1K and 2K, so it is only twice
the price of flash at 1K and about a third more at 2K.

The paid path has two quality tiers, selected with `--model` (orthogonal to
`--free`/`--paid`): the default `flash` (Nano Banana 2, ~$0.067/image @1K) and
`pro` (`gemini-3-pro-image-preview` / Nano Banana Pro, ~$0.134/image @1K-2K —
higher fidelity for hero/cover figures). **You do not normally choose this
either**: the pipeline sets it from the run's `gen_paper_repo.viz_gen.image_model`
config, and the Max/Ultra presets pick `pro`. A `pro` call that exhausts its
retries falls back to `flash`, and every charge the provider reports is
recorded — including one on a response that came back priced and carrying no
image, which is a refusal (quota, moderation) rather than a blank a retry
fills in. Such a response is not asked for again at the same price, and the
figure's failure still names what the body said.

- **On a free-tier run the default is already `--free`** (the backend exports
  `AII_FREE_TOOLS=1`). Do not pass `--paid` there: six figures on the paid
  path cost $0.81, which was 78% of a measured "free" run's entire bill.
- Pass `--paid` only when you must EDIT an existing image, which the free
  provider cannot do — it takes a prompt with no image input.
- The free path has TWO providers and walks between them. Cloudflare's
  10,000-neuron daily allocation is shared with the free LLM pool, so a busy day
  spends it; the call then fails over to Hugging Face automatically. You do not
  need to do anything for this.
- If BOTH are down the call fails. Do not silently fall back to paid on a free
  run: report it and continue without the figure.

### Free costs you the labels, not just the fidelity

The returned JSON's `model` field says which of the three served the image, and
it is worth reading: they are tiers apart on the thing concept figures are
mostly made of — words in boxes. Same prompt, same day, measured live:

| Model that served it | Diagram | Labels came out as |
|---|---|---|
| paid `gemini-3.1-flash-image-preview` | right | all three correct |
| CF `flux-1-schnell` | right | `Enc:der`, `conveged?` |
| HF `stable-diffusion-3-medium-diffusers` | wrong | `erooder`, `routter` |

Three paid runs, three clean figures — every word right, and the flow chart
came back with the NO branch actually looping back, which neither free model
managed once. SD3 went the other way and put text in a figure that asked for
none: a prompt ending "no text of any kind" came back with `Kat q` and
`Wet ker wee Bir Sauh` lettered across it, in red and green as its two main
colours under `--style neurips`. Treat an HF-served image as a draft to check
hard, not a figure to ship.

That is where the $0.067 goes, so spend the verification effort to match: on a
free run read every word in the image letter by letter, and on a paid one look
first for the things a good speller still gets wrong — a stage you do not have,
an arrow the wrong way round.

None of it is checked automatically. `success: true` means a valid JPEG of the
right size arrived — nothing reads the words in it.

## Edit Image

```bash
$PY $G --edit input.jpg --prompt "Make the background blue" --output edited.jpg
```

**Parameters:**
- `--prompt` / `-p` (required) — image description or edit instruction
- `--output` / `-o` (default: `./generated_image.jpg`) — output file path (always saved as `.jpg`; suffix is forced)
- `--edit` — path to source image for editing (omit for generation)
- `--aspect-ratio` (default: `16:9`) — valid: `1:1`, `2:3`, `3:2`, `3:4`, `4:3`, `4:5`, `5:4`, `9:16`, `16:9`, `21:9`
- `--image-size` (default: `1K`) — resolution: `1K`, `2K`, `4K`
- `--model` (default: `flash`) — paid Gemini tier: `flash` (Nano Banana 2, ~$0.067/img) or `pro` (Nano Banana Pro, ~$0.134/img @1K-2K). Normally set by the pipeline from `gen_paper_repo.viz_gen.image_model` (Max/Ultra presets pick `pro`); ignored on `--free`.
- `--style neurips` — appends NeurIPS academic style guidance
- `--negative-prompt` — things to exclude from the image
- `--system` — system-level style instruction
- `--timeout` (default: `180`) — the WHOLE call's deadline, and therefore the
  retry budget. Each attempt gets the lesser of 180 s and whatever is left, and
  the loop will not start one it cannot finish: with 180 s and fast failures
  (a connection error, a 5xx) all six paid attempts run, while on slow
  responses it stops and says how much budget was left rather than being cut
  off mid-request. Raise it if you want the full budget under slow responses —
  six attempts of 180 s would need 1092 s.

## Parallel Batch Generation

Use GNU `parallel` for multiple images:

```bash
export SKILL_DIR="$(git rev-parse --show-toplevel 2>/dev/null || echo /ai-inventor)/.claude/skills/aii-concept-fig-gen"
export PY="$SKILL_DIR/../.ability_client_venv/bin/python"
export G="$SKILL_DIR/scripts/concept_fig_gen.py"
parallel -j 5 -k --group --will-cite 'eval {}' ::: \
  "\$PY \$G -p \"prompt 1\" -o output_1.jpg --aspect-ratio 21:9" \
  "\$PY \$G -p \"prompt 2\" -o output_2.jpg --aspect-ratio 16:9" \
  "\$PY \$G -p \"prompt 3\" -o output_3.jpg --aspect-ratio 1:1"
```

## Preview

Do **NOT** open generated images in a GUI viewer (`loupe`, `xdg-open`, `eog`,
etc.). This skill is for automated / headless generation (e.g. pipeline figure
steps), and popping image windows clutters the user's desktop. Inspect images
programmatically if needed (read the file, check the returned JSON), not by
opening a viewer.

For interactive, human-curated review of multiple figure variants — where the
user wants to arrow-navigate batches in `loupe` — use the
`amg-iter-image-gen-human` skill instead; loupe-driven review is its job, not
this one's.

## Features

- **Model**: default `gemini-3.1-flash-image-preview` (Nano Banana 2, `--model flash`); `--model pro` selects `gemini-3-pro-image-preview` (Nano Banana Pro), which falls back to flash if it exhausts its retries
- **Auth**: API key on ability server (routed via `call_server()`)
- **Retries**: 3 attempts with exponential backoff, then fallback model — as far as `--timeout` allows, since it is the deadline for the whole call
- **Edit mode**: Edit existing images with text instructions
- **Parallel**: GNU `parallel` with `-j 5` for batch generation
- **Headless**: never auto-opens a viewer (use `amg-iter-image-gen-human` for human review)

## Prompting Tips

- Name every element and where it sits — boxes, arrows, groupings, labels.
  The model places what you describe and invents what you leave out
- **Put the labels in their own closing sentence**, not inline in the sentence
  that describes the layout. "…three boxes joined by arrows. The boxes read
  Tokenizer, Transformer, Classifier." rendered all three words correctly;
  "…three labelled boxes left to right, Encoder, Router, Decoder, joined by
  arrows…" rendered `Enc:der`. Four out of four runs that stated the labels
  as a separate final sentence spelled every one of them right, including the
  same words the inline phrasing had corrupted. Word length was not the
  driver — `Transformer` and `Classifier` both came out clean
- Specify colors, fonts, layout, and what to exclude
- Use `--style neurips` for academic papers. It also pins the figure to the
  same colours every DATA figure in the paper uses — seaborn's `colorblind`
  — and tells the model not to let red-versus-green be the only difference
  between two elements, which is the one pairing that carries no meaning for
  about 8% of male readers
- Any number that DOES appear — a throughput on an arrow, a stage count —
  has to be stated explicitly, and read back off the image to check it
  survived. If the figure is mostly numbers, it is a data figure: stop and
  use `aii-data-fig-gen`, which renders them instead of approximating them
- 1K resolution is default and most reliable

## Figure type templates

An image model draws what you name and invents what you leave out, so the
prompt for each kind of concept figure has a different set of things it
cannot omit. Start from the row that matches and add the specifics.

| Kind | The prompt must name |
|---|---|
| Architecture / pipeline diagram (`21:9`) | Every stage in order, left to right; what flows along each arrow and which way it points; which stages are yours vs. baseline or off-the-shelf; where the boundary of the system sits |
| Flow chart (`21:9` or `16:9`) | Each decision point and both of its outcomes; where a branch rejoins; the start and the terminal states; that arrows are labelled, not bare |
| Side-by-side comparison (`16:9`) | What the two panels are, in which order; that both use the SAME visual vocabulary so only the difference differs; a caption strip or heading per panel |
| Conceptual artwork / cover (`1:1`, `16:9`) | The single idea in one sentence; the metaphor and what maps to what; that no text appears unless you asked for it, since invented labels are the usual failure |

Two things every row shares: state the sans-serif requirement (`--style
neurips` does it for you), and read the image back to check that nothing was
invented — a stage that is not in your pipeline, an arrow that runs the wrong
way, a label you never wrote.

Reading it back is not optional, and re-running is a real fix. The same prompt
sent twice gave a correct three-box chain once and, the other time, four boxes
with `Encoder` in two of them and an arrow pointing at nothing — identical
text, different diagram. So a structure you cannot check by looking is a
structure you do not have; when it comes back wrong, generate it again rather
than editing the prompt, because the prompt was not what failed.

## Aspect Ratios

Pick by shape, not by venue. `--help` lists all ten; these are the ones a
paper figure normally wants.

| Ratio | Use Case |
|-------|----------|
| `21:9` | Ultra-wide — pipelines, architecture diagrams, the hero figure |
| `16:9` | Wide — side-by-side comparisons, multi-panel concepts |
| `4:3`, `3:2`, `5:4` | Standard — a single diagram with room around it |
| `1:1` | Square — a symmetric diagram, a cover image |
| `9:16`, `3:4`, `2:3`, `4:5` | Vertical — a stacked flow, a poster panel |

**If the ability server is not running**, nothing needs doing: the CLI already
falls back to running the same function in-process, so `concept_fig_gen.py`
works standalone. Verified — with no server reachable it still resolves the
free/paid path and reports its own errors ("OPENROUTER_API_KEY not set")
rather than a connection failure.

What it needs is the deps. If the import fails, install them INTO THE VENV
`$PY` names above — creating a `.venv` in whatever directory you happen to be
standing in leaves `$PY` pointing at the same broken interpreter:
```bash
CLIENT_VENV="$SKILL_DIR/../.ability_client_venv"
uv venv "$CLIENT_VENV" --python=3.12          # only if it is not there yet
uv pip install --python="$CLIENT_VENV/bin/python" \
  -r "$SKILL_DIR/scripts/server_requirements.txt"
```
````

### [4] SKILL-INPUT — aii-parallel-computing · 2026-08-21 01:54:13 UTC

The agent loaded the **aii-parallel-computing** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-parallel-computing
description: "CRITICAL PERFORMANCE SKILL. Maximize hardware utilization for compute-intensive tasks. Covers GPU acceleration, CPU parallelism, and async I/O. The difference between hours of failure and minutes of success. Use whenever writing ANY script that processes data, makes API calls, or does computation."
---

**ALWAYS parallelize. Sequential processing is unacceptable for any non-trivial workload.** A sequential script doing 1000 API calls takes hours and fails halfway. An async version finishes in minutes with proper error handling. ALWAYS ask: "Can this run in parallel?" — the answer is almost always yes.

Read aii-use-hardware skill first → get `NUM_CPUS`, `HAS_GPU`, `VRAM_GB`, `device`. Set `NUM_WORKERS` proportional to available CPU capacity — check `psutil.cpu_percent(interval=1)` and scale accordingly (e.g. 30% used → use ~70% of cores).

## Decision Tree (follow strictly)

- **I/O-bound** (API calls, downloads, web, file reads) → `asyncio` + `aiohttp` with `Semaphore(NUM_WORKERS * 4)`. NEVER do sequential HTTP requests in a loop.
- **CPU-bound, vectorizable** → GPU available: PyTorch on device / No GPU: NumPy vectorized ops. NEVER loop over array elements in Python.
- **CPU-bound, independent items** → `ProcessPoolExecutor(max_workers=NUM_WORKERS)`. NEVER process items one-by-one when they're independent.
- **Sequential** → only acceptable when items have data dependencies (each depends on the previous result).

## GPU Rules

- Use up to 90% of available VRAM — scale gradually (start small, increase after each successful run, keep 10% buffer)
- Move to device → compute → move back: `torch.tensor(data, device=device)` → `.cpu().numpy()`
- OOM fallback: catch `torch.cuda.OutOfMemoryError` → `empty_cache()` → halve batch size → retry on GPU. Keep reducing until it fits. Stay on GPU.
- Batch large data: chunk it, `del batch` between iterations to free VRAM

## Parallelism Rules

- **CPU-bound**: `ProcessPoolExecutor` + `as_completed`, pre-allocate result list indexed by submission order
- **I/O-bound**: `asyncio` + `aiohttp`, `Semaphore(NUM_WORKERS * 4)`, single shared `ClientSession`, `asyncio.gather(*tasks, return_exceptions=True)`
- Always add `tenacity` retries for transient failures, always set timeouts on HTTP requests
- **CRITICAL — `ProcessPoolExecutor` start method**: Default `fork` deadlocks with loguru (and any threading library). ALWAYS pass `mp_context=multiprocessing.get_context("spawn")` when constructing `ProcessPoolExecutor` in any script that uses loguru, threading, or async I/O. Example:
  ```python
  import multiprocessing as mp
  from concurrent.futures import ProcessPoolExecutor
  with ProcessPoolExecutor(max_workers=N, mp_context=mp.get_context("spawn")) as pool:
      ...
  ```
````

### [5] SKILL-INPUT — aii-data-fig-gen · 2026-08-21 01:54:18 UTC

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
  handled where a renderer registers it with `place_point_label`, which five
  types do: `pareto`, `network`, `tree`, `volcano` and `bubble`. If you
  hand-write a figure, call `fit_point_labels` too.
  `bubble` registers only the names it draws OUTSIDE their disc — a name
  small enough to sit inside its own bubble is already where it belongs and
  no nudge improves it. That registration became worth doing once the
  clearance test started measuring each marker against ITS OWN radius: with
  a single radius for the axes (the largest drawn) a bubble field running
  4 px to 88 px left no candidate position measuring clean, so every name
  stayed on its first guess.
  One limit remains, and it is the candidate SET rather than the model: the
  nudger tries corners a few pixels out, which cannot clear a very large
  neighbouring disc. On a crowded bubble chart a small bubble's name can
  still touch a big one — give those names in a legend, or space the points.
- Still uncovered: geographic/choropleth (needs a basemap and boundary data,
  neither of which is in the image). Add a renderer to its family's
  `chart_renderers*.py` rather than hand-writing matplotlib at the call site
  — that is what keeps every figure in a paper looking like a set.
````

### [6] SKILL-INPUT — aii-use-hardware · 2026-08-21 01:54:18 UTC

The agent loaded the **aii-use-hardware** skill; its `SKILL.md` (the instructions injected into the agent's context) follows verbatim.

````
---
name: aii-use-hardware
description: Detect hardware and use it responsibly. Covers CPU/RAM/GPU detection, memory-safe data processing, and resource-aware computation.
---

**Step 1** — Run `bash scripts/get_hardware.sh` (relative to this skill's directory).

Read the `=== CGROUP ===` section carefully. If `Type: cgroup v1` or `cgroup v2`:
- You are in a **container with hard resource limits**. Exceeding them = OOM kill, no recovery.
- **Never** use `psutil.virtual_memory().total`, `free -h`, `/proc/meminfo`, `os.cpu_count()`, or `nproc` for resource limits — these report **host** values, not your container's allocation.
- **Always** read limits from the cgroup paths shown in the output, or use the Python helpers below.
- For **runtime memory monitoring**, read current usage from cgroup too:
  - v2: `/sys/fs/cgroup/memory.current`
  - v1: `/sys/fs/cgroup/memory/memory.usage_in_bytes`

**Step 2** — Use Step 1 results to pick package variants **before** installing.

Defaults often target the most powerful environment — PyPI's `torch` ships with CUDA libs even on CPU-only hosts. Wrong variant = wasted disk, slow setup, possible import-time failures.

If `=== GPU ===` shows `No GPU`, install torch's CPU build (skips ~4.5GB of CUDA libs):
```bash
uv pip install torch --extra-index-url https://download.pytorch.org/whl/cpu
```
Same idea for any library whose wheel selection depends on detected hardware (GPU/CPU-only builds, architecture-specific wheels).

After install, sanity-check imports right away (`python -c "import torch"`). Disk-pressure or interrupted installs leave half-built wheels (e.g. `libtorch_global_deps.so` missing) — catch these before the experiment runs.

**Step 3** — Set Python constants from the Step 1 results:
```python
import os, math, torch, psutil
from pathlib import Path

def _detect_cpus() -> int:
    """Detect actual CPU allocation (containers/pods/bare metal)."""
    try:  # cgroups v2 quota
        parts = Path("/sys/fs/cgroup/cpu.max").read_text().split()
        if parts[0] != "max":
            return math.ceil(int(parts[0]) / int(parts[1]))
    except (FileNotFoundError, ValueError): pass
    try:  # cgroups v1 quota
        q = int(Path("/sys/fs/cgroup/cpu/cpu.cfs_quota_us").read_text())
        p = int(Path("/sys/fs/cgroup/cpu/cpu.cfs_period_us").read_text())
        if q > 0:
            return math.ceil(q / p)
    except (FileNotFoundError, ValueError): pass
    try:  # CPU affinity (cpuset — used by RunPod, Docker --cpuset-cpus)
        return len(os.sched_getaffinity(0))
    except (AttributeError, OSError): pass
    return os.cpu_count() or 1

def _container_ram_gb() -> float | None:
    """Read RAM limit from cgroup (containers/pods)."""
    for p in ["/sys/fs/cgroup/memory.max", "/sys/fs/cgroup/memory/memory.limit_in_bytes"]:
        try:
            v = Path(p).read_text().strip()
            if v != "max" and int(v) < 1_000_000_000_000:
                return int(v) / 1e9
        except (FileNotFoundError, ValueError): pass
    return None

NUM_CPUS = _detect_cpus()
HAS_GPU = torch.cuda.is_available()
VRAM_GB = torch.cuda.get_device_properties(0).total_mem / 1e9 if HAS_GPU else 0
DEVICE = torch.device("cuda" if HAS_GPU else "cpu")
TOTAL_RAM_GB = _container_ram_gb() or psutil.virtual_memory().total / 1e9
AVAILABLE_RAM_GB = min(psutil.virtual_memory().available / 1e9, TOTAL_RAM_GB)
```

## Step 4 — Set Memory Limits

OOM kills the entire container. **Every script MUST set RAM and VRAM limits at startup.**

Decide the budget based on what the script actually needs. Estimate data size × 2-5x for in-memory overhead, then add ~50% breathing room for temporaries. You may use up to 90% of available RAM/VRAM, but **scale gradually** — start small (e.g. 30-50%), verify it works, then increase toward the limit. Never exceed 90% to keep a buffer for the OS, system processes, and the agent runtime itself. Going over crashes the container/machine with no recovery.

```python
import resource, psutil

_avail = psutil.virtual_memory().available
RAM_BUDGET = ???  # YOU decide: estimate what this script needs (in bytes)
assert RAM_BUDGET < _avail, f"Budget {RAM_BUDGET/1e9:.1f}GB > available {_avail/1e9:.1f}GB"
resource.setrlimit(resource.RLIMIT_AS, (RAM_BUDGET * 3, RAM_BUDGET * 3))  # 3x: virtual > RSS; raises MemoryError on exceed

if HAS_GPU:
    _free, _total = torch.cuda.mem_get_info(0)
    VRAM_BUDGET = ???  # YOU decide: estimate GPU memory needs
    torch.cuda.set_per_process_memory_fraction(min(VRAM_BUDGET / _total, 0.95))  # raises OutOfMemoryError on exceed
```

## Memory-Safe Data Processing

- **One at a time**: load one large object → process → `del obj; gc.collect()` → next
- **Load only what you need**: select specific tables/columns/rows, not entire databases
- **Test small first**: run on a sample before scaling to full data to estimate memory/time
- **Free intermediates in loops**: don't accumulate large results — aggregate incrementally
- **Size before loading**: check file/dataset size before loading; if it's >30% of `RAM_BUDGET`, chunk it

## Common Mistakes (from real crashes)

- **Skipping this skill entirely** — loading data with no RAM detection, no limits, no budget. Container OOM-killed, all agents lost.
- **Using `psutil.virtual_memory().total` instead of `_container_ram_gb()`** — reports host RAM (e.g. 66 GB) when container limit is 28 GB. You MUST use the cgroup-aware functions above.
- **Loading all tables from a multi-table database at once** — one agent loaded 14 RelBench tables simultaneously, spiked past container limit.
- **Setting no memory limits** — without `resource.setrlimit` (RAM) and `set_per_process_memory_fraction` (VRAM), a runaway script OOM-kills the container instead of raising a catchable error.
- **Using `os.cpu_count()` directly** — returns host CPUs (e.g. 192) instead of container limit (e.g. 4) on RunPod/Docker. Always use `_detect_cpus()` above which checks cgroup quota → CPU affinity → `os.cpu_count()` in order.

## Hardware Use

- Keep these results in mind for ALL subsequent tasks — don't assume more than detected
- GPU if available and parallelizable, multiprocessing if multiple CPUs
- Push available resources to their full potential — don't leave hardware idle
````
