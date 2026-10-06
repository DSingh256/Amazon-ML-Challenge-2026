"""
aml26-ens3a: ASSIGN ONLY with the model trained by aml26-ens3 v29 (ens3b: holdout 0.9874) whose
assign ran out of memory; stage-2 frame built column by column, CE columns assigned in place.

aml26-ens3 = aml26-ens2 + SAME-NAME / SAME-ADDRESS RIVAL features in stage 2 (rival.py, found with
the local ctx2 re-scorer: +0.0015 honest on the holdout) + the holdout pairs saved (work/dec) for
local decoder tuning. Everything else as ens2, so ens3 vs ens2 is a clean A/B. v28.

aml26-ens2: the FINAL combination, CPU only. v27.
    base      : aml26-wide30 (30 candidates per record instead of 15: more true matches reachable)
    LLM layer : mean cross-encoder score of EVERY aml26-llm<N> notebook in the inputs (llm2..llm7)
    self-training: sure test pairs of wide30's model become extra stage-2 learning pairs (as pseudo1)
(below: the pseudo1 description, which still holds)

aml26-pseudo1: self-training (pseudo-labels) on the TEST set, CPU only. v25.

The test set has a country the training data does not have (France). The model never saw
a French match, so its French probabilities are less right. Self-training lets the model
see test data: the test pairs the current model (SRC = aml26-ens1) is almost sure about
become extra training examples for stage 2.
    positive : the pair keeps its Source 2/3 record after exclusivity and p >= POS
    negative : p <= NEG
No hand labels, no external data, no country rule: every test record is treated the same.

Steps
    gen    : SRC's models score all test pairs (stage 1 -> collective -> cross-encoder -> stage 2,
             exactly like assign.py), pick the sure pairs, write work/pseudo/pseudo_pairs.parquet
             with every stage-2 feature + label
    train  : train.py patched: the pseudo pairs are added to the LEARNING part only (early
             stopping and the holdout stay real train labels, so the holdout still tells
             whether India / US got worse)
    assign : the new model -> matching_results.tsv (+ t0.5/0.6/0.8 files, test probabilities)
"""
import gc
import json
import os
import shutil
import subprocess
import sys
import time
import zipfile
from pathlib import Path

NOTEBOOK_START = time.time()
SRC = "aml26-wide30"
NOTE = "v31 ens3c (ens3b + llm7 CE, seed 7, memory patches): ens2 + rival features + 12% pseudo pairs (float32; v28 ran out of memory)"
RIVAL_B64 = """"
Same-name / same-address RIVAL features (ens3; found with ctx2/ctx3 on the holdout).

40% of Source 1 names occur more than once (one business name, several addresses), and many
Source 1 addresses hold several businesses. A Source 2/3 copy with an empty address (or with a
made-up name) fits every such rival about equally, so a pair model that looks at ONE pair gives
each ~1/n. The copy was made from ONE of them: its exact spelling ("Ltd" vs "Limited", "Inc" or
not, the numbers of the address) points at the owner. For every unsure pair these features compare
the copy with ALL Source 1 records of the split that share its name key (or its address numbers).
They are counted over the FULL Source 1 table of the split (train or test), so the 25% training
sample does not change them: train and test get the same kind of numbers.
Only pairs with a stage-1 probability in (LOW, HIGH) get them (the others: NaN), in train and test alike.
"""
import os
from pathlib import Path

import numpy as np
import pandas as pd
import pyarrow as pa
import pyarrow.csv as pc
from rapidfuzz import fuzz

LOW, HIGH = 0.005, 0.995
MAX_RIVALS = 300
LEGAL = set("llc inc ltd limited pvt private corp corporation co company the lp llp pc pa plc pllc sarl sas "
            "sasu eurl sa sci and of".split())
RIVAL_COLUMNS = ["rv_empty", "rv_key_eq", "rv_n1", "rv_n2", "rv_sim", "rv_tset", "rv_gap_best", "rv_n_better",
                 "rv_n_tie", "rv_gap_second", "rv_asim", "rv_ad_n2", "rv_ad_gap_best", "rv_ad_better",
                 "rv_ad_gap_second", "rv_n_words", "rv_max_word"]
