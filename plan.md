# Roadmap — Sample Results & Collect Statistics Overhaul

A staged plan to rework the bottom two stages of TinkerSim so they reuse the EDA
plotting primitives and shift Collect Statistics from a formula-builder to a
"pick the statistic you can already see" workflow.

## Vision

1. **Sample Results** should look and behave like the EDA window: **data table on
   the left, interactive plot on the right**. New draws append to the **bottom** of
   the table (chronological), not the top.
2. **Collect Statistics** should let students build a sampling distribution by
   **selecting statistics that are already visible in the Sample Results plot**
   (mean, median, SD, Q1/Q3, proportion, slope, …) rather than encoding a formula in
   dropdown pseudocode. Each selected statistic becomes a **column** in a Collect
   Statistics data table; every sampler run appends the statistic values for that
   sample as a new row. A **plotting window** on the right shows the sampling
   distribution of a chosen column, with a new **divider tool** for reading off
   proportions in a range.

Pedagogical intent: students explore and play with a sample first, decide which
statistic matters by seeing it on the plot, and only then promote it to a tracked
sampling distribution — no need to know formula syntax up front.

## Guiding constraints (from CLAUDE.md — do not regress)

- **Shared draw logic.** Both the per-run accumulation and the batch "collect N"
  shortcut must draw through `makeDrawState` / `drawStacks` / `drawMixer`. Never
  reimplement the draw loop (this previously caused a without-replacement bug).
- **Reuse, don't duplicate, plotting primitives.** This overhaul is the moment to
  extract the EDA plot's scales + dot-stacking so `EDAPlot`, Sample Results, and the
  sampling-distribution plot share one implementation (currently split across
  `EDAPlot`, `DotPlot`, `StatDistPlot`).
- **Quantiles** stay on the interpolating `quantile()` in both `computeStat` and
  `numericSummary`.
- **Plots fit vertically** — keep the "tallest column first, then shrink
  `dotSpacing`" pattern.
- Named React hook imports only; no `<foreignObject>`/`xmlns=` in SVG; shared style
  consts stay near the top.
- Stay dependency-light (no chart lib, no state lib).

## Current state (baseline)

| Concern | Where | Notes |
|---|---|---|
| Sample Results layout | `App.jsx` ~2371–2402 | Plot **left** (`DotPlot`, flex 2), table **right** (flex 1). Table uses `sampleData.slice(-60).reverse()` → newest on **top**. |
| Sample plot | `DotPlot` ~1010 | X/Y/Color/dot-size selectors, dot-stacking, **no** stat overlays. |
| EDA plot | `EDAPlot` ~1400 | Rich: numeric/time/categorical scales, box/mean/SD/LS overlays, responsive width, value labels. The target primitive to reuse. |
| EDA data table | `DataTable` ~1678 | Left-aligned table, sticky header, column highlight — the layout to mirror. |
| Collect UI | `App.jsx` ~2404–2449 | `StatDefiner` dropdown rows → `computeStat` → `distributions[id]` arrays → `StatDistPlot` per stat. |
| Stat engine | `computeStat` ~1120, `statLabel` ~1146, `FN_OPTS` ~1152 | Supports count/countVal/proportion/mean/median/min/max/q1/q3/slope/intercept with optional conditional filter. **Keep the engine; replace the UI that builds the stat spec.** |
| Collect loop | `doCollect` ~2226 | Chunked `requestAnimationFrame` loop; already uses the shared draw helpers. Good template for the batch path. |
| Dist plot | `StatDistPlot` ~1183 | Small dot plot + mean line. To be replaced by the shared plot + divider. |

## Target design

### Sample Results
- Two-column flex: `DataTable`-style table **left**, plot **right** (mirror EDA).
- Table appends newest rows at the **bottom**; auto-scroll to bottom on new draw.
- Plot is the unified EDA plot component with overlay toggles (mean/median/SD/
  box/LS/values), driven by the sample's variables — **univariate and bivariate**.
- Each overlay that resolves to a scalar statistic exposes an **"＋ track"**
  affordance (chip or click target) that promotes it into Collect Statistics. The
  plot's variable selection is what determines whether the stat is unconditional or
  conditional:
  - **Univariate numeric** → mean / median / SD / Q1 / Q3 / min / max of that var.
  - **cat × cat** → **conditional proportion** of one outcome given the other
    (`proportion` + `condVar`/`condVal`), promoted from a clicked cell.
  - **num × cat** → a numeric stat **for a specific group** (e.g. group mean =
    `mean` + `condVar`/`condVal`), promoted from a clicked group's overlay.
  - **num × num** → **LS line**, with separate "＋ track slope" / "＋ track
    intercept" affordances on the fitted line.

