# Executive Summary — How to Enter & Submit to the GEMS Prize Challenge

> **Official Sources & Authoritative Documents:**
> - **Competition Platform:** [DrivenData GEMS Prize Challenge](https://www.drivendata.org/competitions/306/competition-doe-gems/)
> - **Problem Description & Submission Format:** [DrivenData Page 967](https://www.drivendata.org/competitions/306/competition-doe-gems/page/967/)
> - **About & Background:** [DrivenData Page 968](https://www.drivendata.org/competitions/306/competition-doe-gems/page/968/)
> - **Official Rules Document (OSTI 96647, Sept 2026):** [https://docs.nlr.gov/docs/fy26osti/96647.pdf](https://docs.nlr.gov/docs/fy26osti/96647.pdf) (Governed by 15 U.S.C. § 3719)
> - **HeroX Rules Resource:** [HeroX Resource 2274](https://www.herox.com/GEMSPrize/resource/2274)
> - **Training Data GDR Compilation:** [INGENIOUS Great Basin Regional Dataset DOI 10.15121/1881483](https://gdr.openei.org/submissions/1391)
> - **GeoDAWN Geophysical Survey:** [USGS ScienceBase DOI 10.5066/P93LGLVQ](https://doi.org/10.5066/P93LGLVQ)
> - **Live Project Webpage (this repository, GEMSDOE4):** [https://buffedlizard55-lab.github.io/GEMSDOE4/docs/executive_summary.html](https://buffedlizard55-lab.github.io/GEMSDOE4/docs/executive_summary.html)
- **Live Project Webpage (previous line, GEMSDOE):** [https://buffedlizard55-lab.github.io/GEMSDOE/docs/executive_summary.html](https://buffedlizard55-lab.github.io/GEMSDOE/docs/executive_summary.html)

---

## Quick Reference Facts

| Key Parameter | Official Specification | Verification / Provenance |
|---|---|---|
| **Total Cash Prize Pool** | **$300,000** | Rules §1.1 ($50k Phase 1 + $250k Phase 2) |
| **Phase 1 (Initial Round)** | **$50,000** (Top 5 split $10k each) | Evaluated on private test set of new faults (Rules §1.1, §3.6.1) |
| **Phase 2 (Final Round)** | **$250,000** (1st: $100k, 2nd: $70k, 3rd: $40k, 4th: $25k, 5th: $15k) | Evaluated on full expanded label set after expert review (§1.1, §3.6.1) |
| **Submission Deadline** | **December 3, 2026, 11:59 PM UTC** (platform close). Rules §A.1 separately sets the submission-form / final-content deadline at **5:00 PM ET (22:00 UTC) on the deadline date** — treat the *earlier* as the operative deadline | Competition Home Page (verified 2026-09-21) & Rules §A.1 (verified 2026-09-21) |
| **Submission Limit** | **Up to 3 per week**; **1 final submission chosen** | Rules §3.4 & §3.5 (selected before deadline without private scores) |
| **Projected CRS** | **UTM Zone 11N (EPSG:32611)** | Problem description & `data/sample_submission.tif` |
| **Spatial Resolution** | **100.0 m × 100.0 m** | Matches feature stack `data/training_features.tif` |
| **Grid Dimensions** | **3,292 columns × 3,730 rows** | Total raster area = 12,279,160 pixels |
| **Raster Data Type** | **Single-band 32-bit float (`float32`)** | Values in `[0.0, 1.0]` representing fault presence probability |
| **NoData Mask** | **NaN / null** outside GeoDAWN survey footprint | **57.92% NaN**; finite values strictly inside valid survey area |
| **Shipped Winning Policy** | **Floor 0.180482, k = 2 of 5, width 0 px** | Pre-registered decision rule (session 32); LOO drop of seed-correlated `nff42`, keep structurally different `po46` (proxy_only supervision) — see `docs/SESSION32_PROTOCOL.md` |
| **Shipped Raster Artifact (GEMSDOE4)** | `data/evidence/combined/submission.tif` | sha256 `c1da7dd9c44e05382b67367a8eba1987fca5594e33bf23812d308f37112dadb4` (547.1 KB; new-fault-first union of 5 detectors incl. proxy_only member, k = 2 — see `report.json`, `sanitize.json`) |
| **Suggested submission Note** | `nff-po-drop-nff42 · proxy_only diversity · union k=2 of 5 (t0=0.18, w=0)` | Unique per the dialog's "clustering with k=25" example; tells this build apart from `extradr19` / prior unions |
| **Previous artifacts (kept as evidence)** | session-31 union sha256 `19de9950ceffbdf7a7163b645984353965ab7d61dca07dfe8b9b68856edb853b` (548,834 B); 4-member union `932c2f30…` (793,704 B, in git history); deep ensemble `7f00890a…` (570.9 KB, member `deep11`) |

---

## 0. TL;DR — Submit in 5 Commands (Fastest Verified Path, 2026-09-18)

> **If you need a valid submission today, this is the fastest measured path — no training, no GPU, fully validated and ready to upload. There is now a shorter one for the file itself: the [How-to-submit page §3](https://buffedlizard55-lab.github.io/GEMSDOE4/docs/how_to_submit.html#generate) writes the submission `.tif` (or the `.zip` the dialog also accepts) in the browser, with no clone, no install and no network call — the pixels it produces are the artifact's, verified bit for bit by `data/evidence/site_generator.json`.** All commands below were re-executed in the sandbox on 2026-09-25.

```bash
git pull
python scripts/assemble_data_bridge.py   # re-verify & place 418 MB feature stack (sha256 pinned)
python scripts/prepare_data.py           # PASS: 3292×3730, 19 bands, EPSG:32611, 100 m
python scripts/validate_submission.py --pred data/evidence/combined/submission.tif --sample data/sample_submission.tif --train data/training_features.tif
# → ✅ Validation PASSED — upload the .tif below
```

**Pre-computed, validated submission artifact (GEMSDOE4 new-fault-first union — 11-fold deep ensemble ∪ classical raw-band GBM ∪ three lineament NFF detectors, emitted where ≥ 2 of the 5 agree; rule selected on held-out geography, adopted 2026-09-25 session 31):**
- **Path:** `data/evidence/combined/submission.tif`
- **sha256:** `19de9950ceffbdf7a7163b645984353965ab7d61dca07dfe8b9b68856edb853b` (548,834 bytes)
- **Policy:** union k = 2 of 5 members (`deep11`, `classical`, `nff42`, `nff43`, `nff45`); probability members floored at t0 = 0.180482, no dilation; 332,544 px at 1.0
- **Format:** 3292×3730, single-band float32, EPSG:32611, 100 m, NaN outside GeoDAWN footprint (57.92%), values in [0,1], finite on **every** pixel of the sample submission's valid region (template conformance, enforced by `scripts/validate_submission.py` since 2026-09-25)

**Then on DrivenData (requires account + enrollment):**
1. Go to **https://www.drivendata.org/competitions/306/competition-doe-gems/submissions/** → **Make new submission** → upload the `.tif`
2. Paste the **Generative AI Disclosure** (§3.2 template in §3 below) into the narrative box
3. Before **Dec 3, 2026 11:59 PM UTC** select this as your **single final submission** for both prize rounds (quota: 3/week max)

*Full training-from-scratch workflow is detailed in §6 below. Validation is mandatory — `scripts/validate_submission.py` checks CRS, 100 m resolution, single band, float32, [0,1] range, and size/transform against the competition template.*

> **Operational page:** [`docs/submission.html`](https://buffedlizard55-lab.github.io/GEMSDOE/docs/submission.html) ("Make a submission") is the same path as a checklist — artifact identity re-hashed at build time, the placement table compared against whatever `data/` holds now, the validator table parsed from its own committed log, and every rules sentence quoted by id from `data/evidence/rules_quotes.json` with its verification badge.

---

---

## 1. Challenge Architecture & The Incomplete Labels Design

The American-Made Geologic Enhanced Mapping System (GEMS) Prize is presented by the U.S. Department of Energy (DOE) Office of Geothermal (OG) and administered by the National Laboratory of the Rockies (NLR). 

**The Geological Problem:** Geothermal resources require subsurface permeability, heat, and fluid flow. Faults act as natural conduits for hot geothermal fluids. Detecting faults—particularly hidden or concealed faults that exhibit faint geophysical expressions in aeromagnetic and radiometric surveys—drastically de-risks exploratory drilling.

**The Competition Mechanism:**
1. **Public Ground Truth is Incomplete:** The training labels (`data/labels.tif`) contain known Quaternary faults from USGS maps and the INGENIOUS project. However, geologists know many regional faults remain unmapped.
2. **Hidden Test Set:** Structural geology experts manually mapped previously uncataloged faults in the GeoDAWN region using lidar and geophysical data. These *new* faults form the test set for scoring.
3. **Dual Scoring Rounds:**
   - **Phase 1:** Your selected submission is evaluated against the private withheld set of new faults. The top 5 entrants each receive $10,000.
   - **Expert Panel Discovery:** An expert panel reviews the submitted prediction rasters from all competitors to verify previously unmapped faults.
   - **Phase 2:** The ground truth is expanded by incorporating verified discoveries. All submissions are automatically rescored against the expanded ground truth, competing for $250,000 in top prizes ($100k, $70k, $40k, $25k, $15k).
4. **Single Final Submission:** Entrants must select **one single submission** before the deadline that will be scored across both Phase 1 and Phase 2. This selection occurs without knowing private test scores, rewarding genuine generalization over leaderboard overfitting.

---

## 2. Eligibility & Legal Compliance Checklist (§1.3, §1.4, App A)

All rules below are drawn verbatim from the official rules document ([OSTI 96647](https://docs.nlr.gov/docs/fy26osti/96647.pdf)):

- [x] **Individual Competitor:** Must be a **U.S. citizen or permanent resident** (Rules §1.3). Minors under 18 years of age are ineligible.
- [x] **Team Entries:** Teams are permitted. The **designated team captain must be a U.S. citizen or permanent resident**. All team members must be legally authorized to work in the United States (Rules §1.3).
- [x] **Private Entities & Academia:** Private entities must be incorporated in and maintain a primary place of business in the United States. Academic institutions must be based in the U.S. and accredited by a recognized agency (Rules §1.3).
- [x] **FFRDC Restrictions:** Federally Funded Research and Development Centers (FFRDCs) cannot compete. Individual researchers affiliated with FFRDCs may compete only in personal capacity without using FFRDC resources; they may receive honorable mention but **cannot receive cash prizes** (Rules §1.3).
- [x] **Ineligible Entities:** Non-DOE Federal employees; employees, contractors, and immediate family members of DrivenData, NLR, or DOE; debarred or suspended entities (Rules §1.3).
- [x] **Foreign Countries of Concern (FCOC) Prohibition:** Individuals participating in a Malign Foreign Talent Recruitment Program (MFTRP) sponsored by a Foreign Country of Concern (China, Russia, Iran, Belarus, North Korea) and entities controlled by FCOC governments are **strictly ineligible** (Rules §1.3).
- [x] **Commercialization Intent:** Competitors must confirm intent to commercialize early-stage technology and establish a viable U.S.-based business with revenues not solely dependent on IP licensing (Rules §1.4).
- [x] **Prize Payment Forms:** Within **30 days** of notification, winning competitors must sign and return completed NLR ACH Banking Information and IRS Form W-9 (Rules §A.2).

---

## 3. Mandatory Generative AI Disclosure (§3.2)

The official rules require all entrants using generative AI to include a disclosure statement in their submission narrative:

> *“Using generative AI technology in the development of your prize submission is allowed. However, you must **indicate in the narrative (not included in the word count)** the extent to which, if any, you used generative AI technology and how you used it to develop your submission... You are responsible for the accuracy, authenticity, and authorship representations of your submission under consideration, including content developed with generative AI tools.”* — **Rules §3.2**

### Recommended Disclosure Narrative for Submission:
```text
### Generative AI Technology Disclosure (GEMS Prize Rules Section 3.2)
Generative AI assistance (LLM agent workflows) was utilized during the development of this submission for code refactoring, verification automation, test authoring, and documentation synthesis. All algorithms, feature processing pipelines, model architectures (UNet / SegFormer / DeepLabV3+), loss formulations (Distance-Weighted Tversky loss), and post-processing emission policies (floor 0.1, thin, width 0 px) were rigorously verified against official USGS/DOE datasets and evaluated via machine-measured validation evidence. The entrant assumes complete responsibility for the accuracy, authenticity, and authorship of all code, predictions, and submission materials.
```

---

## 4. Exact GeoTIFF Submission Specifications

Submissions are strictly validated by `scripts/validate_submission.py`. Any non-conforming GeoTIFF will be rejected by DrivenData's ingestion engine.

| Attribute | Mandatory Value | Check Command / File Verification |
|---|---|---|
| **CRS** | `EPSG:32611` (UTM Zone 11N) | `rasterio.open(path).crs == 'EPSG:32611'` |
| **Pixel Resolution** | `(100.0, 100.0)` meters | `rasterio.open(path).res == (100.0, 100.0)` |
| **Grid Extents** | `3292` width × `3730` height | `rasterio.open(path).shape == (3730, 3292)` |
| **Bounding Box** | `(243350.0, 4135550.0, 572550.0, 4508550.0)` | Coordinates match `data/sample_submission.tif` |
| **Bands** | Exactly `1` band | Single floating-point prediction raster |
| **Data Type** | `float32` (32-bit floating point) | `dtypes[0] == 'float32'` |
| **Value Range** | `[0.0, 1.0]` | Continuous fault presence probability |
| **NoData Handling** | `NaN` outside valid GeoDAWN boundary | `57.92% NaN`; finite values strictly inside valid survey mask |

---

## 5. Evaluation Metric & Shipped Emission Policy

The competition metric is the **Distance-Weighted Tversky Index ($DTI_{\alpha=0.2, \beta=0.8}$)**:

$$\text{DTI}(\alpha=0.2, \beta=0.8) = \frac{\text{TP}_w}{\text{TP}_w + 0.2 \cdot \text{FP}_w + 0.8 \cdot \text{FN}_w + \epsilon}$$

where distances to ground truth are weighted by a linear triangular kernel with $R = 300\text{ m}$ (3 pixels):
$$k(d) = \max\left(1 - \frac{d}{R}, 0\right) = \max\left(1 - \frac{d}{300}, 0\right)$$

### Key Strategic Insights:
1. **4:1 Penalty Asymmetry:** False negatives ($\beta=0.8$) cost 4× more than false positives ($\alpha=0.2$). Being overly conservative destroys your DTI score.
2. **The In-Domain Trap:** If you tune your probability threshold on the known training faults (`data/labels.tif`), the optimizer selects a high floor ($t_0 \approx 0.47$) and narrow skeleton. On unseen faults (the proxy population), that calibrated policy scores only **0.0247**.
3. **The Shipped Emission Policy (`floor 0.1, thin, width 0 px`):**
   - Evaluated across 132 parameter combinations ($t_0 \in [0.0 \dots 0.9]$, width $\in [0 \dots 20\text{ px}]$).
   - Ranked **#1 of 132 candidates** by worst-case contrast across multiple independent ensembles.
   - Contrast over baseline on independent sweeps:
     - **Ensemble 1 (Run 35042805806):** DTI **0.1365** vs 0.0410 (+0.0954 contrast)
     - **Ensemble 2 (Run 35249562910):** DTI **0.0777** vs 0.0320 (+0.0456 contrast)
     - **Ensemble 1+2 Mean (Run 35275312337):** DTI **0.0999** vs 0.0304 (+0.0695 contrast)
     - **3-Ensemble Mean (16 live folds, Run 35285326679):** DTI **0.0850** vs 0.0269 (+0.0581 contrast)
   - Delivers **0.1365 proxy DTI** (48% of the top public leaderboard score 0.2854, snapshot 2026-09-21).

---

## 6. Step-by-Step Practical Submission Workflow

> **Subpage (added session 20): [How to submit, exactly](https://buffedlizard55-lab.github.io/GEMSDOE/docs/how_to_submit.html)**
> — the same procedure as a single actionable page, with a **gate table measured in this checkout**
> (`python scripts/check_submission_readiness.py` → `data/evidence/submission_readiness.json`), the
> artifact's sha256 re-hashed at build time, a CPU-only route that needs neither a GPU nor any runner
> artifact, and the human-only steps labelled `HUMAN` instead of counted as done. The long-form
> operational page is [submission details](https://buffedlizard55-lab.github.io/GEMSDOE/docs/submission.html).

### Step 1: Enroll on DrivenData
1. Navigate to [https://www.drivendata.org/competitions/306/competition-doe-gems/](https://www.drivendata.org/competitions/306/competition-doe-gems/).
2. Log in or create a DrivenData account.
3. Click **"Compete!"** and accept the official rules ([HeroX Resource 2274](https://www.herox.com/GEMSPrize/resource/2274)).

### Step 2: Ensure Competition Data is Placed & Validated
In your workspace:
```bash
# Reassemble the official competition rasters from the sha256-pinned git bridge
python scripts/assemble_data_bridge.py

# Run pre-flight check to verify projection, bounds, resolution, and band tags
python scripts/prepare_data.py
```

### Step 3: Select or Generate Your Submission Raster

#### Route A: Use the Pre-Computed Winning Ensemble Raster (Fastest & Fully Verified)
The repository contains an already generated, 11-fold ensemble mean submission with the adopted policy applied:
- **Path:** `data/evidence/runs/ens12-adopted-floor0.1-w0/submission.tif`
- **sha256:** `7f00890a62878d612fb5eef67a9a364a2df819433dde74b6762ce4fc0fc4fe15`
- **Size:** 570,890 bytes
- **Status:** Format verified, ready for immediate upload.

#### Route B: Run Local Pipeline Inference
```bash
# src/inference.py automatically loads data/evidence/emission_decision.json
# and applies the adopted policy (floor 0.1, thin, width 0 px)
python -m src.inference --config configs/config.yaml --out submission.tif
```

#### Route C: Multi-Ensemble Cloud Blend
```bash
python scripts/blend_submission.py \
    --runs data/evidence/runs/35042805806 data/evidence/runs/35249562910 \
    --shaping-t0 0.1 --shaping-dilate 0 \
    --shaping-source data/evidence/emission_decision.json \
    --out submission.tif
```

#### Route D: CPU-only baseline, no GPU and no runner artifacts (added session 20)
```bash
python scripts/baseline_submission.py          # -> data/evidence/baseline/
python scripts/validate_submission.py --pred data/evidence/baseline/submission.tif \
    --sample data/sample_submission.tif --train data/training_features.tif
```
Histogram gradient boosting on the official feature stack, trained on folds ≠ 0 of the standard
`src/blocks.py` partition; the emission policy (floor × thin × width) is chosen by the **union**
population's DTI on the fold the model never saw, with a pre-registered support cap so the search
cannot select the degenerate "emit the whole footprint" candidate. Its measured numbers are in
`data/evidence/baseline/baseline_report.json`. This is a floor, not a contender — its own report
says so — but it makes a valid entry possible from any machine.

### Step 4: Validate GeoTIFF Format (Mandatory Pre-Upload Gate)
Run the automated validation check:
```bash
python scripts/validate_submission.py \
    --pred data/evidence/runs/ens12-adopted-floor0.1-w0/submission.tif \
    --sample data/sample_submission.tif \
    --train data/training_features.tif
```
**Expected Output:**
```text
Validating data/evidence/runs/ens12-adopted-floor0.1-w0/submission.tif
  Width: 3292, Height: 3730, Count: 1, Dtype: ('float32',), CRS: EPSG:32611, Res: (100.0, 100.0), Nodata: None
  Data min: 0.0000, max: 1.0000, mean: 0.0335, nan%: 57.93%
  ✓ CRS EPSG:32611
  ✓ Resolution 100m
  ✓ Single band
  ✓ Dtype float32
  ✓ Values in [0,1] (min 0.0000 max 1.0000)
  ✓ Size matches sample 3292x3730
  ✓ Transform matches sample
  ✓ Size matches training_features
  i NaN fraction 57.93% (NaN is expected outside the GeoDAWN footprint)

✅ Validation PASSED - Ready for submission!
Next: Upload to https://www.drivendata.org/competitions/306/competition-doe-gems/ via 'Submit' button
```

### Step 5: Upload to DrivenData Platform
1. Go to the [DrivenData Submissions Page](https://www.drivendata.org/competitions/306/competition-doe-gems/submissions/).
2. Click **"Make new submission"**.
3. Upload your validated `.tif` file.
4. In the submission description box, paste the **Generative AI Disclosure Statement** (Section 3 above).
5. Submit and verify that the submission parses successfully on the public leaderboard.

### Step 6: Final Selection (Before Dec 3, 2026)
- **Quota:** You can make up to 3 submissions per week.
- **Final Selection:** Before December 3, 2026 at 11:59 PM UTC, go to your DrivenData submissions history and mark your best-performing, metric-aligned submission as your **Final Selection** for Phase 1 and Phase 2.

---

## 7. Solution Verification & Finalist Package (§3.2, §3.5)

Prize finalists are required to provide complete code assets and documentation following the competition:
1. **Reproducible Codebase:** Full source code, weights, training pipelines, and data assembly scripts.
2. **Environment & Dependencies:** Pin exact dependencies via [`requirements.verified.txt`](requirements.verified.txt).
3. **Winning Model Documentation Template:** DrivenData standard documentation describing hardware, dependencies, pre-processing, training time, and inference commands.
4. **Generalization Proof:** Ability to run predictions on new, unseen data samples.

---

## 8. Line-by-Line Auditable Official Links Table

| Target Resource | Responsible Entity | Official URL | Manual Verification Note |
|---|---|---|---|
| **Problem Description** | DrivenData / DOE OG | [https://www.drivendata.org/competitions/306/competition-doe-gems/page/967/](https://www.drivendata.org/competitions/306/competition-doe-gems/page/967/) | Defines task, UTM 11N, 100m res, single band float32, DTI α=0.2, β=0.8. |
| **Competition Home & Data Tab** | DrivenData / DOE | [https://www.drivendata.org/competitions/306/competition-doe-gems/](https://www.drivendata.org/competitions/306/competition-doe-gems/) · [https://www.drivendata.org/competitions/306/competition-doe-gems/data/](https://www.drivendata.org/competitions/306/competition-doe-gems/data/) | Lists Dec 3 2026 11:59pm UTC deadline, $300k pool; data tab requires login (verified redirect to /accounts/login/). |
| **About Page & Scientific Background** | DrivenData / DOE / USGS | [https://www.drivendata.org/competitions/306/competition-doe-gems/page/968/](https://www.drivendata.org/competitions/306/competition-doe-gems/page/968/) | GeoDAWN definition, fault taxonomy, cited papers: Matteo et al 2021 & Hermant et al 2025. |
| **Official Rules PDF** | National Lab of the Rockies (NLR) | [https://docs.nlr.gov/docs/fy26osti/96647.pdf](https://docs.nlr.gov/docs/fy26osti/96647.pdf) | OSTI 96647; 29 verbatim machine-checked quotes; governs eligibility, 3/week, GenAI disclosure, $300k awards. |
| **HeroX Rules Page** | American-Made Challenges | [https://www.herox.com/GEMSPrize/resource/2274](https://www.herox.com/GEMSPrize/resource/2274) | Resource 2274; official terms linking to the rules document. |
| **INGENIOUS Regional Data** | Geothermal Data Repository | [https://gdr.openei.org/submissions/1391](https://gdr.openei.org/submissions/1391) | DOI 10.15121/1881483; official source of training faults. |
| **GeoDAWN Data Release** | U.S. Geological Survey (USGS) | [https://doi.org/10.5066/P93LGLVQ](https://doi.org/10.5066/P93LGLVQ) | Airborne magnetics and radiometrics covering NW Nevada and E California. |
| **USGS SGMC (Proxy Catalogue)** | USGS | [https://doi.org/10.3133/ds1052](https://doi.org/10.3133/ds1052) | DOI 10.3133/ds1052; independent fault catalogue used for proxy evaluation. |
| **Reference Solution** | DrivenData | [https://github.com/drivendataorg/gems-prize-reference-solution](https://github.com/drivendataorg/gems-prize-reference-solution) | Official reference code benchmark (commit aebe92f). |
| **This Repository** | GEMSDOE | [https://github.com/buffedlizard55-lab/GEMSDOE](https://github.com/buffedlizard55-lab/GEMSDOE) | Top-leaderboard framework, verified data bridge, and auditable site. |

### 8b. Competition Data Files — Official Names & Dropbox Mirrors (for manual verification)

The same files appear under different names on different official pages (flagged irregularity, handled in code). Every URL below was extracted from the competition data tab (requires login) and re-printed in `data/README.md`; every sha256 is pinned in `data/evidence/inventory.json`.

| Content | Problem Page Name | Dropbox Mirror (from data tab) | Size | sha256 (first 16) |
|---|---|---|---|---|
| **Feature stack (19 bands)** | `training_features.tif` | [gems-geodawn-numerical-features.tif](https://www.dropbox.com/scl/fi/3vz9o0wwavi26xaeoxlwr/gems-geodawn-numerical-features.tif?rlkey=je8d8fepqfbst9lnwsq9rkplu&st=zj1lag1r&dl=0) | 399.5 MB | `4371c82e3b8339b8…` |
| **Training labels** | `labels.tif` | [existing_faults.tif](https://www.dropbox.com/scl/fi/t7fyt03qdh9egyme0itwo/existing_faults.tif?rlkey=yiao96uluqdkipf0h5vju71jf&st=rnino7ya&dl=0) | 415.8 KB | `7ba308ccdc4418b3…` |
| **Sample submission** | `sample_submission.tif` | [example_submission.tif](https://www.dropbox.com/scl/fi/6rgvnuady818ol8yqgis4/example_submission.tif?rlkey=kbykilvau066xuogoosbf4cq8&st=8junzdyw&dl=0) | 1.5 MB | `2176d08e485aa2cd…` |
| **1m DEM tile links** | `1m_DEM_links.csv` | [Digital-elevation-model-links-JSON.pdf](https://www.dropbox.com/scl/fi/ig0mban712ns1atphgphe/Digital-elevation-model-links-JSON.pdf?rlkey=zm77f1vbtt2if8hlruymptnu3&st=srhhir10&dl=0) | 22.0 MB | `c2996eaf0adcc76b…` |
| **Official rules PDF** | `GEMS_96647.pdf` | [GEMS_96647.pdf](https://www.dropbox.com/scl/fi/aemhtutjgcp6tr3tint94/GEMS_96647.pdf?rlkey=rek210cj2smnmzb8n0sla1vmd&st=wz4kofki&dl=0) | 444.5 KB | `50d854b1e0239fe6…` |

> **Naming drift — verified:** Reference solution calls feature file `numeric_features.tif`, problem page calls it `training_features.tif`, Dropbox calls it `gems-geodawn-numerical-features.tif` — all same 399.5 MB file. Sample submission described as “total fault absence” but is bit-identical to labels (60,988 px) — flagged; we write from georeferencing only.

---


## 8c. Common Pitfalls & How to Avoid Them (Measured Failures)

| Pitfall | What Happens | How This Repo Prevents It | Verified Fix |
|---|---|---|---|
| **Uploading a file with wrong CRS / resolution** | DrivenData ingestion rejects; no score | `scripts/validate_submission.py` checks EPSG:32611, 100 m, 3292×3730, single band float32, [0,1] — exit 1 on failure | Re-measured 2026-09-18: shipped submission **PASSED** |
| **Using the sample submission as a zero template** | You submit the known faults (60,988 px) — not a blank slate | Sample submission is **bit-identical to labels** (flagged irregularity); we write from georeferencing only, values from model | `data/evidence/transfer_analysis.json` |
| **Training-induced threshold (t0≈0.47) on known faults** | Collapses to DTI 0.0247 on new-fault proxy (in-domain trap) | Adopted policy `floor 0.1, thin, w=0` measured +0.1118 over shipped on proxy, reproduced on 3 ensembles | `data/evidence/emission_decision.json` |
| **Silently corrupted TIFF (110-byte stub)** | Workflow reported success, submission empty (run 35042805806) | `src/submission_io.py` read-back verifier + `pipefail` + 10 KB + non-empty guard; `FAILED.json` on failure | `tests/test_submission_writer.py` |
| **Data not placed (empty data/)** | `prepare_data.py` fails, training cannot start | `data/bridge/` → `assemble_data_bridge.py` (sha256 pinned, tamper-refused, regression-tested) | `data/evidence/data_placement.json` (2026-09-17) + re-verified 2026-09-18 |
| **Platform rejects with "Predicted values must be in range [0, 1]"** | Every finite value is in [0, 1] but NaN sits *inside* the sample submission's valid (scored) region — 3,061 px did, in the file rejected on 2026-09-24 | `src/submission_io.conform_to_template` aligns every written field to the template mask (finite inside / NaN outside / nodata=nan); `scripts/validate_submission.py` now fails any file with a non-finite pixel inside the valid region; check a candidate with `python scripts/sanitize_submission.py --pred FILE` (exit 1 = not conformant) | `data/evidence/runs/ens12-adopted-floor0.1-w0/sanitize.json` (before/after hashes) + `tests/test_template_conformance.py` |
| **Forgetting GenAI disclosure** | Finalist verification risk (§3.2) | Template provided (§3 above); must be pasted into narrative | Rules PDF §3.2 verbatim |

## 8d. Data Placement — The Single Former Blocker, Now Resolved (2026-09-17)

The competition data cannot be fetched inside the sandbox (egress allowlist permits only `github.com`/`pypi.org`; Dropbox/DrivenData/S3 blocked — re-measured 2026-09-18). The workaround is **verified end-to-end**:

1. **Fetch on a runner:** `.github/workflows/place-competition-data.yml` (run 35168924460) downloads the three official rasters from the Dropbox mirrors on the official data tab, **verifies each sha256 against `data/evidence/inventory.json`**, and commits them as ≤90 MiB parts in `data/bridge/` (`manifest.json`)
2. **Reassemble locally:** `python scripts/assemble_data_bridge.py` re-verifies every part + whole-file sha256, writes `data/training_features.tif` (418,912,844 B), `data/labels.tif` (425,830 B), `data/sample_submission.tif` (1,599,597 B)
3. **Validate:** `python scripts/prepare_data.py` — **PASS** (3292×3730, 19 bands, EPSG:32611, 100 m, bounds aligned)
4. **Full pipeline proof:** `data/evidence/runs/local-sandbox-smoke/` (train→inference→validate→score ran inside 3.9 GB sandbox after two memory fixes) and `data/evidence/runs/35169168957/` (runner). See `STATUS.md` session 9.

**One-line reproduction:** `git pull && python scripts/assemble_data_bridge.py && python scripts/prepare_data.py` (idempotent, refuses on mismatch).


## 9. Limitations, Required Access & What Is Still Human-Only

This repository is engineered to be auditable and reproducible, but several steps are gated by competition design or sandbox network policy. Each limitation states why it exists and the exact manual action to clear it.

| Limitation / Gate | Why It Is Blocked Here | What You Need | How to Resolve |
|---|---|---|---|
| **DrivenData login & enrollment** | Data tab redirects to `/accounts/login/` without auth; submission form behind same gate. | Human with U.S. citizen / permanent resident identity (rules §1.3) must create account and click “Compete!” | Go to [competition home](https://www.drivendata.org/competitions/306/competition-doe-gems/) → “Compete!” → accept rules. **Only step that cannot be automated.** |
| **Private test labels withheld** | By design — scored “new faults” are hidden; public labels are incomplete by ~6,166 km trace. | No one outside organizers can observe them; even public LB is held-out split of hidden set. | Treat local DTI on `labels.tif` as plumbing monitor only; proxy population (SGMC, §5 & metric page) is honest local monitor. |
| **Competition data cannot be fetched inside sandbox** | Egress allowlist: sandbox reaches only `github.com / api.github.com / pypi.org`; Dropbox, S3, DrivenData blocked (TLS 35). | Any unrestricted machine (laptop, GH runner, cloud VM). | **Option A (preferred, verified 2026-09-17):** `git pull && python scripts/assemble_data_bridge.py && python scripts/prepare_data.py` — reassembles sha256-pinned git bridge in `data/bridge/` with no network.<br>**Option B:** `bash scripts/download_competition_data.sh` into `data/` then `python scripts/prepare_data.py`. Both verify sha256 vs `inventory.json`. |
| **GPU needed for competitive training** | Full config (EfficientNet-B5, 10 MC splits, 60 epochs, 4 architectures) needs ~24 GB VRAM; sandbox has 3.9 GB RAM / 2 vCPU, no GPU. | GPU box (≥16 GB VRAM) with CUDA, or GH Actions ensemble workflow (shards 6 folds). | `python -m src.train --config configs/config.yaml` (GPU) or dispatch `train-ensemble.yml`. CPU smoke proves plumbing but not competitive. |
| **Pretrained weights blocked in sandbox** | `objects.githubusercontent.com` blocked; `pretrained:true` fails here. | Unrestricted egress or `pretrained:false` for sandbox. | On unrestricted machine configs work as-is; in sandbox use `config_fixture.yaml` or override `model.pretrained=false`. |
| **Leaderboard submission & scoring** | Requires authenticated DrivenData POST; private DTI never disclosed. | Same enrolled human (3/week; 1 final selection before deadline without private scores — §3.4, §3.6.2). | Validate locally (`validate_submission.py`), then upload at [Submissions page](https://www.drivendata.org/competitions/306/competition-doe-gems/submissions/) → “Make new submission” (include §3.2 GenAI disclosure). |
| **GitHub Pages deployment** | Workflow `pages.yml` deploys only from `main` (environment protection). | Maintainer must merge to `main`. | Merge this branch → `main` → site publishes `docs/` to [GitHub Pages](https://buffedlizard55-lab.github.io/GEMSDOE/docs/index.html). |

> **Single remaining blocker — now RESOLVED for local use.** Prior sessions noted “run `bash scripts/download_competition_data.sh` on any unrestricted machine” as blocker. Since 2026-09-17 that download is committed as **sha256-pinned git parts in `data/bridge/`** (workflow run 35168924460); sandbox itself now runs `assemble_data_bridge.py` and `prepare_data.py` **passes** (3292×3730, 19 bands, EPSG:32611, 100 m). Full train→inference→validate→score ran on real bytes both on runner (`35169168957`) and inside sandbox (`local-sandbox-smoke`). GPU and DrivenData-auth upload remain only gates to leaderboard-visible result.

---

## 10. Free Publicly Available External Data We Are Allowed to Use

Competition **explicitly permits external data** provided license allows challenge use and sponsor sharing ([problem page #external-datasets](https://www.drivendata.org/competitions/306/competition-doe-gems/page/967/#external-datasets) → rules PDF §3.2). This repo uses **only public-domain or openly licensed sources** in `docs/data_catalog.csv`; every link is re-fetched live by `verify_links.py`. Key free sources wired into pipeline:

| Source & DOI | License / Access | Why It Helps Top-Leaderboard | Evidence / How to Use |
|---|---|---|---|
| **USGS 3DEP 1m DEM** (projects CA_SierraNevada_B22, NV_WestCentral_EarthMRI_2020_D20, NV_Humboldt_2021_D21) — Host: `prd-tnm.s3.amazonaws.com` | **Public Domain** (U.S. Government) — “All 3DEP products available free without restrictions” ([USGS 3DEP](https://www.usgs.gov/3d-elevation-program/about-3dep-products-services)) | Fault scarps/lineaments are direct surface expressions at 1m; resampled to 100m + derived slope/curvature/TPI/hillshade complement 19 bands. | 716 tiles confirmed vs bucket (see Data page). Derive: `python scripts/download_dem_tiles.py --complete-listing` → `src/external_data.py`. |
| **USGS Quaternary Faults (QFaults)** — [doi.org/10.5066/P9BCVRCK](https://doi.org/10.5066/P9BCVRCK) | **Public Domain** (USGS); shapefiles & KML via [ScienceBase 589097…](https://www.sciencebase.gov/catalog/item/589097b1e4b072a7ac0cae23) | Training-label provenance; independent catalogue for cross-catalogue transfer experiments (emit A, score vs B). | Verified via ScienceBase; programmatic [ArcGIS MapServer](https://earthquake.usgs.gov/arcgis/rest/services/haz/Qfaults/MapServer). |
| **USGS SGMC State Geologic Maps** — [doi.org/10.3133/ds1052](https://doi.org/10.3133/ds1052) | **Public Domain** (USGS); Data Series 1052 | Source of **proxy catalogue** (61,664 px absent from labels) — only local population resembling scored new faults. | Wired: `fetch_proxy_faults.py` → `build_proxy_catalogue.py` → `eval_proxy_catalogue.py`; evidence `data/evidence/proxy/`. |
| **INGENIOUS Great Basin Compilation** — [doi.org/10.15121/1881483](https://doi.org/10.15121/1881483) | **CC / Publicly Accessible** via [GDR 1391](https://gdr.openei.org/submissions/1391) | Origin of training features & labels; sub-datasets provide official dt-elevation, geophysics grids. | Verified via GDR + ScienceBase; sub-DOIs in Sources page. |
| **INGENIOUS Detrended Elevation** — [doi.org/10.5066/P9MQRCBY](https://doi.org/10.5066/P9MQRCBY) | **Public Domain** (USGS); 12.34 GB grids | Ready-made fault-emphasising topography over whole study area at 30m. | Candidate extra band; source for re-derived slope. |
| **GeoDAWN Mag/Radiometrics** — [doi.org/10.5066/P93LGLVQ](https://doi.org/10.5066/P93LGLVQ) | **CC0 1.0 Universal** (USGS) | Survey underlying 19-band stack; clarifies band semantics and flight-line provenance. | ScienceBase 657e1d85… (149,030 line-km; 51,857 km²). |

> **License compliance — non-negotiable.** Rules require external data shareable with sponsor (§3.2). Only PD/CC/CC0 sources above are used — any dataset without clear PD/CC/open license is **not** used even if it might improve DTI, because unverifiable license = disqualification risk. If you add external data, add it to `docs/data_catalog.csv` with publisher, DOI/URL, and license, and let `verify_links.py` confirm.

---

> **Completed in this session (2026-09-19, session 17):** the two dispatched measurements **landed**.
> (1) **Cross-catalogue transfer refused — with a result.** The runner fetched QFaults layer 21 (14,481
> features, integrity gate passed) and rasterised it on the competition grid: **60,938 of 60,939**
> in-footprint B pixels are already within R = 3 px of a training label, leaving **1** code-2 pixel.
> **The training labels in this footprint are QFaults**, so no transfer number can be computed against
> them; `measure_cross_catalogue_transfer.py` now refuses by pre-registered population threshold
> (`--min-b-only-px 100`), writes the refusal **with the overlap that establishes it**, and exits 0.
> (2) **Runner reproduction is bit-for-bit**: an independent GitHub-hosted environment reproduced the
> block-stratified evidence exactly — DTI **0.099859**, CI95 **[0.088338, 0.111886]**, `agree: true` on
> all ten compared quantities (`data/evidence/block_holdout/sandbox_vs_runner.json`). Two workflow
> defects were found and fixed on the way to a green run — a stats-key mismatch that hid the overlap
> result, and a params job that tested `BOOTSTRAPS` while assigning from `BOOT`, handing `''` to a
> typed argument — and three static lints (`tests/test_workflow_yaml.py`, 3 → 6 tests) now fail on that
> class without a runner. The refusal itself is reproduced across **three fetches and two
> environments**: byte-identical raster (sha256 `3fb2ca73…`), identical population, identical verdict.
> Opened as [PR #23](https://github.com/buffedlizard55-lab/GEMSDOE/pull/23). 288 torch-free tests pass
> locally; the runner suite (with torch) is green on the PR.
>
> **Completed 2026-09-18 (session 16):** error bars on the emission decision (block-stratified DTI + paired block bootstrap: **0.0999, CI95 [0.0883, 0.1119]**, alternative-beats-reference probability **0.008**); a digit-for-digit **reproduction gate** against the runner's committed sweep; the **field axis settled at matched support** (the shipped 11-fold mean is best — 0.0999 vs 0.0850 / 0.0777 / 0.0644 — stable across ±15/25/40 % windows, so ensemble 1's 0.1365 was a support effect); the **cross-catalogue transfer measurement built end to end** (QFaults fetch + controls + pre-registered union test) and dispatched to a runner; block-holdout **training** wired with a partition cross-check. 291 tests pass (was 175).
>
> **Completed earlier on 2026-09-18 (session 15):** Executive summary subpage polished with TL;DR 5-command path, pitfalls table, and data-placement proof; site rebuilt; 175 tests + audit pass; data bridge re-verified (`assemble → prepare → validate` all exit 0).

## 11. What Still Needs Doing — Suggestions to Reach Top Leaderboard (Next Session Priority)

Pipeline runs end-to-end on real competition rasters, but placing top-5 — the public bar was **0.2854** on 2026-09-21 (it was 0.1972 five days earlier; both snapshots are committed in `data/evidence/independent_verification.json`) — requires moving from **measured plumbing fixes** to **geophysical detection gains**. Prioritized by impact/risk:

| # | Improvement | Why It Matters (measured) | Status | Next Action |
|---|---|---|---|---|
| 1 | **Fix detection, not just width — cross-catalogue transfer** | 74% of new-fault-like truth >12 px (1.2 km) from any emitted pixel; widening to 16 px lifts DTI only 0.0247→0.0713. Remaining error is detection, not localization (`miss_distance-ensemble1.json`). | **MEASURED 2026-09-19 — verdict `REFUSED`, and the refusal is the finding.** The runner fetched QFaults layer 21 (14,481 features; `fetched == service_reported`), rasterised it on the competition grid with the same script used for catalogue A, and the overlap with the training labels came out **total**: 60,938 of 60,939 in-footprint B px are within R = 3 px of a label (**1** code-2 px), while 60,986 of the 60,988 label fault px are within R of B. The controls and the pre-registered union test are built and unit-tested (15 tests), but they cannot run on a 1-pixel truth population, so the script refuses by threshold and commits `data/evidence/xcat/transfer_report.json` with the overlap that establishes it. | **Do not re-run this expecting a different answer** — the population is a property of the two catalogues, not of the run. The question is now answered negatively: *no free second Quaternary catalogue is independent of these labels.* To pursue external-catalogue emission you need a layer demonstrably disjoint from `labels.tif` (verify with `build_proxy_catalogue.py` first); the SGMC proxy (61,664 code-2 px, 24.94 % covered) stays the only surrogate. Detection gains must come from **item 3 (DEM derivatives)** or **item 6 (capacity)** instead. |
| 2 | **Spatial block-holdout (solve in-domain/proxy sign conflict)** | In-domain DTI (0.1903→0.0908 when widening) and proxy DTI (+0.11) disagree on sign — choosing one corrupts other. | **COMPLETE 2026-09-19 — all four folds trained and committed.** `scripts/block_holdout_eval.py` scores the shipped submission per 51.2 km block and bootstraps over blocks: proxy DTI **0.0999, CI95 [0.0883, 0.1119]**; the best genuinely different alternative (width 1 px, 0.0878) beats the reference with probability **0.008**. The four trained folds give gaps **+0.0114 / −0.0070 / +0.0139 / +0.0093** — mean **+0.006904**, spread **0.020935**, positive in 3 of 4 (`data/evidence/block_holdout/fold_gap_summary.json`, derived by `scripts/read_landed_reports.py --gaps-only` from the committed per-fold files). **Read as a spread, not an error bar:** no fold has the ≥12 resampling units a readable block-bootstrap CI needs (8/9/9/8 scoreable blocks), so every per-fold interval is flagged `interval_readable: false` and the sign is not stable across folds — *no clear memorisation, no clear transfer gain*. | Closed. The full-grid number (0.099859, reproduced digit-for-digit on a runner) remains the selection statistic. Each fold's raw field now also carries the **combined** truth population (`--combined-population`), so a later population question is a download, not a retrain — but note the artifact retention window (14 days) in `LIMITATIONS.md`. |
| 3 | **1m DEM derivatives as additional bands** | Fault scarps are direct surface expressions; 716 tiles confirmed deliver slope/curvature/lineament at 100× finer native res than 100m stack. | Code ready (`src/external_data.py`, `download_dem_tiles.py`); disabled by default (`external_dem_path: null`). | On unrestricted machine: download tiles, build mosaic, derive 5 features, set `external_dem_path`, re-train. |
| 4 | **Model selection on the population the leaderboard actually scores** | Early stopping & fold weighting maximized in-domain DTI; emission policy no longer does. | **WIRED end to end 2026-09-22.** The emission policy was re-checked on a third population 2026-09-19 (`--combined-population`: union of catalogue labels + new-fault-like proxy, 122,652 px disjoint; shipped artifact **0.207431 CI95 [0.192924, 0.222879]**, adopted policy holds). Training-side selection is now built: `src/train.py` logs `DTI_union` per epoch AND `training.select_on` (`in_domain`/`union`) drives the early-stopping comparator, the saved checkpoint and the manifest `dti` — the last of which `blend_submission.py --weights dti` reads, so `union` feeds the signal into **both** early stopping and ensemble weights. Demonstrated on the fixture: `in_domain` picks epoch 2 (0.1206), `union` picks epoch 1 (0.1081 > 0.1015). Off by default; a `union` run with no proxy scope fails fast. Pinned by `tests/test_union_selection.py`. | Run one GPU fold each way (`select_on=in_domain` vs `union`) and compare the held-out union DTI of the selected checkpoints. Select on the union, never its components (`FP_w` sums over *prediction* pixels). |
| 5 | **More independent folds (seed diversity)** | 3-ensemble mean (16 live folds, seeds 42/43/44) confirms +0.0581 contrast; more folds = cheapest variance reduction. | Ensembles 1 (6), 2 (5 live), 3 (6 live) committed; 11-fold blend shipped. | **Deferred on evidence, 2026-09-19.** At matched emission support the 11-fold shipped mean scores **0.0999** while the 16-fold `ens123` scores **0.0850** (`data/evidence/emission_field_axis.json`, `ranking_stable_across_windows: true`): more folds did not help. Fire ensemble 4 only after item 3/6 change the field, then reblend with `reblend.yml RUN_ID=a,b,c,d`. |
| 6 | **Full-capacity GPU training (EfficientNet-B5, 60 epochs)** | Current frontier is MobileNetV2/resnet34 at 8–15 epochs on CPU; reference config is 10 MC splits × 60 epochs × 4 architectures on EfficientNet-B5. | Config ready (`configs/config.yaml`); needs 24 GB GPU (~1 h) vs ~4 h CPU for smoke. | Run on GPU box or via Actions with GPU runner; bridge already supplies data. |
| 7 | **Pseudo-label / self-training from proxy trace** | SGMC trace allowed to inform model (rules), but only through held-out split so gain ≠ label leakage. | **MEASURED 2026-09-19/20, fold 0, on all three populations — a trade-off on the components, suggestive but under-powered on the union, not shippable.** Held-out blocks: proxy-only **0.0806 → 0.1841 (+0.1036, P = 0.999)** but catalogue labels **0.2113 → 0.1239 (−0.0874, P = 0.001)**; same split on the trained-on blocks (+0.0507 / −0.0764); emission support 90,433 → 338,649 px. Derived verdict `TRADE_OFF_PROXY_GAINS_CATALOGUE_LOSSES`, `shippable_evidence: false` (`data/evidence/pseudo_labels/fold0_two_population_contrast.json`). The +0.1036 arm is **source-circular** — `configs/config_pseudo_labels.yaml`'s `pseudo_label_path` is the same `proxy_catalogue.tif` (code 2) the proxy truth is cut from — which the derivation reads from the config rather than asserting. Leakage safety is by design and pinned by test (held-out region zeroed from the pseudo mask before it touches the loss). | **MEASURED 2026-09-20 (run 35477119490) — suggestive on the union, and under-powered.** The baseline arm's raw field was downloaded from run 35413207736's artifact, sha256-gated against the report it produced, and re-scored on the union: held-out blocks **0.197183 → 0.228463, +0.031280 at P = 0.916, CI95 [−0.010, +0.082]** — the interval spans zero on 8 scoreable blocks, and the trained-on blocks move the other way (−0.0375, P = 0.0025). Derived verdict `GAIN_ON_THE_COMBINED_SURROGATE`, `shippable_evidence: false`. Do not re-fire fold 0 expecting a different number: the two fires (same seed, config and partition, different runners) differ by ~0.036 on the proxy arm, i.e. the effect is the size of the replicate noise. **Pooling reader built 2026-09-22:** `scripts/read_landed_reports.py --pool` concatenates every committed fold's two arms into one paired block bootstrap, verifying the fold block ids are **disjoint** (they partition the grid), refusing mismatched partitions and same-field pairs, and marking the pool COARSE below 12 units (`data/evidence/pseudo_labels/pooled_two_population_contrast.json`). On the one committed fold it reproduces fold 0 exactly (+0.031263 at P = 0.9515, 7 units) with verdict `POOL_POSITIVE_BUT_UNDER_POWERED` naming the exact blocker. **Next:** fire the pseudo-label workflow for folds 1–3 and the pool crosses 12 units. The bar `docs/FIELD_SELECTION_RULE.md` pre-registers for adopting a field is R3 **P ≥ 0.95** / R1 +0.010 on both fields' raw rasters; the single-fold pool clears both but is not yet readable. |
| 8 | **Human-only: DrivenData account + first leaderboard upload** | All above is local; only externally-sourced quality signal is public LB split of new faults. | Not yet done; 3/week; 1 final selection before Dec 3 2026 without private scores. | Enroll → upload shipped `submission.tif` → observe public DTI → iterate within weekly quota. |

> **Suggested order for next session:** items **1** and **2** are *closed by measurement* (1 refused on a total label/QFaults overlap; 2 complete with all four folds committed), **5** is deferred because more folds measurably did not help, **4** is now *fully wired* (`training.select_on=union` drives early stopping + ensemble weights; verified to change the selected epoch), and **7**'s *pooling reader is built* (`--pool`, disjointness-verified) leaving only the folds-1–3 fires. The remaining upside is therefore **8 (human: enroll, upload, read the public leaderboard) → 3 (1 m DEM derivatives) → 6 (GPU capacity — the first place item 4's switch actually runs) → the pooled 7 contrast over folds 1–3 before ~2026-10-03**. Items 3–6 require an unrestricted machine/GPU; the bridge already supplies the competition rasters. Item 8 is only human-gated — until upload, every number here remains a local surrogate and the public leaderboard is the first unbiased signal.

---

## 12. GEMSDOE4 — the new-fault-first line (this repository's strategy)

**The one fact that changes the strategy.** Both prize phases are scored against the
**expert-mapped new faults**, not the catalogue we can download. Verbatim from the official rules
(<https://docs.nlr.gov/docs/fy26osti/96647.pdf>, quoted and machine-verified in
`data/evidence/rules_quotes.json`):

> *"In Phase 1, submissions will be evaluated against a privately withheld subset of the original
> new fault dataset compiled by expert reviewers."* — §1.1
> *"Submissions will be reevaluated against the full, revised new fault dataset using the same
> distance-weighted Tversky index."* — §1.1

`data/labels.tif` (60,988 fault px) is the **training** catalogue and is scored in neither phase.
Every earlier line in this project tuned its emission policy on the catalogue, i.e. on a population
that is never scored. GEMSDOE4 targets the new-fault population instead, measured through the
independent SGMC-derived proxy compilation in `data/evidence/proxy/proxy_catalogue.tif`.

**What was built (all CPU, all torch-free, all measured in this checkout):**

| Piece | File | What it does |
|---|---|---|
| Lineament features | `src/lineament_features.py` | 63 features: 19 raw bands, Sato ridgeness (σ = 1/2/3) and structure-tensor coherence (σ = 1.5) on the 6 edge-signal bands, mean/std at 5 px and 11 px on 8 bands |
| New-fault detector | `scripts/newfault_detector.py` | `HistGradientBoostingClassifier` on those features, supervised by catalogue ∪ SGMC proxy, trained outside both held-out folds (R = 3 px collars) |
| Detector union | `scripts/combine_newfault.py` | unions structurally different detectors; selects the rule on the new-fault population on held-out geography inside a pre-registered support window |

**Measured on the full grid (both populations, same metric):**

| Field | new-fault (proxy) DTI | catalogue DTI | emitted px |
|---|---|---|---|
| 11-fold deep ensemble (previous artifact) | 0.0999 | **0.2298** | 172,974 |
| classical raw-band GBM | 0.1191 | 0.0611 | 155,889 |
| lineament NFF, seed 42 (folds 0/1 held out) | 0.1351 | 0.1184 | 218,688 |
| lineament NFF, seed 43 (folds 2/3 held out) | 0.1553 | 0.1312 | 215,449 |
| 4-member union (previous artifact, k = 1) | 0.1864 | 0.1977 | 547,862 |
| **shipped union (k = 2 of 5)** | **0.2096** | 0.1713 | 332,544 |

The deep ensemble is the best *catalogue* detector here and the worst *new-fault* detector — that
asymmetry is the argument for a different strategy rather than another variant of the same model.
The shipped union's measurement-fold (fold 1, never used by any sweep) proxy DTI is **0.1897 vs
the 4-member union's 0.1747** (+0.0150; paired block bootstrap P(cand > ref) = 0.957 over the
fold's 9 blocks — a COARSE interval, disclosed as such in
`data/evidence/union6/paired_contrast.json`); the catalogue DTI falls, and the catalogue is not
what the rules score (§1.1 above).

**Reproduce it:**

```bash
python scripts/newfault_detector.py --seed 42 --fold 0 --eval-fold 1     --out-dir data/evidence/newfault/seed42        # ~15 min, 2 vCPU
python scripts/newfault_detector.py --seed 43 --fold 2 --eval-fold 3     --out-dir data/evidence/newfault/seed43        # ~15 min, 2 vCPU
python scripts/newfault_detector.py --seed 44 --fold 0 --eval-fold 1 --neg-ratio 5  --out-dir data/evidence/newfault/seed44   # ~14 min (member dropped by the LOO below)
python scripts/newfault_detector.py --seed 45 --fold 2 --eval-fold 3 --neg-ratio 20 --out-dir data/evidence/newfault/seed45   # ~17 min
python scripts/combine_newfault.py \
    --member deep11=data/evidence/runs/ens12-adopted-floor0.1-w0/submission.tif \
    --member classical=data/evidence/baseline/submission.tif \
    --member nff42=data/evidence/newfault/seed42/prob_raw.tif:prob \
    --member nff43=data/evidence/newfault/seed43/prob_raw.tif:prob \
    --member nff45=data/evidence/newfault/seed45/prob_raw.tif:prob \
    --fold 0 --eval-fold 1 --floors 18 --votes 1,2 --name nff-union-5 --out-dir data/evidence/combined
```

**What this cannot show:** the proxy is a stand-in for the private expert labels, not the scored
set. Every number above is a local surrogate on held-out geography; the public leaderboard is the
only unbiased test of the transfer, and the report says so in its own `caveats`.

---

## 13. Verification & No-Hallucination Statement

Every number, link, and rule sentence on this page is drawn from machine-measured evidence or directly fetched official sources:
- **Evidence:** `data/evidence/inventory.json` (file sizes/sha256), `data/evidence/rasters.json` (grid/CRS/bands), `data/evidence/data_placement.json` (bridge provenance), `data/evidence/emission_decision.json` (policy sweeps), `data/evidence/proxy/` (miss distance, oracle ceiling), `docs/link_verification.json` (live URL checks via `scripts/verify_links.py` on a runner).
- **Sources:** Competition problem page, data tab, About page, official rules PDF (29 verbatim quotes checked by `scripts/verify_rules_quotes.py`), HeroX resource, GDR, USGS GeoDAWN — all listed in `docs/data_catalog.csv` (92 rows / 84 unique URLs, each with `verification_method`, `verification_date`, `verification_result`).
- **Irregularities flagged, not hidden:** Three verified irregularities are documented line-by-line: (1) `example_submission.tif` is bit-identical to `labels.tif` (60,988 px, `data/evidence/transfer_analysis.json`) despite the problem page describing it as predicting total absence; (2) naming drift — `training_features.tif` / `numeric_features.tif` / `gems-geodawn-numerical-features.tif` are the same content (handled in `src/dataset.py`); (3) DEM links PDF has no text layer (scan, 0 URLs via three extractors, OCR + S3-verified). None are silently fixed — all flagged in `docs/data.html` and `LIMITATIONS.md`.
- **Reproduce:** `python scripts/build_site.py` regenerates the companion HTML (`docs/executive_summary.html`) from the JSON above; `scripts/audit_docs.py` refuses to deploy if any cited artefact is missing or any link is uncatalogued.