_TABLES = {}


def _read(path, cols):
    t = pc.read_csv(path, parse_options=pc.ParseOptions(delimiter="\t", quote_char=False),
                    convert_options=pc.ConvertOptions(include_columns=cols,
                                                      column_types={c: pa.string() for c in cols}))
    return {c: t.column(c).combine_chunks() for c in cols}


def plain(texts):
    s = pd.Series(texts, dtype=object).fillna("").str.lower()
    s = s.str.normalize("NFKD").str.encode("ascii", "ignore").str.decode("ascii")
    return s.str.replace(r"\s+", " ", regex=True).str.strip()


def name_key(pl):
    s = pl.str.replace(r"www\.\S+|https?://\S+|\S+@\S+|\S+\.com\b", " ", regex=True)
    s = s.str.replace(r"\(id:?\s*\d+\)|\d{6,}", " ", regex=True)
    s = s.str.replace(r"[^a-z0-9 ]", " ", regex=True)
    s = s.str.replace(r"\b(\w+)( \1\b)+", r"\1", regex=True)
    return s.map(lambda x: " ".join(w for w in x.split() if w not in LEGAL))


def digit_key(addr):
    return addr.str.findall(r"\d+").map(lambda x: " ".join(sorted(set(x))))


def _groups(keys):
    """key -> (sorted row numbers, bounds) without a Python dict of arrays."""
    codes, uniques = pd.factorize(keys)
    order = np.argsort(codes, kind="stable")
    bounds = np.searchsorted(codes[order], np.arange(len(uniques) + 1))
    return pd.Index(uniques), order, bounds


def _tables(n_s23):
    """Full Source 1 (names, keys, addresses) and Source 2/3 (names, addresses) of the split whose
    Source 2/3 table has n_s23 rows."""
    if n_s23 in _TABLES:
        return _TABLES[n_s23]
    data = Path(os.environ["AML26_DATA"])
    for split in ("test", "train"):
        d = data / split
        if not (d / f"{split}_source1.tsv").exists():
            continue
        s23 = [_read(d / f"{split}_source{k}.tsv", ["business_name", "business_address"]) for k in (2, 3)]
        if sum(len(x["business_name"]) for x in s23) != n_s23:
            continue
        s1 = _read(d / f"{split}_source1.tsv", ["business_name", "business_address"])
        t = {"s1_plain": plain(s1["business_name"].to_numpy(zero_copy_only=False)),
             "s1_addr": plain(s1["business_address"].to_numpy(zero_copy_only=False)),
             "s23_name": pa.concat_arrays([x["business_name"] for x in s23]),
             "s23_addr": pa.concat_arrays([x["business_address"] for x in s23])}
        del s1, s23
        t["s1_key"] = name_key(t["s1_plain"])
        t["s1_dkey"] = digit_key(t["s1_addr"])
        t["name_groups"] = _groups(t["s1_key"].to_numpy())
        t["addr_groups"] = _groups(t["s1_dkey"].to_numpy())
        t["n_key"] = t["s1_key"].map(t["s1_key"].value_counts()).to_numpy(dtype=np.float32)
        print(f"rival: {split} tables loaded ({len(t['s1_plain']):,} Source 1, {n_s23:,} Source 2/3 records)", flush=True)
        _TABLES[n_s23] = t
        return t
    raise SystemExit(f"rival: no split with {n_s23:,} Source 2/3 records under {data}")


def release():
    _TABLES.clear()


def _rivals(query, own, groups, key, s1_texts, scorer, own_score):
    """Scores of the query text against every Source 1 record with this key."""
    index, order, bounds = groups
    code = index.get_indexer([key])[0]
    if code < 0:
        return None
    rs = order[bounds[code]:bounds[code + 1]]
    if len(rs) == 0 or len(rs) > MAX_RIVALS:
        return None
    sc = np.fromiter((scorer(query, s1_texts[r]) for r in rs), dtype=np.float32, count=len(rs))
    others = sc[rs != own]
    return sc.max(), (sc > own_score).sum(), (sc == own_score).sum() - (own in rs), (others.max() if len(others) else np.nan)


