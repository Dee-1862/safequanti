# SafeQuant: Phased Diagnostic Approach

## ? The Strategy

We're narrowing down the bottleneck in 4 phases:

1. **Phase 1: Integrity Checks** (30 min) - Verify restoration code works
2. **Phase 2: Per-Matrix Recovery** (2-4 hours) - Which matrix type?
3. **Phase 3: Per-Layer Ablation** (2-4 hours) - Which layers?
4. **Phase 4: V-Scores + Sparse Fix** (1 hour) - Which columns?

**Result:** From "read side is broken" -> "these 50 specific columns in 5 specific layers of up_proj"

---

## ? Quick Start

### Option A: Run Today (Phase 1 + 2 only)

```bash
# Submit to GPU
sbatch run_phase1_phase2.sbatch

# Check status
squeue -u $USER

# View output when done
tail -f safequant_phase12_*.out
```

**What you get:**
- Verification that code works (Phase 1)
- Which matrix type is the bottleneck (Phase 2)

**Time:** ~2-4 hours on GPU

---

### Option B: Full Pipeline (All 4 Phases)

```bash
# Interactive (can monitor progress)
bash run_phased_diagnostics.sh qwen1.5b 100

# Or submit to batch (runs overnight)
# (TODO: create full sbatch script)
```

**Time:** ~6-10 hours total

---

## ? Phase-by-Phase Guide

### Phase 1: Integrity Checks ?

**What it does:**
- Checks that restoring ALL matrices exactly reproduces FP32
- Checks that un-restored matrices stay quantized

**Run:**
```bash
python diagnostics/integrity_checks.py --model qwen0.5b --n_eval 20
```

**Expected output:**
```
CHECK 1: Weight Identity Test
  FP32 ASR:    22.0%
  Restored ASR: 22.5%
  Difference:  0.5pp
OK PASS

CHECK 2: Quantization Persistence Test
  5/5 read matrices still Params4bit
OK PASS

OK ALL CHECKS PASSED
```

**If it fails:** Fix restoration code before proceeding!

**Time:** ~10-20 minutes

---

### Phase 2: Per-Matrix-Type Recovery ?

**What it does:**
- Restores each matrix type (q/k/v/gate/up/o/down) individually
- Computes recovery ratio for each

**Run:**
```bash
python diagnostics/matrix_type_recovery.py --model qwen1.5b --n_eval 100
```

**Expected output:**
```
Matrix Type   Side   ASR    Recovery   Ratio
--------------------------------------------
up_proj       read   20%    +20pp      111%
gate_proj     read   35%    +5pp       28%
q_proj        read   38%    +2pp       11%
down_proj     write  40%    +0pp       0%
o_proj        write  40%    +0pp       0%
...

OK Primary Bottleneck: up_proj (read side)
  Recovers 111% of safety damage
```

**Interpretation:**
- `up_proj` alone recovers 111% of damage (even better than FP32!)
- Write matrices recover ~0% (as expected)

**Time:** ~2-4 hours for 100 prompts x 7 matrix types

---

### Phase 3: Per-Layer Ablation ?

**What it does:**
- Takes winning matrix type from Phase 2
- Restores it one layer at a time (28 experiments)

**Run:**
```bash
python diagnostics/layer_recovery.py \
    --model qwen1.5b \
    --matrix_type up_proj \
    --proj_path mlp.up_proj \
    --n_eval 100
```

**Expected output:**
```
Layer    ASR    Recovery   Ratio
---------------------------------
12       25%    +15pp      83%
13       26%    +14pp      78%
14       28%    +12pp      67%
...
OK Top-5 Critical Layers: [12, 13, 14, 15, 16]
  Combined contribution: 400% of damage
```

**Interpretation:**
- Layers 12-16 are the critical layers
- Rest of layers contribute little

**Time:** ~2-4 hours for 100 prompts x 28 layers

---

### Phase 4: V-Scores + Sparse Restoration ?

**What it does:**
- Computes per-column V-scores for critical matrix/layers
- Tests sparse restoration (restore top-k% of columns)

