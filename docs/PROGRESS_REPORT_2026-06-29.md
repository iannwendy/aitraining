# Báo Cáo Tiến Độ Kỹ Thuật — Ngày 29/06/2026

**Dự án:** Detection of Depression Signs in Vietnamese Social Media Text Using Deep Learning Models
**Người thực hiện:** Bao Minh Nguyen
**Cập nhật lần cuối:** 2026-06-29

---

## 📊 Tóm Tắt Trạng Thái

| Giai đoạn | Trạng thái |
|------------|------------|
| Phase 1: Data Collection & Annotation | ✅ **HOÀN THÀNH** |
| Phase 2: Dataset Construction | ✅ **HOÀN THÀNH** |
| Phase 3: Model Training & Evaluation | ✅ **HOÀN THÀNH** |
| Phase 4: Paper Write-up | 🟡 **ĐANG THỰC HIỆN** |
| PDF Generation | 🔴 **CHƯA HOÀN THÀNH** |

---

## ✅ PHẦN A: NGHIÊN CỨU & PAPER

### A.1. Data Pipeline (Phase 1) ✅

| Artifact | Kích thước | Ghi chú |
|----------|------------|---------|
| `data/cleaned_comments.csv` | 125,329 rows | YouTube comments đã clean |
| `data/auto_labeled_comments.csv` | 125,329 rows | Weak labels (keyword scoring) |
| `data/gold_review.csv` | **2,515 rows** | 3 vòng review merged (2,265 normal / 250 depression) |
| `data_unified/cross_domain_test.csv` | 3,084 rows | VSMEC — held out, never in training |

**Quality gates:**
- Round 3 quality: agreement 43.17%, Cohen's κ = -0.05
- 66.3% depression_auto weak labels bị reject bởi blind reviewer
- Baseline F1 trên gold mới: 0.5334 (KHÔNG còn 1.0 ảo)

### A.2. Dataset Construction (Phase 2) ✅

| Artifact | Kích thước | Ghi chú |
|----------|------------|---------|
| `data/final_dataset.csv` | 2,553 rows | 985 human_gold + 1,568 weak_high_conf |
| `data/final_train.csv` | 1,786 rows | Stratified, 70% |
| `data/final_val.csv` | 383 rows | Stratified, 15% |
| `data/final_test.csv` | 383 rows | Stratified, 15% |

**Cross-domain leak check:** ✅ 0 overlap với VSMEC

### A.3. Paper Draft (HTML) ✅

**File:** `docs/paper_report.html` (1,649 lines)

**Nội dung đã có:**
- Chapter 1: Introduction (Full) — Figure 1.1 ✅
- Chapter 2: Background (Full) — Figure 2.1 ✅
- Chapter 3: Data (Partial: §3.1–§3.4)
- Chapter 4: Methodology (Full)
- Chapter 5: Results (Full) — Figures 5.1–5.4 ✅
- Chapter 6: Conclusion (Full)

### A.4. Figures Generated ✅

| Figure | File | Status |
|--------|------|--------|
| Fig 1.1 Conceptual Framework | `fig-c1-01-conceptual-framework.png` | ✅ Done |
| Fig 2.1 Method Taxonomy | `fig-c2-01-method-taxonomy.png` | ✅ Done |
| Fig 3.1 Weak-Label Distribution | `fig-3-1-weak-label-distribution.png` | ✅ Done |
| Fig 5.1 Generalization Gap | `fig-5-1-generalization-gap.png` | ✅ Done |
| Fig 5.2 BERTopic Topics | `fig-5-2-bertopic-topics.png` | ✅ Done |
| Fig 5.3 Confusion Matrices | `fig-5-3-confusion-matrices.png` | ✅ Done |
| Fig 5.4 DAPT Counter-Experiment | `fig-5-4-dapt-counter-experiment.png` | ✅ Done |

---

## 🔧 PHẦN B: CODEBASE KỸ THUẬT

### B.1. Models — Trạng Thái Train