### Collect Statistics
- **Tracked-statistic columns** replace `StatDefiner` rows. A tracked column is a
  `{ id, fn, variable, variable2?, target?, condVar?, condVal? }` spec — the same
  shape `computeStat` already consumes, just authored by selection instead of
  dropdowns. `statLabel` still names the column.
- A **Collect Statistics data table** (left): one column per tracked statistic, one
  row per repetition. Persistent/accumulating across runs.
- **Accumulation paths (both via shared draw helpers):**
  1. *Per-run (always on)*: **every** "Draw Sample" auto-appends one row = each
     tracked stat computed on that sample.
  2. *Batch*: "Collect 500" appends 500 rows at once via the internal draw loop
     (the `doCollect` pattern). Default batch size 500.
- **Persistence & invalidation warnings.** The accumulated rows ("results") are
  distinct from the tracked-stat **columns** ("variables"):
  - **Sample-size change** → warn that it **clears the results** (accumulated rows)
    but **keeps the tracked columns**. A distribution at n=10 must not be mixed with
    one at n=20.
  - **Sampler/pipeline change** (editing or removing a device) → warn that it
    **deletes existing statistics in the table** (results), and any tracked column
    referencing a removed variable is dropped along with it.
- **Sampling-distribution plot** (right): the unified plot over one selected stat
  column, with the **divider tool**.

### Divider tool (new)
- Lives on the **shared `Plot` primitive**, so it is available anywhere a numeric
  distribution is shown — EDA, Sample Results, and the Collect Statistics
  distribution plot — not just Collect Statistics. Off by default; toggled on.
- **Availability gate (only where a continuous numeric axis exists):**
  - ✅ univariate numeric (dot plot along an x-axis);
  - ✅ num × cat side-by-side distributions (`SplitDotPlots`) — see multi-group note;
  - ❌ cat × cat grid and univariate categorical (`UniCatPlot`) — no continuous axis;
  - ❌ num × num scatter — **deferred** (a vertical divider reads as a statement
    about x alone, which is more confusing than useful here).
  - The Collect Statistics distribution plot is univariate numeric by construction,
    so the tool always applies there.
- Overlay on the plot's x-axis. Draggable handles (pointer events) **and** numeric
  inputs for exact values.
- **Single mode:** one divider → shades two regions, shows P(< v) and P(≥ v).
- **Range mode:** two dividers → shows P(< lo), P(lo–hi), P(> hi).
- Proportions computed from the plotted values (count on each side ÷ n).
- **num × cat multi-group:** one shared divider line across all groups, with
  **per-group** proportion read-outs at the same cutoff (compare "% above v" between
  groups) plus an overall read-out.

## Phased task breakdown

Each phase is independently shippable; verify with `npm run dev` after each.

### Phase 0 — Module split + extract the shared plot primitive (enabler)
Do the `components/` + `lib/` split now, as part of this phase.
- [x] Stand up `src/lib/` and `src/components/`. Keep named-hook React imports and
      shared style consts; export the style consts (`iSm`, `btnX`, `Sel`, …) from a
      shared module so import order can't reintroduce the "const not hoisted" bug.
      → `src/lib/styles.js`.
- [x] Move pure helpers to `src/lib/`: `parseCSV`, `isNumericColumn`/`colKind`,
      `quantile`, `numericSummary`, `lsFit`, `computeStat`/`statLabel`, and the shared
      draw helpers `makeDrawState`/`drawStacks`/`drawMixer`/`sampleSpinner`.
      → `lib/util.js`, `lib/stats.js`, `lib/sampling.js`, `lib/hooks.js`.
- [x] Move components to `src/components/` (`EDAPlot`, `CatCatGrid`, `SplitDotPlots`,
      `DotPlot`, `StatDistPlot`, `DeviceCard` + device cards, `DataTable`, …).
      → `components/ui.jsx`, `components/devices.jsx`, `components/plots.jsx`.
