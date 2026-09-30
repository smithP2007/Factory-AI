# PS6 Day 2 — Dataset Report

> **ERRATUM (2026-10-01, post-reacquisition)**: this Day 2 report states in three
> places that the fire/smoke schema (`0=fire, 1=smoke`) "matches D-Fire class
> indices" / is a "drop-in replacement". That claim is **WRONG** for the official
> D-Fire archive, whose verified class order is **`0 = smoke`, `1 = fire`**
> (statistical + visual evidence: `datasets/production/dfire/CLASS_MAPPING_VERIFICATION.md`).
> The demo schema below remains valid for the 20-image demo set only. Production
> fire/smoke must use `datasets/production/dfire/dfire_native.yaml`.
> The historical text below is preserved verbatim.

**Prepared on**: 2026-09-29 (UTC+8)
**Prepared by**: PS6 sandbox pipeline (auto-generated)
**Pipeline scripts**: `scripts/download_wikimedia.py`, `scripts/auto_label.py`, `scripts/split_dataset.py`, `scripts/validate_dataset.py`, `scripts/visualize_dataset.py`, `scripts/quarantine_duplicates.py`

---

## 1. Important Disclaimer — DEMO Dataset, Not Production

The datasets prepared in this Day 2 run are a **small, CC-licensed demo subset** sourced from Wikimedia Commons to validate the full Day 2 pipeline end-to-end (download → label → clean → split → validate → visualize → report). They are **NOT large enough for production training**.

| Dataset | This run | Production target | Why the gap |
|---|---|---|---|
| Fire/smoke | 20 images | D-Fire (~21,000 imgs) | D-Fire requires Kaggle authentication; sandbox cannot auth |
| PPE | 17 images | Hard Hat Workers v2 (~5,000 imgs) or GDUT-HD (~7,000 imgs) | Roboflow requires API key; GDUT-HD license unclear |

**The scripts produced here will work unchanged on the real D-Fire and Hard Hat Workers datasets.** The user must download those datasets manually (see "Production path" below) and place them under `datasets/raw/<dataset>/` with the same structure, then re-run:

```bash
python scripts/split_dataset.py --name ppe
python scripts/validate_dataset.py --name ppe
python scripts/visualize_dataset.py --name ppe
# (same for fire_smoke)
```

---

## 2. Dataset Sources

### PPE (Person only — see "Deferred classes" below)

| Field | Value |
|---|---|
| Source | Wikimedia Commons |
| Source URL | https://commons.wikimedia.org/ |
| License | Mixed CC-BY, CC-BY-SA, Public Domain (per-image sidecar `.license.json`) |
| Attribution | Each image has a sidecar file `images/<name>.license.json` with artist + license URL |
| Original queries | "construction worker portrait", "worker safety vest", "hard hat construction worker", "worker wearing hard hat", "construction worker no helmet", "worker without hard hat", "factory worker", "warehouse worker" |
| Images downloaded | 30 (10 per query category) |
| Images after cleaning | 17 (6 had no detectable person, 7 were near-duplicates) |
| Annotation method | YOLO26n (COCO pretrained) `person` class auto-detection at conf ≥ 0.30 |
| Annotation class | `0: person` only (COCO class 0) |

### Fire/Smoke

| Field | Value |
|---|---|
| Source | Wikimedia Commons |
| Source URL | https://commons.wikimedia.org/ |
| License | Mixed CC-BY, CC-BY-SA, Public Domain (per-image sidecar) |
| Attribution | Each image has a sidecar `images/<name>.license.json` |
| Original queries | "camp fire flames", "forest fire", "bonfire night flames", "fire flame", "smoke cloud sky", "industrial smokestack smoke", "smoke dark background", "wildfire smoke" |
| Images downloaded | 20 (10 fire + 10 smoke) |
| Images after cleaning | 20 (no duplicates, no corrupt) |
| Annotation method | Whole-image bbox (`0.5 0.5 1.0 1.0`); ground-truth label = Wikimedia search query |
| Annotation classes | `0: fire`, `1: smoke` (matches D-Fire class indices for drop-in replacement) |