def rival_features(s1_row, s23_row, p, n_s23):
    """dict RIVAL_COLUMNS -> float32 arrays (NaN outside the unsure window)."""
    n = len(p)
    out = {c: np.full(n, np.nan, dtype=np.float32) for c in RIVAL_COLUMNS}
    w = np.flatnonzero((p > LOW) & (p < HIGH))
    if len(w) == 0:
        return out
    t = _tables(n_s23)
    a = s1_row[w]
    u, inv = np.unique(s23_row[w], return_inverse=True)
    take = pa.array(u)
    r_plain = plain(t["s23_name"].take(take).to_numpy(zero_copy_only=False))
    r_addr = plain(t["s23_addr"].take(take).to_numpy(zero_copy_only=False))
    r_key, r_dkey = name_key(r_plain), digit_key(r_addr)
    b_plain, b_key = r_plain.to_numpy()[inv], r_key.to_numpy()[inv]
    b_addr, b_dkey = r_addr.to_numpy()[inv], r_dkey.to_numpy()[inv]
    s1_plain, s1_key, s1_addr = t["s1_plain"].to_numpy(), t["s1_key"].to_numpy(), t["s1_addr"].to_numpy()
    s1_dkey = t["s1_dkey"].to_numpy()
    a_plain, a_key, a_addr = s1_plain[a], s1_key[a], s1_addr[a]
    empty = (b_addr == "").astype(np.float32)
    sim = np.array([fuzz.ratio(x, y) for x, y in zip(a_plain, b_plain)], dtype=np.float32)
    asim = np.array([fuzz.token_set_ratio(x, y) for x, y in zip(a_addr, b_addr)], dtype=np.float32)
    kc = t["s1_key"].value_counts()
    n2 = pd.Series(b_key).map(kc).fillna(0).to_numpy(dtype=np.float32)
    dc = t["s1_dkey"].value_counts()
    ad_n2 = pd.Series(b_dkey).map(dc).fillna(0).to_numpy(dtype=np.float32)
    ad_n2[b_dkey == ""] = -1
    cols = {c: np.full(len(w), np.nan, dtype=np.float32) for c in RIVAL_COLUMNS}
    for i in range(len(w)):
        r = _rivals(b_plain[i], a[i], t["name_groups"], b_key[i], s1_plain, fuzz.ratio, sim[i])
        if r is not None:
            cols["rv_gap_best"][i], cols["rv_n_better"][i], cols["rv_n_tie"][i] = sim[i] - r[0], r[1], r[2]
            cols["rv_gap_second"][i] = sim[i] - r[3]
        if b_dkey[i]:
            r = _rivals(b_addr[i], a[i], t["addr_groups"], b_dkey[i], s1_addr, fuzz.token_set_ratio, asim[i])
            if r is not None:
                cols["rv_ad_gap_best"][i], cols["rv_ad_better"][i] = asim[i] - r[0], r[1]
                cols["rv_ad_gap_second"][i] = asim[i] - r[3]
    words = pd.Series(b_plain).str.split()
    cols.update({
        "rv_empty": empty, "rv_key_eq": (a_key == b_key).astype(np.float32), "rv_n1": t["n_key"][a],
        "rv_n2": n2, "rv_sim": sim,
        "rv_tset": np.array([fuzz.token_set_ratio(x, y) for x, y in zip(a_key, b_key)], dtype=np.float32),
        "rv_asim": asim, "rv_ad_n2": ad_n2,
        "rv_n_words": words.str.len().to_numpy(dtype=np.float32),
        "rv_max_word": words.map(lambda x: max((len(y) for y in x), default=0)).to_numpy(dtype=np.float32)})
    for c in RIVAL_COLUMNS:
        out[c][w] = cols[c]
    print(f"rival: features for {len(w):,} of {n:,} pairs", flush=True)
    return out
