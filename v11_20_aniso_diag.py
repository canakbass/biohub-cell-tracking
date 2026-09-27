# =============================================================================
# V11 ADIM 3c - KONFIG YENIDEN TARAMASI, ADIM 5 DETEKTORU (CPU, ~25 dk)
# =============================================================================
# ADIM 2 BULGUSU: linker, tespitin sagladiginin ~%20'sini kaybediyor
#   (edgeJ 0.606 vs recall^2 0.761).  2540cd90'da recall 0.996 iken edgeJ 0.805.
# Bu script NEDEN kaybettigini SAYIYOR: her GT kenari icin iki ucu da eslesmisse,
# bizim grafta o kenar var mi, yoksa neden yok?
#
# Girdi : yarisma verisi (GT icin) + cand_v3_*.npz  (Adim 1b notebook cikti'si)
# Cikti : sweep tablolari + RAPOR blogu
# =============================================================================

import sys, subprocess

def _ensure(mod, spec=None):
    """Kaggle 'script' kernel'inde !pip sihri YOK -> subprocess ile kur."""
    try:
        __import__(mod)
        return True
    except ImportError:
        print(f"[bootstrap] {spec or mod} kuruluyor...", flush=True)
        subprocess.run([sys.executable, "-m", "pip", "install", "-q", spec or mod], check=False)
        try:
            __import__(mod)
            return True
        except ImportError:
            print(f"[bootstrap] {mod} KURULAMADI"); return False

_ensure("zarr")

import os, glob, json, time, math, itertools
import numpy as np
from scipy.spatial import cKDTree
from scipy.optimize import linear_sum_assignment
from scipy.spatial.distance import cdist

COMP  = "/kaggle/input/competitions/biohub-cell-tracking-during-development"
TRAIN = os.path.join(COMP, "train")
WORK  = "/kaggle/working"

# 3 model icin ayri cand_*.npz kaynaklari (ayni 12 dataset, ayni yontem -
# tek fark hangi checkpoint'in ureftigi heatmap). Adil kiyas icin hepsi
# AYNI post-process konfigiyle (asagida FIXED_*) degerlendirilir.
CAND_TAGS = ["v3", "v3aniso"]   # v3=mevcut uretim detektoru  v3aniso=izotropik havuzlama (yeni)
def _cand_dir(tag):
    hits = sorted(glob.glob(f"/kaggle/input/**/cand_{tag}_*.npz", recursive=True))
    return os.path.dirname(hits[0]) if hits else "/kaggle/working"
CAND_DIR_MAP = {t: _cand_dir(t) for t in CAND_TAGS}
CAND_TAG = CAND_TAGS[0]   # geriye-uyum: load_cands/build_nodes bunu varsayilan kullanir
CAND_DIR = CAND_DIR_MAP[CAND_TAG]

SCALE        = (1.625, 0.40625, 0.40625)
MAX_MATCH_UM = 7.0
ALPHA        = 0.1
DIV_W        = 0.1

CORE = {'44b6_341df25f','44b6_3bb3690f','44b6_c771cb04','44b6_8f9ecab4',
        '6bba_2540cd90','6bba_3a1849c2','6bba_67ebd073','6bba_57b7cc1e'}

# --- SWEEP IZGARASI ---------------------------------------------------------
R_LIST   = [7.0]                # ADIM 2: r_nms=7.0 optimum
BEST_R   = 7.0
BEST_N   = 0.95                 # ADIM 2: n* = 0.95
THR_GRID = [3e-4, 6e-4, 1.2e-3, 2.5e-3, 5e-3, 8e-3,
            1.2e-2, 2.0e-2, 2.5e-2, 3.5e-2, 6e-2, 1.2e-1, 2.5e-1]  # 2.5e-2 = v9 baseline
N_STARS  = [round(0.9 + 0.05 * i, 2) for i in range(19)]   # n-hedefleme politikasi

FRAME_LIMIT = None      # None = 100 frame; sure yetmezse 50 yap
rng = np.random.default_rng(0)

t_start = time.time()
def elapsed(): return (time.time() - t_start) / 60.0