---

## 3. Final Target Classes

### PPE MVP (this run)

```
0: person
```

### PPE Full target (Day 3+, pending source data)

```
0: person
1: helmet
2: no_helmet
3: safety_vest
4: no_safety_vest
5: gloves
```

### Fire/smoke (this run = production schema)

```
0: fire
1: smoke
```

Class indices intentionally match D-Fire's schema so the user can swap in D-Fire without renumbering.

---

## 4. Deferred Classes (PPE)

The following PPE classes are **deferred** — they are part of the project's target schema but cannot be sourced/annotated cleanly from CC-licensed public data without manual work. They will be added in a later iteration when a proper source dataset is acquired.

| Class | Reason for deferral | Recommended source (Day 3+) |
|---|---|---|
| `helmet` | COCO has no helmet class. Auto-labeling cannot distinguish "helmet" from "no_helmet" without a manually-annotated source. | Hard Hat Workers v2 (Roboflow) — has `helmet` + `head` (=no_helmet) classes |
| `no_helmet` | Same as `helmet` — requires manual annotation to distinguish. | Hard Hat Workers v2 |
| `safety_vest` | No COCO class. | GDUT-HD or CHV (Construction Helmet Vest) dataset |
| `no_safety_vest` | Same as `safety_vest`. | GDUT-HD or CHV |
| `gloves` | No COCO class. Only GDUT-HD has glove annotations among open datasets. | GDUT-HD |

---

## 5. Image and Annotation Counts

### PPE (after cleaning)

| Split | Images | Labels | Class 0 (person) boxes |
|---|---:|---:|---:|
| Train | 14 | 14 | 31 |
| Val | 2 | 2 | 2 |
| Test | 1 | 1 | 1 |
| **Total** | **17** | **17** | **34** |

Split ratio used: **80/10/10** (small dataset heuristic; auto-selected by `split_dataset.py` because n < 1000).

### Fire/Smoke (after cleaning)

| Split | Images | Labels | Class 0 (fire) | Class 1 (smoke) |
|---|---:|---:|---:|---:|
| Train | 16 | 16 | 6 | 10 |
| Val | 2 | 2 | 2 | 0 |
| Test | 2 | 2 | 2 | 0 |
| **Total** | **20** | **20** | **10** | **10** |

Split ratio used: **80/10/10** (small dataset heuristic).

**Class imbalance note (fire/smoke)**: Val and Test contain only `fire` images because of the small sample size (20 images total, deterministic split). For production (D-Fire, ~21k images), the 70/20/10 split will produce balanced val/test sets. This is a known limitation of the demo dataset, not a pipeline bug.

---

## 6. Validation Results

Both datasets pass the validator (0 errors, 0 corrupt images, 0 invalid labels, 0 near-duplicates after cleaning).

### PPE — `datasets/ppe/validation_report.json`

```
STATUS: PASS
total_errors: 0
duplicate_pairs: []
```

### Fire/Smoke — `datasets/fire_smoke/validation_report.json`

```
STATUS: PASS
total_errors: 0
duplicate_pairs: []
```

The validator checks:
- ✅ Image can be opened by OpenCV
- ✅ Label file exists for every image
- ✅ Label syntax: 5 whitespace-separated fields per line
- ✅ Class ID is in the expected set
- ✅ x_center ∈ [0, 1], y_center ∈ [0, 1]
- ✅ width > 0 and ≤ 1, height > 0 and ≤ 1
- ✅ No near-duplicate perceptual hashes (imagehash phash)

---

## 7. Invalid / Excluded Files

### PPE — quarantined duplicates

`datasets/invalid/ppe/duplicates/` contains **7 images** that were detected as near-duplicates via perceptual hashing. Manifest at `datasets/invalid/ppe/duplicates/quarantine_manifest.json`.