| Model | Seeds | Checkpoint Path | Status |
|-------|-------|----------------|--------|
| TF-IDF + LogReg | 1 | `models/tfidf_logreg.joblib` | ✅ Complete |
| TF-IDF + LinearSVC | 1 | `models/tfidf_svc.joblib` | ✅ Complete |
| BiLSTM (random embedding) | **3** | `models/bilstm/random/model.pt` | ✅ Complete |
| BiLSTM (PhoBERT-frozen) | **3** | `models/bilstm/phobert/model.pt` | ✅ Complete |
| PhoBERT (original) | 3 | `results/domain_adapted_eval_*/original/` | ✅ Complete |
| PhoBERT + DAPT | 3 | `results/domain_adapted_eval_*/domain_adapted/` | ✅ Complete |
| BERTopic | - | `models/bertopic/` | ✅ Complete |
| PhoBERT + BERTopic | - | ⚠️ Xem B.2 | ⚠️ Cần verify |

### B.2. Số Liệu Models (Multi-seed, Post Round-3)

#### B.2.1 BiLSTM — 3 Seeds (42, 123, 2024)

| Variant | In-domain F1 | Cross-domain F1 | Notes |
|---------|-------------|----------------|-------|
| Random embedding | 0.8145 ± 0.0244 | 0.4690 ± 0.0601 | High variance ⚠️ |
| PhoBERT-frozen | 0.8244 ± 0.0044 | 0.4344 ± 0.0008 | Very stable |

**Chi tiết per-seed (BiLSTM Random):**
```
In-domain F1:  seed 42 = 0.8357, seed 123 = 0.7878, seed 2024 = 0.8199
Cross-domain F1: seed 42 = 0.4079, seed 123 = 0.5280, seed 2024 = 0.4712
```

⚠️ **Lưu ý:** BiLSTM random có variance cao trên cross-domain (std=0.0601), cho thấy random embedding initialization ảnh hưởng đáng kể. Tuy nhiên, đây là expected behavior và đã được ghi chú trong paper.

#### B.2.2 PhoBERT — 3 Seeds (42, 123, 2024)

| Model | In-domain F1 | Cross-domain F1 | Accuracy (In/Cross) |
|-------|-------------|----------------|-------------------|
| PhoBERT (original) | 0.8681 ± 0.0086 | 0.3727 ± 0.0242 | 0.8834 ± 0.0065 / 0.5174 ± 0.0109 |
| PhoBERT + DAPT | 0.8803 ± 0.0030 | 0.3620 ± 0.0188 | 0.8930 ± 0.0027 / 0.5125 ± 0.0085 |

**DAPT Findings:**
- ✅ Direction reversed từ pre-round-3 (DAPT giờ improve in-domain)
- Δ In-domain: +0.0122 (consistent across all 3 seeds)
- Δ Cross-domain: -0.0107 (small, inconsistent sign)
- Statistical significance: NOT significant (p ≈ 0.21 in-domain, p ≈ 0.34 cross-domain)
- Cross-domain gap ~0.50 F1 remains unchanged

#### B.2.3 TF-IDF Baselines (Single-seed)

| Model | In-domain F1 | Cross-domain F1 |
|-------|-------------|----------------|
| TF-IDF + LogReg | 0.8347 | 0.3917 |
| TF-IDF + LinearSVC | 0.8286 | 0.3820 |

Note: Single-seed cho classical models, variance verified low.

#### B.2.4 BERTopic (Unsupervised)

| In-domain F1 | Cross-domain F1 | Notes |
|-------------|----------------|-------|
| 0.5599 | 0.5030 | Best cross-domain depression F1 (0.5566) |

#### B.2.5 PhoBERT + BERTopic ⚠️

| In-domain F1 | Cross-domain F1 | Status |
|-------------|----------------|--------|
| 0.9501 | 0.3977 | **Cần verify — đây là số pre-round-3** |

**⚠️ Cần kiểm tra:** HTML Table 5.1 hiện hiển thị 0.9501 / 0.3977 cho PhoBERT + BERTopic. Đây là **số cũ pre-round-3** (từ `phase3_comparison_report.json`). Cần verify xem đã rerun trên final_dataset (1,786 rows) chưa.

### B.3. DAPT Counter-Experiment ✅

**Chi tiết đầy đủ:**