# =============================================================================
# GT OKUMA  (Adim 0: 199/199 dataset voxel yaziyor -> donusum gereksiz)
# =============================================================================
def read_gt(geff_path):
    import zarr
    g = zarr.open_group(str(geff_path), mode="r")
    meta = dict(g.attrs).get("geff", {}) or {}
    est = (meta.get("extra") or {}).get("estimated_number_of_nodes")

    def arr(p):
        n = g
        for k in p.split("/"):
            n = n[k]
        return np.asarray(n[:])

    def get(k):
        for p in (f"nodes/props/{k}/values", f"nodes/{k}"):
            try:
                return arr(p)
            except Exception:
                pass
        raise KeyError(k)

    t = get("t").astype(np.int64)
    z, y, x = (get(k).astype(np.float64) for k in ("z", "y", "x"))
    try:
        ids = arr("nodes/ids").astype(np.int64)
    except Exception:
        ids = np.arange(len(t), dtype=np.int64)
    try:
        e_raw = arr("edges/ids").astype(np.int64).reshape(-1, 2)
    except Exception:
        e_raw = np.zeros((0, 2), np.int64)
    if len(e_raw):
        o = np.argsort(ids)
        edges = o[np.searchsorted(ids[o], e_raw.ravel())].reshape(-1, 2)
    else:
        edges = e_raw
    return dict(t=t, z=z, y=y, x=x, edges=edges, n_nodes=len(t),
                est_nodes=float(est) if est is not None else float("nan"))


def subset_gt(gt, t_lo, t_hi):
    """GT'yi [t_lo,t_hi]'ye kis, kenarlari yeniden indeksle (aralik disini FN sayma)."""
    keep = np.where((gt["t"] >= t_lo) & (gt["t"] <= t_hi))[0]
    remap = -np.ones(gt["n_nodes"], np.int64)
    remap[keep] = np.arange(len(keep))
    e = gt["edges"]
    if len(e):
        m = (remap[e[:, 0]] >= 0) & (remap[e[:, 1]] >= 0)
        e = np.column_stack([remap[e[m, 0]], remap[e[m, 1]]])
    else:
        e = np.zeros((0, 2), np.int64)
    scale_frac = (t_hi - t_lo + 1) / 100.0
    return dict(t=gt["t"][keep], z=gt["z"][keep], y=gt["y"][keep], x=gt["x"][keep],
                edges=e, n_nodes=len(keep), est_nodes=gt["est_nodes"] * scale_frac)


# =============================================================================
# RESMI METRIK  (Adim 0'daki dogrulanmis mantik, hizlandirilmis)
# =============================================================================
def match_nodes(pred_nodes, gt, scale=SCALE, max_dist=MAX_MATCH_UM):
    sc = np.asarray(scale)
    matched = np.full(len(pred_nodes), -1, np.int64)
    if len(pred_nodes) == 0 or gt["n_nodes"] == 0:
        return matched
    gt_P = np.stack([gt["z"], gt["y"], gt["x"]], 1) * sc
    p_t = pred_nodes[:, 0].astype(np.int64)
    p_P = pred_nodes[:, 1:] * sc
    # frame dilimleri: pred zaten t sirali
    for tv in np.unique(gt["t"]):
        gi = np.where(gt["t"] == tv)[0]
        pi = np.where(p_t == tv)[0]
        if len(gi) == 0 or len(pi) == 0:
            continue
        D = np.linalg.norm(p_P[pi][:, None, :] - gt_P[gi][None, :, :], axis=2)
        C = np.where(D <= max_dist, D, 1e6)
        if not np.any(C < 1e6):
            continue
        r, c = linear_sum_assignment(C)
        ok = C[r, c] < 1e6
        matched[pi[r[ok]]] = gi[c[ok]]
    return matched


def canonical_edges(pred_nodes, pred_edges, matched):
    """dt==1 / tekille / merge-dedup / out-degree<=2  (vektorlestirilmis)"""
    e = np.asarray(pred_edges, np.int64).reshape(-1, 2)
    if len(e) == 0:
        return e
    ts = pred_nodes[e[:, 0], 0].astype(np.int64)
    tt = pred_nodes[e[:, 1], 0].astype(np.int64)
    e = e[(tt - ts) == 1]
    if len(e) == 0:
        return e

    # tekrarlayan (source,target) ciftlerini ilk gorunume gore tekille
    _, first = np.unique(e, axis=0, return_index=True)
    e = e[np.sort(first)]

    # merge-dedup: ayni (matched_src, matched_tgt)'a dusenlerden ilkini tut
    ms, mt = matched[e[:, 0]], matched[e[:, 1]]
    both = (ms >= 0) & (mt >= 0)
    if both.any():
        idx = np.where(both)[0]
        span = int(matched.max()) + 2
        key = ms[idx].astype(np.int64) * span + mt[idx].astype(np.int64)
        o = np.argsort(key, kind='stable')           # esitlikte orijinal sira korunur
        ks = key[o]
        firstmask = np.ones(len(ks), bool)
        firstmask[1:] = ks[1:] != ks[:-1]
        keep = np.ones(len(e), bool)
        keep[idx] = False
        keep[idx[o[firstmask]]] = True
        e = e[keep]
        if len(e) == 0:
            return e

    # out-degree <= 2: kaynak basina ilk iki kenar
    e = e[np.lexsort((np.arange(len(e)), e[:, 0]))]
    src = e[:, 0]
    grp = np.searchsorted(src, src, side="left")
    return e[(np.arange(len(e)) - grp) <= 1]