"
POS, NEG = 0.95, 0.02
PSEUDO_SHARE = 0.12        # pseudo pairs at most 12% of the real learning pairs (0.30 ran out of memory: 31 GB)
EXTRA_THRESHOLDS = (0.5, 0.6, 0.8)
N_JOBS = 4
PACKAGES = ["anyascii==0.3.3", "rapidfuzz==3.14.6", "sparse_dot_topn==1.2.0"]
PIPELINE_TIME_LIMIT = 11.25 * 3600

INPUT = Path("/kaggle/input")
WORKING = Path("/kaggle/working")
DATA = WORKING / "data"
WORK = WORKING / "work"
SRC_MODELS = WORKING / "src_models"


def say(message):
    print(f"### {message}", flush=True)


def find(name):
    return sorted(p for root in (INPUT, WORKING / "unzipped") if root.exists() for p in root.rglob(name))


def link(source, target):
    target.parent.mkdir(parents=True, exist_ok=True)
    if not target.exists():
        os.symlink(source, target)


def combine_ce_scores():
    """The ensemble: for every pair, the mean of the cross-encoder scores (logits) of all
    LLM-layer notebooks given as input (aml26-llm<N>). Written to WORK/<split>/ce_scores.parquet
    BEFORE the other inputs are linked, so train / assign use the mean instead of one model."""
    import re
    import pandas as pd
    for split in ("train", "test"):
        files = sorted(p for p in INPUT.rglob(f"work/{split}/ce_scores.parquet")
                       if re.search(r"aml26-llm\d", str(p)))
        if not files:
            raise SystemExit(f"no {split} ce_scores.parquet of an aml26-llm notebook in the inputs")
        parts = []
        for i, path in enumerate(files):
            part = pd.read_parquet(path, columns=["s1_row", "s23_row", "ce"])
            say(f"{split}: {path} -> {len(part):,} pairs, ce mean {part['ce'].mean():.3f} sd {part['ce'].std():.3f}")
            parts.append(part.rename(columns={"ce": f"ce{i}"}).set_index(["s1_row", "s23_row"]))
        wide = pd.concat(parts, axis=1, join="outer")
        common = wide.dropna()
        say(f"{split}: {len(common):,} pairs scored by all {len(files)} models; correlations:\n{common.corr().round(4)}")
        out = wide.mean(axis=1).rename("ce").astype("float32").reset_index()
        target = WORK / split / "ce_scores.parquet"
        target.parent.mkdir(parents=True, exist_ok=True)
        out.to_parquet(target, index=False)
        say(f"{split}: mean score of {len(out):,} pairs -> {target}")


def prepare():
    subprocess.run([sys.executable, "-m", "pip", "install", "-q", *PACKAGES])
    if not find("test_source1.tsv"):
        for archive in find("*.zip"):
            zipfile.ZipFile(archive).extractall(WORKING / "unzipped")
    for split, names in {"train": ["train_source1.tsv", "train_source2.tsv", "train_source3.tsv",
                                   "train_ground_truth.tsv"],
                         "test": ["test_source1.tsv", "test_source2.tsv", "test_source3.tsv"]}.items():
        for name in names:
            link(find(name)[0], DATA / split / name)
    # SRC's cross-encoder scores (what its model was trained with): gen uses them to reproduce SRC's p
    found = [p for p in INPUT.rglob("work/test/ce_scores.parquet") if SRC in str(p)]
    if not found:
        raise SystemExit(f"{SRC} work/test/ce_scores.parquet not found (did {SRC} finish?)")
    link(found[0], WORK / "test" / "ce_src.parquet")
    say(f"test/ce_src.parquet <- {found[0]}")
    combine_ce_scores()      # the new mean of all llm notebooks -> work/<split>/ce_scores.parquet
    meta = [p for p in INPUT.rglob("work/models/meta.json") if SRC in str(p)]
    if not meta:
        raise SystemExit(f"{SRC} models not found")
    for path in meta[0].parent.iterdir():
        link(path, SRC_MODELS / path.name)
    # everything else (features, cleaned tables, candidates): SRC's files first (its 30-candidate
    # features win), then the block notebooks; the llm notebooks' scores are already in the mean
    import re
    count = 0
    paths = [p for p in INPUT.rglob("work/*/*") if p.is_file() and p.parent.name in ("train", "test")
             and not re.search(r"aml26-llm\d", str(p))]
    for path in sorted(paths, key=lambda p: SRC not in str(p)):
        if not (WORK / path.parent.name / path.name).exists():
            link(path, WORK / path.parent.name / path.name)
            count += 1
    say(f"reusing {count} files of the input notebooks")
    for needed in ["train/features.parquet", "train/candidates.parquet", "test/features.parquet",
                   "test/candidate_pairs.tsv", "test/s1_clean.parquet", "test/s23_clean.parquet"]:
        if not (WORK / needed).exists():
            raise SystemExit(f"work/{needed} missing")