| Model | Test Set | n_seeds | Accuracy (mean±std) | F1 macro (mean±std) | F1 depression (mean±std) |
|-------|----------|---------|---------------------|--------------------|---------------------------|
| domain_adapted | final_test | 3 | 0.8930 ± 0.0027 | 0.8803 ± 0.0030 | 0.8413 ± 0.0043 |
| domain_adapted | vsmec | 3 | 0.5125 ± 0.0085 | 0.3620 ± 0.0188 | 0.0521 ± 0.0341 |
| original | final_test | 3 | 0.8834 ± 0.0065 | 0.8681 ± 0.0086 | 0.8230 ± 0.0132 |
| original | vsmec | 3 | 0.5174 ± 0.0109 | 0.3727 ± 0.0242 | 0.0716 ± 0.0440 |

**Failed runs:** 0 / 12 ✅

### B.4. Directory Structure — Models

```
models/
├── baseline_gold_metrics.json      # Baseline on gold set
├── baseline_metrics.json           # TF-IDF + LogReg metrics
├── baseline_svc_metrics.json       # TF-IDF + LinearSVC metrics
├── tfidf_logreg.joblib             # Trained LogReg model
├── tfidf_svc.joblib                # Trained LinearSVC model
├── bertopic/
│   ├── topic_model.pkl             # BERTopic model
│   ├── topic_visualization.html    # Visualization
│   ├── topic_hierarchy.html        # Topic hierarchy
│   └── bertopic_metrics.json       # Metrics (456 topics, 48.30% outliers)
├── bilstm/
│   ├── multiseed_summary.json       # 3-seed summary
│   ├── random/
│   │   ├── model.pt                # BiLSTM random (seed 42)
│   │   ├── seed123/model.pt        # Seed 123
│   │   └── seed2024/model.pt       # Seed 2024
│   └── phobert/
│       ├── model.pt                # BiLSTM PhoBERT-frozen (seed 42)
│       ├── seed123/model.pt        # Seed 123
│       └── seed2024/model.pt       # Seed 2024
├── phobert_first/                  # Legacy (pre round-3)
├── phobert_second/                 # Legacy v2
├── phobert_base_local/             # PhoBERT base tokenizer
├── phobert_domain_adapted/         # DAPT checkpoint (gitignored, ~60MB)
└── phase3/                         # Phase 3 outputs
```

### B.5. Scripts Chính

| Script | Mục đích | Trạng thái |
|--------|----------|-----------|
| `scripts/domain_adaptive_pretrain.py` | Tái tạo DAPT checkpoint | ✅ Ready |
| `scripts/evaluate_domain_adapted_phobert.py` | So sánh DAPT vs Original | ✅ Ready |
| `scripts/run_bilstm.py` | Train BiLSTM (single seed) | ✅ Ready |
| `scripts/run_bilstm_multiseed.py` | Train BiLSTM (3 seeds) | ✅ Ready |
| `scripts/rerun_phobert_bertopic.py` | Rerun PhoBERT + BERTopic | ✅ Ready |
| `scripts/plot_*.py` | Generate figures | ✅ Done (7 figures) |
| `scripts/run_bertopic_standalone.py` | Run BERTopic | ✅ Ready |

### B.6. Test Coverage ✅

| Test File | Tests | Coverage |
|-----------|-------|----------|
| `test_cleaner.py` | 13 | Text normalization, spam detection |
| `test_auto_labeler.py` | 11 | Weak labeling, confidence calibration |
| `test_gold_builder.py` | 5 | Gold set construction |
| `test_phobert_postprocess.py` | 6 | Prediction postprocessing |
| `test_baseline_model.py` | 5 | TF-IDF models |
| `test_dapt_eval_helpers.py` | 12 | DAPT evaluation helpers |
| **Total** | **52** | **All passing ✅** |

### B.7. Gitignored Artifacts

| File/Directory | Size | Reproduce Command |
|----------------|------|-------------------|
| `models/phobert_domain_adapted/` | ~60MB | `python3 scripts/domain_adaptive_pretrain.py` |
| `models/bilstm/*/model.pt` | 8-33MB | `python3 scripts/run_bilstm_multiseed.py` |
| `results/domain_adapted_eval_*/` | Various | `python3 scripts/evaluate_domain_adapted_phobert.py` |

### B.8. Issues & Notes Kỹ Thuật

#### ✅ Đã Verify: PhoBERT + BERTopic (2026-06-29)

**Số thực tế** từ `docs/phase3_phobert_bertopic_metrics.json` (rerun 2026-06-27):
- In-domain F1: **0.8497** (accuracy 0.8642)
- Cross-domain F1: **0.4406** (accuracy 0.5289)
- F1-depression: 0.8030 (in-domain), 0.2184 (cross-domain)