def division_counts(e, matched, gt, n_pred):
    """FP SADECE eslesmis + GT'de cocugu olan fork'lardan. Bolunmeler seyrek ->
    sadece fork'lar uzerinde donuyoruz."""
    gt_edges = gt["edges"]
    if len(gt_edges) == 0:
        return 0, 0, 0
    gt_out = np.bincount(gt_edges[:, 0], minlength=gt["n_nodes"])
    gt_div_nodes = np.where(gt_out >= 2)[0]
    n_gt_div = len(gt_div_nodes)
    if len(e) == 0:
        return 0, 0, n_gt_div

    gt_child, gt_has_child = {}, set(np.unique(gt_edges[:, 0]).tolist())
    if n_gt_div:
        sel = gt_edges[np.isin(gt_edges[:, 0], gt_div_nodes)]
        for s, t in sel.tolist():
            gt_child.setdefault(s, []).append(t)

    pred_out = np.bincount(e[:, 0], minlength=n_pred)
    forks = np.where(pred_out >= 2)[0]
    if len(forks) == 0:
        return 0, 0, n_gt_div
    pred_child = {}
    for s, t in e[np.isin(e[:, 0], forks)].tolist():
        pred_child.setdefault(s, []).append(t)

    tp, fp, hit = 0, 0, set()
    for p, ch in pred_child.items():
        mp = int(matched[p])
        if mp < 0:
            continue                          # eslesmemis fork -> BEDAVA
        if mp in gt_child:
            got = {int(matched[c]) for c in ch if matched[c] >= 0}
            if len(set(gt_child[mp]) & got) >= 2:
                tp += 1
                hit.add(mp)
            else:
                fp += 1
        elif mp in gt_has_child:
            fp += 1
    return tp, fp, n_gt_div - len(hit)


def evaluate_dataset(pred_nodes, pred_edges, gt, n_total=None, scale=SCALE):
    pred_nodes = np.asarray(pred_nodes, np.float64).reshape(-1, 4)
    matched = match_nodes(pred_nodes, gt, scale)
    e = canonical_edges(pred_nodes, pred_edges, matched)

    gt_edges, n_gt_nodes = gt["edges"], gt["n_nodes"]
    out_deg = np.zeros(n_gt_nodes, np.int64)
    in_deg = np.zeros(n_gt_nodes, np.int64)
    if len(gt_edges):
        np.add.at(out_deg, gt_edges[:, 0], 1)
        np.add.at(in_deg, gt_edges[:, 1], 1)

    tp = valid = 0
    if len(e):
        ms, mt = matched[e[:, 0]], matched[e[:, 1]]
        out_valid = (ms >= 0) & (out_deg[np.clip(ms, 0, None)] > 0)
        in_valid = (mt >= 0) & (in_deg[np.clip(mt, 0, None)] > 0)
        valid = int((out_valid | in_valid).sum())
        both = np.where((ms >= 0) & (mt >= 0))[0]
        if len(both) and len(gt_edges):
            span = int(n_gt_nodes) + 2
            gt_keys = np.sort(gt_edges[:, 0].astype(np.int64) * span + gt_edges[:, 1])
            pk = ms[both].astype(np.int64) * span + mt[both].astype(np.int64)
            pos = np.searchsorted(gt_keys, pk)
            pos = np.clip(pos, 0, len(gt_keys) - 1)
            tp = int((gt_keys[pos] == pk).sum())

    edge_tp, edge_fp, edge_fn = tp, max(0, valid - tp), len(gt_edges) - tp
    n_matched = len(np.unique(matched[matched >= 0]))
    node_recall = n_matched / n_gt_nodes if n_gt_nodes else float("nan")
    dtp, dfp, dfn = division_counts(e, matched, gt, len(pred_nodes))

    num_pred = len(pred_nodes)
    if n_total is None:
        n_total = gt.get("est_nodes", float("nan"))
    ratio = (num_pred - n_total) / n_total if (n_total and n_total > 0) else float("nan")
    denom = edge_tp + edge_fp + edge_fn
    J = edge_tp / denom if denom > 0 else float("nan")
    adj = max(0.0, J * (1 - ALPHA * ratio)) if (J == J and ratio == ratio) else float("nan")
    return dict(edge_tp=edge_tp, edge_fp=edge_fp, edge_fn=edge_fn,
                division_tp=dtp, division_fp=dfp, division_fn=dfn,
                num_pred_nodes=num_pred, n_total=n_total,
                n_ratio=(num_pred / n_total) if (n_total and n_total > 0) else float('nan'),
                node_recall=node_recall, total_node_ratio=ratio,
                edge_jaccard=J, adj_edge_jaccard=adj, n_edges_kept=len(e))