def code_dir():
    return find("run_pipeline.py")[0].parent


# ---------------------------------------------------------------------------
# gen: the pseudo-labelled test pairs (runs in its own process: frees its memory)
# ---------------------------------------------------------------------------
def gen():
    import numpy as np
    import pandas as pd
    import lightgbm as lgb
    import pyarrow.parquet as pq
    sys.path.insert(0, "/tmp/aml26_code")
    from stage2 import collective_features
    from rival import RIVAL_COLUMNS
    from cross_encoder import ce_features

    split_dir = WORK / "test"
    meta = json.loads((SRC_MODELS / "meta.json").read_text())
    model = lgb.Booster(model_file=str(SRC_MODELS / "lgbm.txt"))
    stage1 = [lgb.Booster(model_file=str(SRC_MODELS / n)) for n in meta["stage1_models"]]
    first = meta["stage1_features"]
    file = pq.ParquetFile(split_dir / "features.parquet")

    def batches(columns):
        for batch in file.iter_batches(batch_size=1_000_000, columns=["s1_row", "s23_row"] + columns):
            yield batch.to_pandas()

    rows, p1 = [], []
    for batch in batches(first):
        rows.append(batch[["s1_row", "s23_row"]].to_numpy())
        p1.append((sum(m.predict(batch[first]) for m in stage1) / len(stage1)).astype(np.float32))
    rows = np.concatenate(rows)
    p1 = np.concatenate(p1)
    s1_row, s23_row = rows[:, 0], rows[:, 1]
    del rows
    say(f"gen: stage 1 of {len(p1):,} test pairs done")
    s23 = pd.read_parquet(split_dir / "s23_clean.parquet", columns=["name_core", "addr_clean"])
    extra = collective_features([(s1_row, s23_row, p1)], s23["name_core"].to_numpy(),
                                s23["addr_clean"].to_numpy())[0]
    del s23
    collective = extra
    scores = pd.read_parquet(split_dir / "ce_src.parquet")
    extra = pd.concat([collective, ce_features(s1_row, s23_row, scores)], axis=1)
    del scores
    say(f"gen: collective + cross-encoder features ready {list(extra.columns)}")

    p = np.empty(len(p1), dtype=np.float32)
    start = 0
    for batch in batches(first):
        stop = start + len(batch)
        batch = pd.concat([batch.reset_index(drop=True), extra.iloc[start:stop].reset_index(drop=True)], axis=1)
        p[start:stop] = model.predict(batch[meta["features"]])
        start = stop
    saved = [q for q in INPUT.rglob("test_pair_probabilities.parquet") if SRC in str(q)]
    if saved:
        old = pd.read_parquet(saved[0])["probability"].to_numpy()
        if len(old) == len(p):
            say(f"gen: check vs {SRC}'s saved probabilities: max abs diff {np.abs(old - p).max():.2e}")

    del extra
    gc.collect()
    scores = pd.read_parquet(split_dir / "ce_scores.parquet")
    new_ce = ce_features(s1_row, s23_row, scores)
    del scores
    say(f"gen: new cross-encoder mean: {new_ce.notna().mean().round(3).to_dict()} of pairs scored")
    extra = pd.concat([collective, new_ce], axis=1)
    del collective, new_ce

    # exclusivity winners: the best s1 for every s23
    order = np.lexsort((-p, s23_row))
    winner = np.zeros(len(p), dtype=bool)
    first_of = np.r_[True, s23_row[order][1:] != s23_row[order][:-1]]
    winner[order[first_of]] = True
    positive = winner & (p >= POS)
    negative = p <= NEG

    labels = pq.read_table(WORK / "train" / "features.parquet", columns=["label"]).column(0).to_numpy()
    n_learn = int(len(labels) * 0.8)
    rate = float(labels.mean())
    del labels
    cap_pos, cap_neg = int(PSEUDO_SHARE * n_learn * rate), int(PSEUDO_SHARE * n_learn * (1 - rate))
    rng = np.random.default_rng(7)

    def sample(mask, cap):
        idx = np.flatnonzero(mask)
        return np.sort(rng.choice(idx, cap, replace=False)) if len(idx) > cap else idx

    pos_idx, neg_idx = sample(positive, cap_pos), sample(negative, cap_neg)
    say(f"gen: sure test pairs: {positive.sum():,} positive (p>={POS}, exclusive), {negative.sum():,} negative "
        f"(p<={NEG}); train positive rate {rate:.3f}, learning pairs ~{n_learn:,}; "
        f"taking {len(pos_idx):,} + {len(neg_idx):,}")
    country = pd.read_parquet(split_dir / "s1_clean.parquet", columns=["country"])["country"].to_numpy()
    say("gen: positives by country (log only) " + str(pd.Series(country[s1_row[pos_idx]]).value_counts().to_dict()))
    say("gen: test records by country (log only) " + str(pd.Series(country).value_counts().to_dict()))
    say("gen: p between 0.3 and 0.9 (unsure) by country (log only) "
        + str(pd.Series(country[s1_row[winner & (p > 0.3) & (p < 0.9)]]).value_counts().to_dict()))

    take = np.zeros(len(p), dtype=bool)
    take[pos_idx] = True
    take[neg_idx] = True
    label = positive.astype(np.int8)
    parts = []
    start = 0
    for batch in batches(first):
        stop = start + len(batch)
        sel = take[start:stop]
        if sel.any():
            part = pd.concat([batch.reset_index(drop=True), extra.iloc[start:stop].reset_index(drop=True)], axis=1)[sel]
            part = part[list(dict.fromkeys(meta["features"] + RIVAL_COLUMNS))].copy()
            part["label"] = label[start:stop][sel]
            parts.append(part)
        start = stop
    out = pd.concat(parts, ignore_index=True)
    (WORK / "pseudo").mkdir(parents=True, exist_ok=True)
    out.to_parquet(WORK / "pseudo" / "pseudo_pairs.parquet", index=False)
    say(f"gen: wrote {len(out):,} pseudo pairs ({out['label'].mean():.3f} positive), {out.shape[1]} columns")