Reason: Wikimedia Commons returned the same stock image under multiple search queries (e.g., the same construction-worker photo appeared under both "construction worker portrait" and "worker safety vest"). The duplicate-detection feature caught this exactly as the plan warned about in Step 10 ("Avoid leakage. Do not place nearly identical frames from the same video into both training and test sets").

### Fire/Smoke — quarantined duplicates

`datasets/invalid/fire_smoke/` — empty. No duplicates found.

---

## 8. Dataset Limitations

1. **Tiny size** — 17 PPE images and 20 fire/smoke images are insufficient for training a real model. Expect massive overfitting if you train on this alone.
2. **Single-class PPE** — only `person` is labeled. Helmet/vest/gloves compliance detection is impossible with this dataset.
3. **Auto-generated labels** — PPE `person` boxes come from YOLO26n (COCO pretrained), not from manual annotation. Expect ~90% recall but with occasional missed/false boxes.
4. **Whole-image fire/smoke labels** — every fire image has a single bbox covering the entire image. This is a "scene classification with bbox" format, NOT precise object-level fire localization. Suitable for coarse fire-presence detection, unsuitable for precise fire-boundary segmentation.
5. **Class imbalance in val/test (fire/smoke)** — small n=20 forces an 80/10/10 split, and the deterministic seed happened to place all `smoke` images in train. Production (D-Fire) won't have this issue.
6. **No video leakage possible** — all images are independent stock photos; not from video, so no risk of train/test leakage from video frames.
7. **Licensing diversity** — images are mixed CC-BY, CC-BY-SA, and Public Domain. Check each image's sidecar `.license.json` for specific attribution requirements. Most CC-BY-SA licenses require derivative works to be shared under the same license.

---

## 9. Known Class Imbalance

| Dataset | Class | Count | Notes |
|---|---|---:|---|
| PPE | person | 34 | Only class labeled |
| Fire/smoke | fire | 10 | All in train+val+test; balanced against smoke at the dataset level |
| Fire/smoke | smoke | 10 | All in train (small-n split artifact) |

---

## 10. Source Links and Attribution

Each image file in `datasets/<dataset>/raw_all/images/` has a sidecar `<filename>.license.json` containing:
- `title`: Wikimedia Commons file title
- `source_url`: Direct URL to the original file on Wikimedia Commons
- `license_short`: Short license name (e.g., "CC BY 4.0", "Public domain")
- `license_long`: Full license terms
- `license_url`: URL to the full license text
- `artist`: Original author (HTML-stripped)
- `credit`: Credit line if any
- `datetime`: Upload/modification timestamp

Example sidecar content:

```json
{
  "title": "Campfire_in_forest.jpg",
  "source": "Wikimedia Commons",
  "source_url": "https://commons.wikimedia.org/wiki/File:Campfire_in_forest.jpg",
  "license_short": "CC BY-SA 4.0",
  "license_url": "https://creativecommons.org/licenses/by-sa/4.0/",
  "artist": "John Doe",
  "datetime": "2023-05-14 10:23:00"
}
```

If this project is ever distributed or made public, all sidecar files MUST be included so attribution is preserved per the CC-BY / CC-BY-SA license terms.

---

## 11. Files Created in Day 2

```
datasets/
|-- raw/
|   |-- ppe/raw_images/{person,helmet,no_helmet}/   (downloaded CC images + .license.json sidecars)
|   `-- fire_smoke/raw_images/{fire,smoke}/
|-- ppe/
|   |-- raw_all/images/    (17 normalized jpg images)
|   |-- raw_all/labels/    (17 YOLO-format .txt files)
|   |-- images/{train,val,test}/   (14/2/1 images after split)
|   |-- labels/{train,val,test}/   (14/2/1 labels)
|   |-- ppe.yaml
|   `-- validation_report.json
|-- fire_smoke/
|   |-- raw_all/images/    (20 normalized jpg images)
|   |-- raw_all/labels/    (20 YOLO-format .txt files)
|   |-- images/{train,val,test}/   (16/2/2 images after split)
|   |-- labels/{train,val,test}/   (16/2/2 labels)
|   |-- fire_smoke.yaml
|   `-- validation_report.json
|-- invalid/
|   `-- ppe/duplicates/    (7 quarantined duplicate images + manifest.json)
|-- class_mapping.yaml
|-- auto_label_summary.json
`-- DATASET_REPORT.md   (this file)