def summarise(rows):
    v = [r for r in rows if r["edge_jaccard"] == r["edge_jaccard"]]
    if not v:
        return dict(score=float("nan"))
    w = np.array([r["edge_tp"] + r["edge_fp"] + r["edge_fn"] for r in v], float)
    aj = np.array([r["adj_edge_jaccard"] for r in v], float)
    ok = aj == aj
    adj = float((w[ok] * aj[ok]).sum() / w[ok].sum()) if ok.any() and w[ok].sum() > 0 else float("nan")
    ej = float(sum(r["edge_tp"] for r in v) /
               max(1, sum(r["edge_tp"] + r["edge_fp"] + r["edge_fn"] for r in v)))
    dtp = sum(r["division_tp"] for r in v)
    dfp = sum(r["division_fp"] for r in v)
    dfn = sum(r["division_fn"] for r in v)
    dj = dtp / (dtp + dfp + dfn) if (dtp + dfp + dfn) else float("nan")
    score = adj + DIV_W * dj if (dtp + dfp + dfn) else adj
    return dict(n=len(v), edge_jaccard=ej, adj_edge_jaccard=adj, div_jaccard=dj,
                node_recall=float(np.mean([r["node_recall"] for r in v])),
                n_ratio=float(np.mean([r["n_ratio"] for r in v])),
                div_tp=dtp, div_fp=dfp, div_fn=dfn, score=score)


# =============================================================================
# ADAY YUKLEME + HIZLI NMS
# =============================================================================
def load_cands(name, cand_dir=None, cand_tag=None):
    cand_dir = cand_dir or CAND_DIR
    cand_tag = cand_tag or CAND_TAG
    d = np.load(os.path.join(cand_dir, f"cand_{cand_tag}_{name}.npz"))
    T = int(d["T"])
    t = d["t"].astype(np.int64)
    coords = np.stack([d["z"], d["y"], d["x"]], 1).astype(np.float64)
    sc = d["score"].astype(np.float64)
    fstart = np.searchsorted(t, np.arange(T + 1))   # t artan sirada
    return dict(T=T, coords=coords, score=sc, fstart=fstart,
                est=float(d["est_nodes"]))


def frame_pairs(coords, r_max, scale=SCALE):
    """(pairs, dist) - frame icindeki r_max'tan yakin tum ciftler (fiziksel)"""
    if len(coords) < 2:
        return np.zeros((0, 2), np.int64), np.zeros(0)
    P = coords * np.asarray(scale)
    pr = cKDTree(P).query_pairs(r_max, output_type='ndarray')
    if len(pr) == 0:
        return pr.reshape(-1, 2), np.zeros(0)
    dd = np.linalg.norm(P[pr[:, 0]] - P[pr[:, 1]], axis=1)
    return pr, dd


def build_csr(pairs, dist, r, M):
    """yonsuz komsuluk -> CSR (b, starts); sadece dist<=r olan ciftler"""
    if len(pairs):
        p = pairs[dist <= r]
    else:
        p = pairs
    if len(p) == 0:
        return np.zeros(0, np.int64), np.zeros(M + 1, np.int64)
    a = np.concatenate([p[:, 0], p[:, 1]])
    b = np.concatenate([p[:, 1], p[:, 0]])
    o = np.argsort(a, kind='stable')
    a, b = a[o], b[o]
    return b, np.searchsorted(a, np.arange(M + 1))


def nms_frame(order, b, starts, active):
    """greedy NMS: skor sirasinda gez, kabul edileni tut, komsularini bastir"""
    sup = ~active
    keep = []
    for i in order:
        if sup[i]:
            continue
        keep.append(i)
        sup[b[starts[i]:starts[i + 1]]] = True
    return keep


# =============================================================================
# LINKER  (v9 mantigi; yerel hareket alani opsiyonel, LAP yerine kapili greedy)
# =============================================================================
def _knn(A, B, k=2):
    if len(B) == 0 or len(A) == 0:
        return np.full((len(A), k), np.inf), np.zeros((len(A), k), np.int64)
    ke = min(k, len(B))
    d, i = cKDTree(B).query(A, k=ke)
    if ke == 1:
        d, i = d[:, None], i[:, None]
    if ke < k:
        d = np.pad(d, ((0, 0), (0, k - ke)), constant_values=np.inf)
        i = np.pad(i, ((0, 0), (0, k - ke)), constant_values=0)
    return d, i


def _greedy_gated(A, B, gate):
    """gate icindeki ciftleri mesafeye gore greedy esle -> {i: j}"""
    if len(A) == 0 or len(B) == 0 or gate <= 0:
        return {}
    nb = cKDTree(B).query_ball_point(A, gate)
    cand = []
    for i, js in enumerate(nb):
        for j in js:
            cand.append((float(np.linalg.norm(A[i] - B[j])), i, j))
    cand.sort()
    ua, ub, out = set(), set(), {}
    for _d, i, j in cand:
        if i in ua or j in ub:
            continue
        ua.add(i); ub.add(j); out[i] = j
    return out