**Run:**
```bash
# First compute refusal direction (prerequisite)
python core/refusal_direction.py --model qwen1.5b --n_samples 100

# Compute V-scores (for critical layers only)
python diagnostics/column_vscores.py \
    --model qwen1.5b \
    --matrix_type up_proj \
    --proj_path mlp.up_proj \
    --layers "12,13,14,15,16"

# Test sparse restoration
python diagnostics/sparse_column_restore.py \
    --model qwen1.5b \
    --vscores outputs/column_vscores_up_proj.json \
    --top_k "10,50,100,200" \
    --n_eval 100
```

**Expected output:**
```
Top-K    ASR    Recovery   Ratio   Overhead
-------------------------------------------
10       35%    +5pp       28%     1.2%
50       22%    +18pp      100%    5.8%
100      18%    +22pp      122%    11.5%
200      16%    +24pp      133%    23.0%
```

**Interpretation:**
- Restoring top-50 columns (5.8% overhead) fully recovers safety!
- Top-10 is too sparse, top-200 is overkill
- Sweet spot: 50-100 columns

**Time:** ~1 hour

---

## ? What You Get

After all 4 phases, you can say:

> "Safety degradation is localized to **50 specific columns** in **5 specific layers** of **up_proj**. Restoring just these columns (5.8% memory overhead) fully recovers safety, while quantizing all other weights."

**This is:**
- ? Novel (no prior work has this level of granularity)
- ? Practical (5.8% overhead is deployable)
- ? Mechanistic (explains exactly where/why safety breaks)

---

## ? For Your Professor

### After Phase 1 + 2 (TODAY):

Show them `outputs/matrix_type_recovery.json`:

```json
{
  "primary_bottleneck": {
    "matrix_type": "up_proj",
    "side": "read",
    "recovery_ratio": 111
  }
}
```

**Say:**
> "I've identified that up_proj (a single read matrix type) is responsible for 111% of the safety damage. Write matrices contribute 0%. This proves Read-Side Collapse at the matrix-type level."

### After All Phases:

Show the funnel:
1. Read side > write side (already known)
2. up_proj is the bottleneck (Phase 2)
3. Layers 12-16 are critical (Phase 3)
4. Top-50 columns in those layers are sufficient (Phase 4)

**Say:**
> "I've narrowed the bottleneck from '3.5 billion parameters' down to '50 specific columns' (0.001% of weights). Restoring just those recovers all safety."

---

## ? Important Notes

1. **Run Phase 1 FIRST on qwen0.5b** (fast validation)
2. **Don't skip phases** - each depends on the previous
3. **Phase 2 is the highest priority** - do this TODAY
4. **Phases 3-4 are optional** but make the paper much stronger

---

## ? Output Files

After completion:
```
outputs/
?-- integrity_checks.json           [Phase 1]
?-- matrix_type_recovery.json       [Phase 2] <- Shows winner
?-- layer_recovery_up_proj.json     [Phase 3] <- Critical layers
?-- column_vscores_up_proj.json     [Phase 4] <- V-scores
?-- sparse_column_restoration.json  [Phase 4] <- Final validation
```

---

## ?? Time Estimates

| Phase | Time (qwen1.5b, n=100) | Priority |
|-------|------------------------|----------|
| Phase 1 | 20 min | **DO FIRST** |
| Phase 2 | 2-4 hours | **DO TODAY** |
| Phase 3 | 2-4 hours | Do if time |
| Phase 4 | 1 hour | Do if time |

**Recommendation:** Run Phase 1+2 today (submit `run_phase1_phase2.sbatch`), then decide on 3+4 after reviewing Phase 2 results.

---

## ? Troubleshooting

**"Phase 1 integrity checks failed"**
-> Restoration code is broken, fix before proceeding

**"Phase 2 shows write matrices win"**
-> Unexpected! Double-check your earlier full-restoration results

**"Can't find refusal_direction.pt for Phase 4"**
-> Run: `python core/refusal_direction.py --model qwen1.5b`

**"Jobs timing out"**
-> Reduce `--n_eval` (try 50 instead of 100)
-> Or increase SLURM time limit

---

## ? Next Steps

**Right now:**
```bash
sbatch run_phase1_phase2.sbatch
```

**Tomorrow (after results):**
- Check `outputs/matrix_type_recovery.json`
- If `up_proj` won -> run Phase 3 for `up_proj`
- If something else won -> adjust Phase 3 command

**End of week:**
- Complete all 4 phases
- Generate visualizations
- Start writing paper