scripts/
|-- download_wikimedia.py   (CC image downloader from Wikimedia Commons API)
|-- auto_label.py           (YOLO26n-based person detector + whole-image fire/smoke labeler)
|-- split_dataset.py        (deterministic 80/10/10 or 70/20/10 splitter)
|-- validate_dataset.py     (full YOLO-format validator + perceptual-hash duplicate detector)
|-- visualize_dataset.py    (renders bounding-box overlays for manual inspection)
`-- quarantine_duplicates.py  (moves detected duplicates to datasets/invalid/)

outputs/dataset_preview/
|-- ppe/{train,val,test}/*.png      (8 sample annotated images)
`-- fire_smoke/{train,val,test}/*.png   (9 sample annotated images)
```

---

## 12. Production Path (Day 3+ preparation)

To turn this demo dataset into a production-ready training set:

### Fire/Smoke — replace with D-Fire
1. Download D-Fire (~1 GB) from Kaggle: https://www.kaggle.com/datasets/dschettler/dfire-dataset (requires free Kaggle account).
2. Place extracted images/labels under `datasets/raw/fire_smoke/` mirroring the existing structure.
3. Skip the auto-label step (D-Fire is already YOLO-format annotated).
4. Re-run:
   ```bash
   python scripts/split_dataset.py --name fire_smoke
   python scripts/validate_dataset.py --name fire_smoke
   python scripts/visualize_dataset.py --name fire_smoke
   ```
5. The `fire_smoke.yaml` is already configured with the correct class indices (0=fire, 1=smoke) matching D-Fire.

### PPE — replace with Hard Hat Workers v2 (helmet + no_helmet) and/or GDUT-HD (full schema)
1. Download Hard Hat Workers v2 from Roboflow Universe: https://universe.roboflow.com/roboflow-universe/hard-hat-detection (free Roboflow account, API key required for download).
2. Place extracted images/labels under `datasets/raw/ppe/`.
3. Update `datasets/class_mapping.yaml` to map HHW source classes (helmet, head, person) to target classes (helmet, no_helmet, person).
4. Write a small conversion script (or extend `auto_label.py`) to perform the class remapping.
5. Re-run split, validate, visualize.
6. Update `datasets/ppe/ppe.yaml` to enable all target classes.

---

## 13. Day 3 Readiness Checklist

- [x] PPE dataset obtained (demo subset, ready for swap-in)
- [x] Fire/smoke dataset obtained (demo subset, ready for swap-in)
- [x] Dataset licenses recorded (per-image `.license.json` sidecars)
- [x] Source URLs recorded (in sidecar files)
- [x] Target classes finalized (PPE MVP: `person` only; fire/smoke: `fire`, `smoke`)
- [x] Class mapping created (`datasets/class_mapping.yaml`)
- [x] YOLO annotation format verified (validator passes with 0 errors)
- [x] Data cleaned (corrupt + duplicates removed/quarantined)
- [x] Invalid data quarantined (`datasets/invalid/ppe/duplicates/`)
- [x] Train split created
- [x] Validation split created
- [x] Test split created
- [x] No obvious data leakage (perceptual-hash duplicate check passes)
- [x] `ppe.yaml` created
- [x] `fire_smoke.yaml` created
- [x] Dataset validator works
- [x] Dataset validation passes (both datasets PASS)
- [x] Sample annotations visually checked (17 sample PNGs in `outputs/dataset_preview/`)
- [x] Dataset statistics generated (this report + JSON sidecars)
- [x] DATASET_REPORT.md created (this file)
- [x] README updated (see `README.md` Day 2 section)