def link_frames(P0, P1, gate=8.0, mnn_ratio=0.80, fill_gate=8.0,
                local_motion=False, motion_iters=3, bw=25.0, min_support=4):
    n0, n1 = len(P0), len(P1)
    assign = np.full(n0, -1, np.int64)
    if n0 == 0 or n1 == 0:
        return assign, np.zeros((max(n0, 1), 3))

    # --- global oteleme (medyan akis) --- tree1 bir kez kurulur
    tree1 = cKDTree(P1)
    shift = np.zeros(3)
    for _ in range(4):
        d, i = tree1.query(P0 + shift, k=1)
        m = d < gate
        if m.sum() < 8:
            break
        step = np.median(P1[i[m]] - (P0[m] + shift), axis=0)
        shift += step
        if np.linalg.norm(step) < 1e-3:
            break
    disp = np.tile(shift, (n0, 1)).astype(np.float64)

    iters = motion_iters if local_motion else 1
    k1 = min(2, n1)
    for it in range(iters):
        Q = P0 + disp
        d01, i01 = tree1.query(Q, k=k1)
        if k1 == 1:
            d01, i01 = d01[:, None], i01[:, None]
            d01 = np.pad(d01, ((0, 0), (0, 1)), constant_values=np.inf)
            i01 = np.pad(i01, ((0, 0), (0, 1)), constant_values=0)
        d10, i10 = _knn(P1, Q, k=2)
        mutual = i10[i01[:, 0], 0] == np.arange(n0)
        gated = d01[:, 0] < gate
        distinct = np.isinf(d01[:, 1]) | (d01[:, 0] < mnn_ratio * d01[:, 1])
        conf = mutual & gated & distinct
        if it < iters - 1:
            if conf.sum() >= min_support:
                vecs = P1[i01[conf, 0]] - P0[conf]
                tree = cKDTree(P0[conf])
                out = np.tile(np.median(vecs, axis=0), (n0, 1)).astype(np.float64)
                for j, nb in enumerate(tree.query_ball_point(P0, 2.5 * bw)):
                    if len(nb) < min_support:
                        continue
                    nb = np.asarray(nb)
                    w = np.exp(-0.5 * ((P0[conf][nb] - P0[j]) ** 2).sum(1) / bw ** 2)
                    sw = w.sum()
                    if sw > 1e-8:
                        out[j] = (w[:, None] * vecs[nb]).sum(0) / sw
                disp = out
        else:
            assign[conf] = i01[conf, 0]

    # --- hedef basina tek kaynak (en yakini tut) ---
    best = {}
    for a in np.where(assign >= 0)[0]:
        bb = int(assign[a])
        dd = float(np.linalg.norm(P0[a] + disp[a] - P1[bb]))
        if bb not in best or dd < best[bb][1]:
            if bb in best:
                assign[best[bb][0]] = -1
            best[bb] = (a, dd)
        else:
            assign[a] = -1

    # --- artakalanlari kapili greedy ile doldur ---
    free0 = np.where(assign < 0)[0]
    used1 = np.zeros(n1, bool)
    used1[assign[assign >= 0]] = True
    free1 = np.where(~used1)[0]
    if len(free0) and len(free1):
        for i, j in _greedy_gated(P0[free0] + disp[free0], P1[free1], fill_gate).items():
            assign[free0[i]] = free1[j]
    return assign, disp


def find_divisions(P0, P1, assign, disp, radius=9.0, min_angle=100.0, max_ratio=2.0):
    import math
    n1 = len(P1)
    used1 = np.zeros(n1, bool)
    used1[assign[assign >= 0]] = True
    free1 = np.where(~used1)[0]
    parents = np.where(assign >= 0)[0]
    if len(free1) == 0 or len(parents) == 0 or radius <= 0:
        return []
    d, i = _knn(P1[free1], P0[parents] + disp[parents], k=1)
    cos_lim = math.cos(math.radians(min_angle))
    out, busy = [], set()
    for oi in np.argsort(d[:, 0]):
        if d[oi, 0] >= radius:
            break
        p = int(parents[i[oi, 0]])
        if p in busy:
            continue
        c1 = P1[assign[p]] - P0[p]
        c2 = P1[free1[oi]] - P0[p]
        n1_, n2_ = np.linalg.norm(c1), np.linalg.norm(c2)
        if min(n1_, n2_) < 1e-6 or max(n1_, n2_) / min(n1_, n2_) > max_ratio:
            continue
        if float(c1 @ c2) / (n1_ * n2_) > cos_lim:
            continue
        out.append((p, int(free1[oi])))
        busy.add(p)
    return out