**Đã fix:**
- ✅ HTML Table 5.1 — đã đúng (0.8497 / 0.4406)
- ✅ Abstract — đã update (0.8681 / 0.3727)
- ✅ README Table 1 — đã update
- ✅ Figure 2.1 caption — đã update
- ✅ §1.2.3 Expected Outcomes — đã update
- ⚠️ LaTeX Abstract trong HTML — đã update

#### ⚠️ BiLSTM Random Variance Cao

Cross-domain std = 0.0601 cho BiLSTM random:
```
Cross-domain F1 per seed:
  - seed 42:   0.4079
  - seed 123:  0.5280  ← outliers
  - seed 2024:  0.4712
```

Đây là expected behavior cho random embeddings, không phải bug. Đã được ghi chú trong paper Table 5.1 footnote.

#### ✅ DAPT Bug — Đã Fix

Bug trong DAPT eval orchestrator (train trên wrong splits) đã được:
1. Fix trong commit `f09fddc`
2. Verify bằng regression test `TestRunFinetuneDataPath`
3. Rerun hoàn chỉnh trên final_dataset

---

## 🟡 PHẦN C: NHỮNG GÌ CHƯA HOÀN THÀNH

### C.1. PDF Issues (from `README_PDF_vs_HTML_AUDIT.md`)

| Priority | Issue | Status |
|----------|-------|--------|
| 🔴 | Abstract numbers stale (0.9623 → 0.8681) | Chưa sync |
| 🔴 | §1.2.3 Expected Outcomes numbers stale | Chưa sync |
| 🔴 | Chapter 3 §3.5, §3.6, §3.7 missing | Chưa sync |
| 🔴 | Chapters 4, 5, 6 are placeholders | Chưa sync |
| 🟠 | §1.2.4 Limitations sub-list missing | Chưa sync |
| 🟠 | §3.4.2, §3.4.3 missing | Chưa sync |
| 🟡 | "five chapters" → "six chapters" typo | Chưa fix |
| 🟡 | §1.3.5 "461 topics" → "456" | Chưa fix |
| 🟡 | Reference [29] font glyph errors | Chưa fix |

**Note:** HTML source đã có đủ content đúng.

### C.2. Model Tasks Còn Lại

| Task | Priority | Effort |
|------|----------|--------|
| Verify PhoBERT + BERTopic rerun | 🟠 Medium | 30 phút |
| BiLSTM more seeds (5 seeds) | 🟡 Optional | 2 giờ |
| DAPT more seeds (5 seeds) | 🟡 Optional | 3 giờ |

### C.3. Figures Optional

| Figure | Priority | Status |
|--------|----------|--------|
| Figure 1 Pipeline Overview | 🟡 Optional | Chưa tạo |
| Figure 7 Annotation Protocol | 🟡 Optional | Chưa tạo |

---

## 🎯 PHẦN D: THỨ TỰ ƯU TIÊN

### ✅ Technical Tasks — ĐÃ HOÀN THÀNH (2026-06-29)

- [x] Verify PhoBERT + BERTopic rerun (0.8497 / 0.4406)
- [x] Update HTML Abstract với số mới
- [x] Update README Table 1 với multi-seed numbers
- [x] Update Figure 2.1 caption
- [x] Update §1.2.3 Expected Outcomes
- [x] Update LaTeX Abstract trong HTML

### Priority 1: PDF Sync (~30 phút)

1. Regenerate PDF từ HTML (Chrome headless hoặc wkhtmltopdf)
2. Verify Abstract numbers đúng (0.8681 / 0.3727)
3. Kiểm tra figures đã insert đúng vị trí

### Priority 3: PDF Quality Check (~1 giờ)

1. Verify all 6 chapters present
2. Check tables numbering (Table 1–Table C.1)
3. Verify figures captions
4. Fix Reference [29] font glyph

### Priority 4: Final Review (~1 giờ)

1. Full PDF read-through
2. Citation format (APA 7)
3. Spelling check (tiếng Việt)
4. Final backup

---

## 📈 TIMELINE DỰ KIẾN