- [x] Extract the EDA plot's scale builder (`makeScale`) and dot-stacking
      (tallest-column → `dotSpacing`) into `src/lib/` so all plots share them.
      → `lib/scale.js`; `DotPlot`, `StatDistPlot`, `EDAPlot` all re-pointed at it,
      verified pixel-identical (univariate, scatter+LS, sample dot plot).
- [x] Factor a `Plot` component (controls + plot body, no bundled table) so EDA,
      Sample Results, and the distribution plot can all mount it; re-pointed `EDAPlot`
      at it. Final boundary: `{ rows, headers, xVar, yVar, setXVar, setYVar, width? }`
      — X/Y are *controlled* so a sibling data table can highlight the selected
      columns; dot size + overlay toggles are Plot-local state. Done as part of Phase 1
      against the real second consumer (Sample Results).
- [x] **Module split + shared primitives done:** production build passes; app mounts
      with no console errors; the scale/dot-stacking duplication is gone. The unified
      `Plot` component is the one remaining Phase 0 item, folded into Phase 1 below.

### Phase 1 — Sample Results layout flip (+ extract the `Plot` component) ✅
- [x] **Factor the `Plot` component** (controls + plot body, no bundled data table)
      out of `EDAPlot`, designed against both EDA and Sample Results as consumers.
      Re-pointed `EDAPlot` at it; the data table stays composed alongside by each
      context. (This is the carried-over second half of Phase 0.) → `Plot` in
      `components/plots.jsx`.
- [x] Swap the flex order: table left, plot right. New `SampleResults` component
      mirrors the EDA layout (table left, `Plot` right).
- [x] Append new rows to the **bottom**; dropped the `.reverse()`; the table scroll
      view auto-follows to the bottom as draws stream in (caps the rendered rows at
      the last 200 for perf).
- [x] Replaced `DotPlot` usage with the shared `Plot` (overlay toggles available);
      removed the now-dead `DotPlot`.