# =============================================================================
# SON ISLEM: GAP CLOSING (FIZIKSEL) + KISA TRACK FILTRESI
# =============================================================================
def gap_close(nodes, edges, max_gap=4, gate_um=10.0, scale=SCALE):
    """v10'daki hata: mesafe HAM VOXEL uzayinda olculuyordu (z'de 3.5x gevsek)."""
    if len(nodes) == 0 or len(edges) == 0 or max_gap < 2 or gate_um <= 0:
        return nodes, edges
    sc = np.asarray(scale)
    N = len(nodes)
    out_deg = np.zeros(N, np.int32); in_deg = np.zeros(N, np.int32)
    np.add.at(out_deg, edges[:, 0], 1)
    np.add.at(in_deg, edges[:, 1], 1)
    tails = np.where(out_deg == 0)[0]
    heads = np.where(in_deg == 0)[0]
    if len(tails) == 0 or len(heads) == 0:
        return nodes, edges

    heads_by_t, trees = {}, {}
    for h in heads:
        heads_by_t.setdefault(int(nodes[h, 0]), []).append(int(h))
    for tv, hl in heads_by_t.items():
        trees[tv] = cKDTree(nodes[hl, 1:] * sc)

    new_nodes, new_edges, used = [], edges.tolist(), set()
    for tail in tails:
        t_tail = int(nodes[tail, 0])
        bh, bd, bg = -1, gate_um, 0
        q = nodes[tail, 1:] * sc
        for gap in range(2, max_gap + 1):
            ts = t_tail + gap
            if ts not in trees:
                continue
            d, i = trees[ts].query(q, k=1)
            if d < bd:
                cand = heads_by_t[ts][i]
                if cand not in used:
                    bd, bh, bg = float(d), cand, gap
        if bh != -1:
            used.add(bh)
            nt, nh, prev = nodes[tail], nodes[bh], int(tail)
            for step in range(1, bg):
                a = step / bg
                interp = (1.0 - a) * nt + a * nh
                interp[0] = t_tail + step
                nid = N + len(new_nodes)
                new_nodes.append(interp)
                new_edges.append([prev, nid])
                prev = nid
            new_edges.append([prev, int(bh)])
    if new_nodes:
        nodes = np.vstack([nodes, np.array(new_nodes)])
        edges = np.asarray(new_edges, np.int64)
    return nodes, edges


def filter_short(nodes, edges, min_len):
    if min_len <= 1 or len(nodes) == 0:
        return nodes, edges
    parent = np.arange(len(nodes))
    def find(i):
        r = i
        while parent[r] != r:
            r = parent[r]
        while parent[i] != r:
            parent[i], i = r, parent[i]
        return r
    for u, v in edges.tolist():
        ru, rv = find(u), find(v)
        if ru != rv:
            parent[ru] = rv
    roots = np.array([find(i) for i in range(len(nodes))])
    size = np.bincount(roots, minlength=len(nodes))
    ok = size[roots] >= min_len
    remap = np.cumsum(ok) - 1
    nodes = nodes[ok]
    if len(edges):
        m = ok[edges[:, 0]] & ok[edges[:, 1]]
        edges = remap[edges[m]]
    return nodes, edges


def build_graph(frames, T, link_kw, div_kw, gap_kw, min_len, scale=SCALE):
    sc = np.asarray(scale)
    all_nodes, all_edges = [], []
    offset, prev_P, prev_off = 0, None, None
    for t in range(T):
        c = frames.get(t, np.zeros((0, 3)))
        P = c * sc
        all_nodes.append(np.column_stack([np.full(len(c), t, np.float64), c]))
        if prev_P is not None and len(prev_P) and len(P):
            assign, disp = link_frames(prev_P, P, **link_kw)
            src = np.where(assign >= 0)[0]
            if len(src):
                all_edges.append(np.column_stack([prev_off + src, offset + assign[src]]))
            if div_kw is not None:
                dv = find_divisions(prev_P, P, assign, disp, **div_kw)
                if dv:
                    all_edges.append(np.array([[prev_off + p, offset + ch] for p, ch in dv],
                                              np.int64))
        prev_P, prev_off = P, offset
        offset += len(c)
    nodes = np.vstack(all_nodes) if all_nodes else np.zeros((0, 4))
    edges = (np.vstack(all_edges).astype(np.int64) if all_edges
             else np.zeros((0, 2), np.int64))
    if gap_kw is not None:
        nodes, edges = gap_close(nodes, edges, **gap_kw)
    nodes, edges = filter_short(nodes, edges, min_len)
    return nodes, edges