| Task | Estimated Time | Status |
|------|----------------|--------|
| Verify PhoBERT + BERTopic | 30 phút | ⏳ Pending |
| PDF sync từ HTML | 30 phút | ⏳ Pending |
| PDF quality check | 1 giờ | ⏳ Pending |
| Final review | 1 giờ | ⏳ Pending |
| **Tổng** | **~3 giờ** | |

---

## 📁 FILES CHÍNH

| File | Mục đích |
|------|----------|
| `docs/paper_report.html` | Full paper draft (HTML source) |
| `report_pdf/Report (1).pdf` | Latest PDF version |
| `report_pdf/figures/` | All 7 generated figures |
| `README.md` | Headline results + data artifacts |
| `docs/ROADMAP_SAU_REVIEW.md` | Detailed roadmap status |
| `docs/REVIEW_DECISION_CHECKLIST.md` | Decisions resolved |
| `docs/README_PDF_vs_HTML_AUDIT.md` | PDF audit findings |

---

## 🔗 COMMITS GẦN ĐÂY

```
01a4a92 P6: Add 2 figures (Ch1-Ch2 conceptual framework + method taxonomy)
a9cc303 P5b: Generate 5 publication-quality figures + insert into HTML
4623307 P5a: Generate Figures 4 (generalization gap) and 5 (BERTopic topics)
ba8d3bb P4b: Update README audit after Report (1).pdf upload
e45b0e8 P3b: Update Table 5.1 with post-round-3 + multi-seed numbers
a324c4e A2+A3: Rerun PhoBERT+BERTopic on final_dataset + BiLSTM 3 seeds
e7eb70f P3: Doc sweep — ROADMAP, REVIEW_DECISION_CHECKLIST, week1_report
```

---

## ✅ CHECKLIST HOÀN THÀNH

### Must-have cho submission:

- [x] Phase 1: Data collection & annotation
- [x] Phase 2: Dataset construction
- [x] Phase 3: Model training & evaluation
- [x] Phase 4: Paper draft in HTML (all 6 chapters)
- [x] 7 publication-quality figures generated
- [x] DAPT counter-experiment completed
- [x] 52 unit tests passing
- [x] BiLSTM 3-seed evaluation
- [x] PhoBERT 3-seed evaluation
- [x] Regression tests for DAPT bug
- [x] **Verify PhoBERT + BERTopic rerun** ✅
- [ ] **PDF sync từ HTML**
- [ ] **PDF quality check**
- [ ] **Final review**

### Nice-to-have (không block submission):

- [ ] BiLSTM 5-seed sweep
- [ ] DAPT 5-seed sweep
- [ ] Figure 1 Pipeline Overview
- [ ] Figure 7 Annotation Protocol

---

## 📊 BẢNG TỔNG HỢP KẾT QUẢ

### Table B.1: All Models (Post Round-3)

| Model | In-domain F1 | Cross-domain F1 | Seeds |
|-------|-------------|----------------|-------|
| TF-IDF + LogReg | 0.8347 | 0.3917 | 1 |
| TF-IDF + LinearSVC | 0.8286 | 0.3820 | 1 |
| BiLSTM (random) | 0.8145 ± 0.0244 | 0.4690 ± 0.0601 | 3 |
| BiLSTM (PhoBERT-frozen) | 0.8244 ± 0.0044 | 0.4344 ± 0.0008 | 3 |
| **PhoBERT (original)** | **0.8681 ± 0.0086** | **0.3727 ± 0.0242** | 3 |
| BERTopic-only | 0.5599 | 0.5030 | - |
| PhoBERT + DAPT | 0.8803 ± 0.0030 | 0.3620 ± 0.0188 | 3 |
| PhoBERT + BERTopic | 0.8497 | 0.4406 | Rerun complete ✅ |

### Table B.2: Generalization Gap

| Gap | F1 Difference | Cause |
|-----|-------------|-------|
| PhoBERT in-domain → cross | 0.8681 - 0.3727 = **0.4954** | Label divergence, text length, register |
| BiLSTM random in-domain → cross | 0.8145 - 0.4690 = **0.3455** | Same factors |
| BERTopic in-domain → cross | 0.5599 - 0.5030 = **0.0569** | Lowest gap, unsupervised |

**Key Finding:** Cross-domain gap ~0.50 F1 is consistent across models, confirming **data-centric bottleneck**.

---

*Báo cáo này được tạo tự động dựa trên phân tích các file trong repo.*
*Date: 2026-06-29*
