# Project memory — ExpertCarCheck / triposr-runpod-worker

## Root-cause analysis method (apply whenever investigating a problem)

Saved at the user's request. When something breaks, is slow, is wrong, or
underperforms — do NOT stop at the first plausible explanation. Run this:

**Discipline**
1. Never accept the first explanation. Ask "Why?" at least five times; keep going past five if the answer is still weak.
2. Challenge every assumption (mine and the user's). If the user is wrong, say so and show why — truth over agreement.
3. Separate symptoms from causes; separate facts from opinions.
4. Consider all factor classes: human, technical, financial, operational, legal, process.
5. Build an explicit cause→effect chain. Flag where evidence is missing.
6. Give a confidence level for every conclusion.

**Output format for a problem**
- PROBLEM (exact statement)
- WHY #1 … WHY #5 (continue #6, #7… until the deepest cause is reached)
- Then: Root Cause · Evidence for · Evidence against · Confidence % ·
  Alternative root causes · Immediate actions · Medium-term fixes ·
  Long-term prevention · Risks if ignored · KPIs to monitor ·
  Early-warning indicators · Cost of doing nothing · Highest-ROI solution
- Then challenge it: "What assumptions could still be wrong?" and re-run the
  analysis from other lenses (technical, business, customer, engineering,
  finance, legal, operations, competitor).

Only produce the full template when there is a real problem to investigate —
don't fabricate an RCA when nothing is broken.

## Product context (for fast re-grounding)

- **Goal:** UK reg → premium, near-instant, interactive 3D car.
- **Architecture (two tiers):** Tier A = hand-built/licensed interactive hero
  models (future). Tier B (live) = material-separated GLB → GPU clean-studio
  turntable → frames in Supabase → drag-to-spin viewer. AI (TRELLIS.2) is an
  offline gap-filler only; never on the user's request path.
- **Serving Supabase (renders/catalogue):** `tfkvthprsntexrcuqpyd`, bucket
  `car-renders` (public). Meshes in `car-meshes`. Catalogue index:
  `…/car-renders/catalogue.json`.
- **App:** Lovable project `1736441d-1aa3-495a-b319-584342507036`
  ("Expert Car Check Pro"), its own Supabase `ghglvtwohetcrrswvqhp`. The app
  fetches the public catalogue cross-origin; `VehicleShowroom3D` component is
  wired into `/check` (real reg) and `/3d-generator` (studio gallery).
- **Render worker:** `render/handler.py` → RunPod endpoint `ng8oiz4p2l0xa0`
  (OPTIX, ~5–7s/frame, scale-to-zero). `studio` input = clean dark backdrop
  for any colour.
- **Hard rule learned:** recolour only lands cleanly on models with a real
  body-paint material — audit every new car's render before it ships.
- **Never** hardcode Supabase/RunPod/Docker secrets in the repo (push
  protection blocks them); use env vars.

## Accuracy rule — do NOT fabricate vehicle metadata (learned 2026-07-12)

The user caught me inventing generation codes (NQ5, W177, L663…), model years,
and trims for sourced GLBs that had none of that in their source. This is
hallucination and is unacceptable in a product built on data accuracy.

- **Catalogue stores only verifiable facts:** make, model, the exact source
  title (verbatim), the colour actually rendered, licence, and asset URLs.
- **Never assert year / generation / trim / fuel that I cannot verify.** If the
  source title states it, quote it as "per source"; otherwise leave it out.
- **Authoritative spec comes from the app's DVLA/DVSA decode at lookup time** —
  not from my guesses. The catalogue's only job is to match make+model → asset.
- The GLBs are sourced third-party CC-BY models (licence, not ownership); the
  "own GLB" route is photos → TRELLIS. Don't conflate the two.

## OEM paint colour resolution (saved 2026-07-13, user-specified workflow)

Database: `platform/paint/oem_paint_db.csv` — user-provided, ~270 rows, columns
`MANUFACTURER,OEM_PAINT_NAME,DVLA_COLOUR,COLOUR_FAMILY,FINISH` covering ~35
brands. This is the source of truth for OEM paint naming in the app and the
render pipeline.

**The 8-step resolution workflow (follow exactly):**
1. Search the registration through DVLA (the app's existing decode — never
   touch that wiring; the reg itself is never keyed, indexed or stored).
2. Save the broad colour returned as `dvla_colour`.
3. Identify manufacturer, model, year, VIN, trim from the decode.
4. Search the OEM paint database for paints valid for that vehicle
   (filter by MANUFACTURER).
5. Filter those candidates by the DVLA broad colour (DVLA_COLOUR column).
6. Image colour analysis may only be used to RANK the remaining candidates —
   never to decide.
7. **Never claim an exact OEM paint code/name from an image alone.**
8. Display as "Possible OEM colour: <name>" (unconfirmed) until confirmed by
   VIN, paint label, or manufacturer record.

Render-side use: COLOUR_FAMILY maps to the render palette (e.g. family
"Gunmetal Grey" → `gunmetal` palette entry); the OEM name is display metadata
only, per rules 7–8.

## Investigation log

### 2026-07-12 — "Why is the 12-car render batch so slow?" (confidence ~85%)
- **Problem:** a 12-car turntable batch (432 frames) took ~30+ min and felt stuck.
- **5-Whys → root cause:** the batch is hundreds of tiny serverless jobs through a
  quota-limited, throttled RunPod endpoint, processed **sequentially per car**.
  - Effective GPUs were ~4, not the 8 requested (`running:4, throttled:1`).
  - RunPod caps this account at **10 serverless workers across ALL endpoints**
    (patch to 10 → 400 "quota of 10"); persistent `throttled:1` from GPU-type capacity.
  - `workersMin:0` scale-to-zero → cold starts (~30–60s) between cars.
  - Script waits on each car's slowest frame, and commits the catalogue **all at
    once at the end** (fragile: one hung car blocks all 12 from going live).
- **Evidence it was NOT a hang:** Python proc idle-waiting (low CPU), 10/12 manifests
  committed steadily.
- **Fixes:** (1) commit catalogue **incrementally per car**, not all-at-end;
  (2) submit all frames in **one parallel pool** so workers stay saturated (no
  per-car gaps); (3) for big runs use a **dedicated pod** — its GPUs sit outside
  the 10-worker serverless quota and never cold-start. This validates the user's
  repeated "put it on a pod" instinct: the pod is the real lever for batch speed.
- **KPIs to watch:** endpoint `throttled` count, `inQueue` depth, wall-time/frame,
  cold-start gaps between cars.