# =============================================================================
# SEED1 vs SEED2 vs ENSEMBLE - AYNI SABIT KONFIGLE ADIL KIYAS
# =============================================================================
# v39/v41 (production) konfigi SABIT tutuluyor - burada post-process ARANMIYOR,
# sadece detektor (heatmap) degisiyor. Amac: LAP sweep'inde oldugu gibi
# kontrollu, tek-degiskenli bir olcum.
FIXED_N_STAR = 0.95
FIXED_LINK   = dict(gate=8.0, mnn_ratio=0.80, fill_gate=0.0, local_motion=False)
FIXED_GAP    = dict(max_gap=6, gate_um=8.0)
FIXED_MINLEN = 3

VOL_UM3 = 64 * 1.625 * 256 * 0.40625 * 256 * 0.40625
def spacing_um(est, T=100):
    return float((6.0 * VOL_UM3 / (math.pi * max(1.0, est / T))) ** (1.0 / 3.0))

# her TAG icin ayri ALL/GT (ayni 12 dataset olmali, farkli klasorlerden)
ALL_BY_TAG, GT_BY_TAG = {}, {}
for tag in CAND_TAGS:
    d = CAND_DIR_MAP[tag]
    names = sorted(os.path.basename(p)[len(f"cand_{tag}_"):-4]
                    for p in glob.glob(os.path.join(d, f"cand_{tag}_*.npz")))
    assert names, f"cand_{tag}_*.npz bulunamadi (dizin={d}) - kernel-source eksik olabilir"
    ALL_BY_TAG[tag] = names
    GT_BY_TAG[tag] = {n: read_gt(os.path.join(TRAIN, n + ".geff")) for n in names}
    print(f"[{tag}] {len(names)} dataset yuklendi ({d})")

REF = ALL_BY_TAG[CAND_TAGS[0]]
for tag in CAND_TAGS[1:]:
    assert ALL_BY_TAG[tag] == REF, f"[{tag}] dataset listesi REF'ten farkli: {ALL_BY_TAG[tag]} vs {REF}"
print(f"\n>>> {len(REF)} dataset her 3 TAG'da da ayni sirada dogrulandi")

g0 = GT_BY_TAG[CAND_TAGS[0]][REF[0]]
_nd = np.column_stack([g0["t"], g0["z"], g0["y"], g0["x"]]).astype(np.float64)
_st = evaluate_dataset(_nd, g0["edges"].copy(), g0)
assert abs(_st["edge_jaccard"] - 1.0) < 1e-9, "metrik bozuk"
print(f"metrik oz-testi: edge_J={_st['edge_jaccard']:.6f} adj={_st['adj_edge_jaccard']:.6f} OK")

CORE_L = [n for n in REF if n in CORE]
G44 = [n for n in CORE_L if n.startswith("44b6")]
G6B = [n for n in CORE_L if n.startswith("6bba")]
print(f"CORE={len(CORE_L)} (44b6={len(G44)} 6bba={len(G6B)})  PUBLIC={len(REF)-len(CORE_L)}")


def build_nodes_fixed(name, cand_dir, cand_tag, gt):
    cd = load_cands(name, cand_dir, cand_tag)
    T, coords, score, fstart, est = cd["T"], cd["coords"], cd["score"], cd["fstart"], cd["est"]
    target = FIXED_N_STAR * est * (T / 100.0)
    fr = []
    for tv in range(T):
        sl = slice(fstart[tv], fstart[tv + 1])
        c, s = coords[sl], score[sl]
        pr, dd = frame_pairs(c, 7.0)
        b, stt = build_csr(pr, dd, 7.0, len(c))
        fr.append((c, s, b, stt, np.argsort(-s, kind='stable')))

    def count_at(thr):
        tot, out = 0, {}
        for tv in range(T):
            c, s, b, stt, o = fr[tv]
            if len(c) == 0:
                continue
            act = s > thr
            if not act.any():
                continue
            k = nms_frame(o, b, stt, act)
            out[tv] = c[k]; tot += len(k)
        return tot, out

    lo, hi, mid, frames = 1e-5, 0.9, 0.9, {}
    for _ in range(16):
        mid = math.sqrt(lo * hi)
        tot, frames = count_at(mid)
        if tot > target:
            lo = mid
        else:
            hi = mid
    return frames, T


def run_fixed(tag):
    cand_dir = CAND_DIR_MAP[tag]
    gt_map = GT_BY_TAG[tag]
    rows = {}
    for name in REF:
        gt = gt_map[name]
        frames, T = build_nodes_fixed(name, cand_dir, tag, gt)
        nd, ed = build_graph(frames, T, FIXED_LINK, None, FIXED_GAP, FIXED_MINLEN)
        rows[name] = evaluate_dataset(nd, ed, gt)
    return rows


print("\n" + "=" * 106)
print("MEVCUT(v3) vs ANISOFIX(v3aniso) - SABIT post-process konfig")
print(f"n*={FIXED_N_STAR} gate={FIXED_LINK['gate']} mnn={FIXED_LINK['mnn_ratio']} "
      f"gap={FIXED_GAP} min_len={FIXED_MINLEN}")