# ---------------------------------------------------------------------------
# patched copy of the code
# ---------------------------------------------------------------------------
TRAIN_OLD = "    model, curve = train_model(learning, stopping, columns)\n"
TRAIN_NEW = """    pseudo_file = work_dir / "pseudo" / "pseudo_pairs.parquet"
    if pseudo_file.exists():
        pseudo = pd.read_parquet(pseudo_file)
        missing = [c for c in columns if c not in pseudo.columns]
        if missing:
            raise SystemExit(f"pseudo pairs lack the columns {missing}")
        n_real = len(learning)
        learning = learning[columns + ["label"]]
        pseudo = pseudo[columns + ["label"]]
        for c in columns:       # column by column: float32 halves the frames without a full copy
            if learning[c].dtype == np.float64:
                learning[c] = learning[c].astype(np.float32)
            if pseudo[c].dtype != learning[c].dtype:
                pseudo[c] = pseudo[c].astype(learning[c].dtype)
        gc.collect()
        learning = pd.concat([learning, pseudo], ignore_index=True)
        log(f"PSEUDO: learning = {n_real:,} train pairs + {len(pseudo):,} sure test pairs "
            f"({pseudo['label'].mean():.3f} positive); early stop + holdout stay train only")
        del pseudo
        gc.collect()
""" + TRAIN_OLD