- [x] **Done:** verified in `npm run dev` — a draw fills the table top→bottom
      (# ascending, newest at bottom, auto-scrolled), table sits left of the plot,
      EDA still renders (table left + SVG plot right, Mean overlay works), production
      build passes, no console errors.

### Phase 2 — Tracked-statistic data model ✅
- [x] Add `trackedStats` state (array of stat specs) + a `collectRows` accumulator
      (array of rows keyed by stat id). → `App.jsx`; `trackStat` dedupes by
      `statLabel`, `untrackStat` drops a column. `collectRows` stays empty until
      Phase 3 wires accumulation.
- [x] Implement tracking from a Sample Results plot → toggle a stat spec (add, or
      remove if the same `statLabel` is already tracked). **Interaction (revised):
      click the number that shows the statistic on the plot** — no chips. Principle:
      *only a statistic whose number is currently visible can be collected* ("why
      track a number the student hasn't seen?"). Gated on the optional `onTrackStat`
      prop, so EDA shows no track UI and renders identically. Helpers `TrackText`
      (SVG) / `CatNum` (HTML) turn a value into a click-to-toggle button. Modes:
      - univariate numeric → click the mean / median / SD value labels (overlay
        values are force-shown in Sample Results, so the "Show values" toggle is
        hidden there);
      - cat × cat → click a cell's **count** (→ `countVal`) or **percent**
        (→ `proportion`) number, each conditioned on the cell (`condVar`/`condVal`);
        gated by the Count/Percent toggles (neither on ⇒ nothing collectable);
      - uni-cat → click a section's count/percent number (unconditional);
      - num × cat group → click a group's mean / median / SD value
        (`condVar`/`condVal`);
      - num × num LS line → click the slope / intercept value (`variable2`).
      - OTHER/collapsed buckets stay non-clickable (no clean target).
      - Added an `sd` case to `computeStat`/`statLabel`/`FN_OPTS` (population SD,
        matching `numericSummary`) so SD is trackable. Q1/Q3/min/max are not
        click-trackable (not shown as standalone numbers).
- [x] Render the **Collect Statistics data table** from `collectRows` (mirror
      `DataTable`): `CollectTable` — one column per tracked stat (named by
      `statLabel`), per-column remove (×) control. Legacy `StatDefiner` UI kept
      below for now (retired in Phase 7).
- [x] **Done when:** Clicking any plot number adds the correctly-scoped column;
      clicking it again (or the table's × ) drops it. **Verified** in `npm run dev`
      across uni-cat, cat × cat, univariate numeric, num × cat, and num × num: each
      number adds the right `statLabel` column, clicking a tracked number toggles it
      off, the no-stats-enabled gate hides all targets, OTHER buckets are inert, no
      console errors; production build passes.

### Phase 3 — Accumulation wiring + invalidation guards ✅
- [x] Per-run (always on): `doSample`'s `onDone` computes every tracked stat on the
      finished sample (`computeStat`) and appends one row to `collectRows` (skipped
      if the run was cancelled). `trackedStats` added to the `useCallback` deps so the
      closure stays fresh.
- [x] **Seed the current sample immediately.** A finished draw is stashed as
      `currentSample = { id, rows }` and its `collectRows` row is tagged with that id.
      Clicking **track** then seeds the value from the *already-drawn* sample at once
      (its number is on the plot now) instead of waiting for the next run: tracking
      updates the current sample's row in place, or creates it if nothing was tracked
      when the sample was drawn. Batch/guard clears also reset `currentSample`.
- [x] Batch: "Collect N" (default 500, `batchSize`) → `doCollectTracked` runs the
      chunked-rAF loop and appends N rows. Extracted a shared, non-animated
      `drawSample(pipeline, sampleSize)` into `lib/sampling.js` (built on
      `makeDrawState`/`drawStacks`/`drawMixer`) and re-pointed **both** `doCollect`
      (legacy) and `doCollectTracked` at it, so the with/without-replacement counting
      cannot diverge between paths.
- [x] **Sample-size change guard:** `changeSampleSize` intercepts the `n=` input; if
      `collectRows` is non-empty, confirms → clears rows, keeps `trackedStats`.
- [x] **Pipeline change guard:** `updDevice`/`remDevice` intercept edit/remove. The
      edit guard fires only on a *distribution-structure* change — `samplingShape`
      fingerprints by stable outcome **id** + count/pct/with-replacement, so it ignores
      pure relabelings and colors — to a device a tracked stat depends on; remove fires
      when a dependent column exists. On confirm → clear rows and drop columns whose
      referenced vars no longer exist (`statVarsValid`).
- [x] **Seamless rename propagation (no warning).** `propagateRenames` rewrites tracked
      specs when an edit only renames things: a device's `varName` → updates every
      `variable`/`variable2`/`condVar` that referenced it; an outcome **label** (matched
      by stable id, scoped to that device's own var) → updates `target`/`condVal`. The
      column header (`statLabel`) and future draws follow the new names while collected
      rows stay (a count is the same number whatever the label is called). Runs on every
      edit, so renames never warn; only real distribution changes do.
- [x] Declined guards call `rejectEdit` (bumps a tick) to force a re-render so the
      controlled input (n box / device fields) snaps back to its unchanged value.
- [x] Manual clear/reset control: "✕ Clear" button next to the batch controls
      (confirms, then `clearCollected`); "⬇ CSV" exports `collectRows`.
- [x] **Done:** verified in `npm run dev` (instant speed, default Stacks): tracking a
      stat seeds the just-drawn sample's value as row 1 immediately, and a second stat
      from the same sample fills the same row; per-run appends one row per later draw;
      "Collect 500" appends 500 (table caps shown at 200, mean count ≈ expected);
      renaming the device var (`stk1`→`coin`) and an outcome (`a`→`heads`) update the
      column headers with **no** warning and keep the rows, and subsequent draws compute
      correctly under the new names; a count edit still warns; sample-size guard cancel
      keeps rows + snaps n back, accept clears rows + keeps the column; device-edit guard
      same; device-remove accept clears rows + drops the dependent column; no console
      errors (incl. the now-empty pipeline); production build passes.

### Phase 4 — Sampling-distribution plot
- [ ] Column selector → render the shared plot over that stat column.
- [ ] Reuse overlay toggles (mean/SD/etc.) on the distribution.
- [ ] Retire `StatDistPlot` once parity is reached.
- [ ] **Done when:** Each tracked column can be plotted with EDA-grade styling.

### Phase 5 — Derived-statistic calculator (build statistics from collected columns)
Goal: let students **assemble new statistics from the columns they have already
collected**, rather than shipping canned formulas. A difference in means/proportions is
a short formula; an informal ANOVA-style total-variation statistic is a longer one the
student builds themselves (collect each group mean + the overall mean, then
`(mean(x|g="a") − m)^2 + (mean(x|g="b") − m)^2 + …`). No pre-built between/within button.
Depends only on Phase 4 (so a derived column inherits the distribution plot); the divider
tool (now Phase 6) then applies to derived columns for free, in either build order.

- [ ] **Derived column model.** A new tracked-column kind
      `{ id, kind:"derived", expr, inputs:[statId…] }` whose value for each row is the
      expression evaluated over that row's other collected-column values. Plain tracked
      stats stay `kind:"stat"` (or absent). `computeStat` is unchanged; derived values
      are computed by the formula evaluator against `collectRows`.
- [ ] **Backfill for free.** Because operands are already-collected columns, a valid
      derived column fills in for **every existing row** the instant it's defined — no
      re-sampling. Both accumulation paths (per-run + batch) compute derived columns
      alongside the plain ones for new rows.
- [ ] **Expression engine (dependency-light, ~100 lines).** A hand-rolled
      recursive-descent / shunting-yard evaluator over: column-reference tokens,
      operators `+ − × ÷ ^` and unary minus, parentheses, and the functions
      `sqrt` and `abs`. Pure, no library. Returns NaN if any referenced operand is
      missing in that row.
- [ ] **Click-to-insert UI (not typed).** Collected columns have verbose `statLabel`s
      (`mean(x | g="a")`), so the calculator inserts column references as **chips you
      click** (backed by a short internal alias), plus operator/function buttons and a
      live preview of the result on the current sample. Typing raw labels is not the
      path.
- [ ] **Partial-sample honesty.** Where a referenced group is absent in a sample
      (small n / without replacement), that operand is `—`/NaN, so the derived value is
      NaN for that row. Surface this rather than silently coercing.
- [ ] **Dependency invalidation.** A derived column depends on its operand columns;
      removing an operand drops or disables the derived column (a column-level analog of
      the Phase 3 `statVarsValid` variable-dependency guard).
- [ ] **Done when:** a student can collect two means and define their difference (live,
      backfilled), and can build the informal ANOVA-style statistic from several group
      means + the overall mean using `^2`, `+`, and parentheses; the derived column plots
      with the Phase 4 distribution plot; removing an operand column invalidates it.

### Phase 6 — Divider tool (shared-plot feature, gated to numeric axes)
- [ ] Add the divider as an opt-in feature of the shared `Plot`, with the
      availability gate (univariate numeric and num × cat only; hidden otherwise).
- [ ] Single-divider overlay: draggable vertical line + numeric input; shade two
      regions; display P(< v) / P(≥ v).
- [ ] Range mode toggle: second handle; display P(< lo) / P(lo–hi) / P(> hi).
- [ ] Pointer-event drag with snap-to-value and clamping to the axis domain; keep
      input and handle in sync.
- [ ] num × cat case: one shared divider across groups → per-group + overall
      proportion read-outs.
- [ ] **Done when:** the tool appears only on numeric-axis plots, and dragging or
      typing a value updates the shaded regions and proportion read-outs live
      (including per-group on side-by-side distributions).

### Phase 7 — Cleanup & retirement
- [ ] Remove `StatDefiner`, `FN_OPTS`-driven dropdown UI, and `DotPlot`/
      `StatDistPlot` if fully superseded (keep `computeStat`/`statLabel`).
- [ ] Update CLAUDE.md architecture notes + "next steps".
- [ ] Final pass: verify every device (Stacks w/ & w/o replacement, Mixer, Spinner)
      feeds both accumulation paths correctly.

## Resolved decisions

1. **Conditional filters & bivariate stats — keep, authored by plotting two
   variables.** A conditional stat is created by selecting a two-variable plot, not a
   filter dropdown: cat × cat → conditional proportion of one outcome given the
   other; num × cat → a numeric stat for a specific group. The **LS line stays**,
   with separate affordances to track its **slope** or **intercept**. (Maps onto the
   existing `computeStat` spec: `condVar`/`condVal` for conditioning, `variable2` for
   LS.)
2. **Accumulator invalidation, with warnings.** Sample-size change → warn and
   **clear results, keep the tracked columns**. Sampler/device change (incl. removing
   a device) → warn and **delete the table's statistics**; columns referencing a
   removed variable are dropped.
3. **Per-run auto-tracking is always on.** Every "Draw Sample" auto-appends a row to
   the Collect Statistics table.
4. **Do the `components/` + `lib/` split now**, as part of Phase 0 (see updated
   Phase 0 tasks).