print("=" * 106)

RESULTS = {}
for tag in CAND_TAGS:
    t0 = time.time()
    rows = run_fixed(tag)
    RESULTS[tag] = rows
    s = summarise([rows[n] for n in CORE_L])
    a = summarise([rows[n] for n in G44])
    b = summarise([rows[n] for n in G6B])
    p = summarise([rows[n] for n in REF if n not in CORE_L]) if len(REF) > len(CORE_L) else None
    print(f"\n[{tag}]  ({time.time()-t0:.0f}s)")
    print(f"  CORE  score={s['score']:.4f} edgeJ={s['edge_jaccard']:.4f} rec={s['node_recall']:.4f} n={s['n_ratio']:.3f}")
    print(f"  44b6  score={a['score']:.4f} edgeJ={a['edge_jaccard']:.4f} rec={a['node_recall']:.4f}")
    print(f"  6bba  score={b['score']:.4f} edgeJ={b['edge_jaccard']:.4f} rec={b['node_recall']:.4f}")
    if p:
        print(f"  PUBLIC score={p['score']:.4f} edgeJ={p['edge_jaccard']:.4f} rec={p['node_recall']:.4f}")

print("\n" + "#" * 106)
print("### V11-ADIM-ENSEMBLE-RAPOR-BASLANGIC")
for tag in CAND_TAGS:
    s = summarise([RESULTS[tag][n] for n in CORE_L])
    a = summarise([RESULTS[tag][n] for n in G44])
    b = summarise([RESULTS[tag][n] for n in G6B])
    print(f"{tag}: core={s['score']:.4f} 44b6={a['score']:.4f} 6bba={b['score']:.4f} "
          f"edgeJ={s['edge_jaccard']:.4f} rec={s['node_recall']:.4f} n={s['n_ratio']:.3f}")
best_tag = max(CAND_TAGS, key=lambda t: summarise([RESULTS[t][n] for n in CORE_L])['score'])
print(f"EN_IYI={best_tag}")
print("--- dataset basina (core skoru CORE_L uzerinde) ---")
for n in CORE_L:
    line = f"{n}:"
    for tag in CAND_TAGS:
        r = RESULTS[tag][n]
        line += f"  {tag}=adj{r['adj_edge_jaccard']:.4f}/rec{r['node_recall']:.4f}"
    print(line)
print("### V11-ADIM-ENSEMBLE-RAPOR-BITIS")
print("#" * 106)


# =============================================================================
# TANI: NEDEN 44b6_3bb3690f ve 44b6_c771cb04 KOTULESTI?
# =============================================================================
PROBLEM_DS = ["44b6_3bb3690f", "44b6_c771cb04"]
print("\n" + "=" * 106)
print("TANI: PROBLEMLI DATASET'LERIN TAM KIRILIMI")
print("=" * 106)
for name in PROBLEM_DS:
    print(f"\n--- {name} ---")
    for tag in CAND_TAGS:
        r = RESULTS[tag][name]
        cd = load_cands(name, CAND_DIR_MAP[tag], tag)
        raw_n = len(cd["score"])
        print(f"  [{tag}] HAM aday={raw_n} (T={cd['T']}, est={cd['est']:.0f})")
        print(f"        num_pred_nodes={r['num_pred_nodes']} n_total={r['n_total']:.0f} "
              f"n_ratio={r['n_ratio']:.3f} total_node_ratio={r['total_node_ratio']:+.3f}")
        print(f"        node_recall={r['node_recall']:.4f} "
              f"edge_tp={r['edge_tp']} edge_fp={r['edge_fp']} edge_fn={r['edge_fn']} "
              f"edge_jaccard={r['edge_jaccard']:.4f}")
        print(f"        adj_edge_jaccard={r['adj_edge_jaccard']:.4f} "
              f"n_edges_kept={r['n_edges_kept']}")
    r0, r1 = RESULTS[CAND_TAGS[0]][name], RESULTS[CAND_TAGS[1]][name]
    print(f"  >>> FARK ({CAND_TAGS[1]}-{CAND_TAGS[0]}): "
          f"node_recall={r1['node_recall']-r0['node_recall']:+.4f}  "
          f"n_ratio={r1['n_ratio']-r0['n_ratio']:+.4f}  "
          f"edge_tp={r1['edge_tp']-r0['edge_tp']:+d}  "
          f"edge_fp={r1['edge_fp']-r0['edge_fp']:+d}  "
          f"edge_fn={r1['edge_fn']-r0['edge_fn']:+d}  "
          f"num_pred_nodes={r1['num_pred_nodes']-r0['num_pred_nodes']:+d}")
print("=" * 106)