ASSIGN_OLD = """    log(f"wrote {output_dir / 'matching_results.tsv'} and candidate_pairs.tsv")\n"""
ASSIGN_NEW = ASSIGN_OLD + f"""    try:
        extra_dir = output_dir / "thresholds"
        extra_dir.mkdir(parents=True, exist_ok=True)
        pairs[["s1_row", "s23_row", "probability"]].to_parquet(extra_dir / "test_pair_probabilities.parquet", index=False)
        for t in {EXTRA_THRESHOLDS!r}:
            extra = decide(pairs, "threshold", threshold=t)
            write_id_lists(extra_dir / f"matching_results_t{{t}}.tsv", s1_ids, extra, s23_ids, header="matched_entity_ids")
            log(f"threshold {{t}}: {{len(extra):,}} pairs -> thresholds/matching_results_t{{t}}.tsv")
    except Exception as error:
        log(f"extra threshold files failed (main answer is fine): {{error!r}}")
"""


S2_COLS_OLD = """                  "sib_addr_support", "sib_name_support"]
"""
S2_COLS_NEW = """                  "sib_addr_support", "sib_name_support"] + __import__("rival").RIVAL_COLUMNS
"""
S2_OLD = """    frames = []
    for order, _, _, numbers in prepared:
"""
S2_NEW = """    from rival import rival_features, release
    for (s1_row, s23_row, _), (order, _, q, numbers) in zip(parts, prepared):
        numbers.update(rival_features(s1_row[order], s23_row[order], q, len(s23_names)))
    release()
    import gc as _gc, ctypes as _ct
    _gc.collect()
    try:
        _ct.CDLL("libc.so.6").malloc_trim(0)
    except Exception:
        pass
""" + S2_OLD
FR_OLD = """    for order, _, _, numbers in prepared:
        frame = pd.DataFrame({k: np.asarray(numbers[k], dtype=np.float32) for k in STAGE2_COLUMNS})
        back = np.empty_like(order)
        back[order] = np.arange(len(order))
        frames.append(frame.iloc[back].reset_index(drop=True))
"""
FR_NEW = """    for order, _, _, numbers in prepared:
        cols = {}
        for k in STAGE2_COLUMNS:            # straight into input order; no second full frame
            col = np.empty(len(order), dtype=np.float32)
            col[order] = numbers.pop(k)
            cols[k] = col
        numbers.clear()
        frames.append(pd.DataFrame(cols))
        del cols
"""
CE_OLD = """        extra = pd.concat([extra, ce_features(pairs["s1_row"], pairs["s23_row"], scores)], axis=1)
"""
CE_NEW = """        _ce = ce_features(pairs["s1_row"], pairs["s23_row"], scores)
        for _c in _ce.columns:
            extra[_c] = _ce[_c].to_numpy()
        del _ce
"""
DEC_OLD = """    result = evaluate(model, columns, holdout, holdout_rows, truth, "HOLDOUT")
"""
DEC_NEW = DEC_OLD + """    try:
        dec_dir = work_dir / "dec"
        dec_dir.mkdir(parents=True, exist_ok=True)
        hp = holdout[["s1_row", "s23_row", "label"]].copy()
        hp["probability"] = model.predict(holdout[columns]).astype(np.float32)
        hp.to_parquet(dec_dir / "holdout_pairs.parquet", index=False)
        truth[truth["s1_row"].isin(holdout_rows)].to_parquet(dec_dir / "holdout_truth.parquet", index=False)
        pd.DataFrame({"s1_row": holdout_rows, "country": s1["country"].to_numpy()[holdout_rows]}).to_parquet(
            dec_dir / "holdout_rows.parquet", index=False)
        log(f"DEC: saved {len(hp):,} holdout pairs to {dec_dir}")
    except Exception as error:
        log(f"DEC save failed: {error!r}")
"""


def patched_code():
    code = Path("/tmp/aml26_code")
    shutil.rmtree(code, ignore_errors=True)
    shutil.copytree(code_dir(), code)
    import base64
    (code / "rival.py").write_bytes(base64.b64decode(RIVAL_B64))
    for name, old, new in (("train.py", TRAIN_OLD, TRAIN_NEW), ("assign.py", ASSIGN_OLD, ASSIGN_NEW),
                           ("stage2.py", S2_COLS_OLD, S2_COLS_NEW), ("stage2.py", S2_OLD, S2_NEW),
                           ("train.py", DEC_OLD, DEC_NEW), ("stage2.py", FR_OLD, FR_NEW),
                           ("assign.py", CE_OLD, CE_NEW)):
        text = (code / name).read_text(encoding="utf-8")
        if text.count(old) != 1:
            raise SystemExit(f"{name} patch failed (code dataset changed?)")
        (code / name).write_text(text.replace(old, new), encoding="utf-8")
    return code


def run(command, label):
    time_left = PIPELINE_TIME_LIMIT - (time.time() - NOTEBOOK_START)
    say(f"{label}: {' '.join(map(str, command))} (time left {time_left / 3600:.2f} h)")
    try:
        returncode = subprocess.run(command, timeout=time_left).returncode
    except subprocess.TimeoutExpired:
        returncode = -1
    import resource
    peak = resource.getrusage(resource.RUSAGE_CHILDREN).ru_maxrss / 1e6
    say(f"peak memory {peak:.1f} GB; time {(time.time() - NOTEBOOK_START) / 3600:.2f} h")
    if returncode != 0:
        WORK.mkdir(parents=True, exist_ok=True)
        (WORK / "FAILED.txt").write_text(f"{label}: exit code {returncode}\n")
        say(f"PIPELINE FAILED ({label}: exit code {returncode}{' = killed, out of memory?' if returncode == -9 else ''})")
        return False
    say(f"PIPELINE OK ({label})")
    return True


def pipeline(code, *args):
    return run([sys.executable, "-u", str(code / "run_pipeline.py"), *args, "--data-dir", str(DATA),
                "--work-dir", str(WORK), "--n-jobs", str(N_JOBS)], args[0])


def validate():
    output = WORK / "output"
    validator = find("validate_submission.py")
    if validator and (output / "matching_results.tsv").exists():
        subprocess.run([sys.executable, str(validator[0]), "-m", str(output / "matching_results.tsv"),
                        "-c", str(output / "candidate_pairs.tsv"), "-t", str(DATA / "test")])


def clean_up():
    for path in WORKING.rglob("*"):
        if path.is_symlink():
            path.unlink()
    (WORK / "test" / "ce_src.parquet").unlink(missing_ok=True)
    for folder in (DATA, WORKING / "unzipped", SRC_MODELS):
        shutil.rmtree(folder, ignore_errors=True)
    (WORK / "pseudo" / "pseudo_pairs.parquet").unlink(missing_ok=True)   # big; the log has its numbers


def gen_in_child():
    """gen in a forked process (its ~10 GB go back to the system when it ends)."""
    import multiprocessing
    say("gen: pseudo-labelled test pairs")
    child = multiprocessing.get_context("fork").Process(target=gen)
    child.start()
    child.join()
    if child.exitcode != 0:
        WORK.mkdir(parents=True, exist_ok=True)
        (WORK / "FAILED.txt").write_text(f"gen: exit code {child.exitcode}\n")
        say(f"PIPELINE FAILED (gen: exit code {child.exitcode}{' = killed, out of memory?' if child.exitcode == -9 else ''})")
        return False
    say(f"PIPELINE OK (gen); time {(time.time() - NOTEBOOK_START) / 3600:.2f} h")
    return True


def main():
    say(f"aml26-ens3: {NOTE}")
    os.environ["AML26_DATA"] = str(DATA)
    try:
        prepare()
        code = patched_code()
        if (gen_in_child() and pipeline(code, "train", "--note", NOTE) and pipeline(code, "assign")):
            validate()
            say("ALL DONE")
    finally:
        clean_up()


main()
