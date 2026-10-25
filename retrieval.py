"""
retrieval.py — EXACT (brute-force) search on GPU.

The paper (Sec. 6.3) discusses approximate indexes (ANN, e.g. ScaNN); we do exact
search instead: on an A100 it is fast enough, and an exact result is the upper bound of
any approximate index (no approximation error to discuss in the paper).

Two cases:
  1) SPARSE  (SPLADE, LCE): score = <q, d> with q and d sparse 30522-dimensional vectors.
  2) DENSE   (Concept Model): score = g(q) . g(d) with k-dimensional vectors (Eq. 5).

TRICK for the sparse case: torch.nn.functional.embedding_bag(doc_indices, TABLE, doc_weights)
computes for each document  sum_t weight_t * TABLE[t].
  - with TABLE = Q^T (vocabulary x queries)  you get the document-query scores  (search)
  - with TABLE = W   (vocabulary x k)        you get g(d) = W . SPLADE(d)       (Concept Model)
Same function, two uses.
"""
import warnings

import numpy as np
import torch
import torch.nn.functional as F

from utils import log


class TorchCSR:
    """A CSR matrix (rows = documents or queries) copied to the GPU (or CPU)."""

    def __init__(self, csr, device, value_dtype=torch.float32):
        self.n_rows, self.n_cols = csr.n_rows, csr.n_cols
        self.device = device
        self.indptr_np = np.asarray(csr.indptr, dtype=np.int64)
        with warnings.catch_warnings():          # read-only arrays (mmap): we copy them to the device anyway
            warnings.simplefilter("ignore", UserWarning)
            self.indptr = torch.from_numpy(self.indptr_np).to(device)
            self.indices = torch.from_numpy(np.ascontiguousarray(csr.indices, dtype=np.int32)).to(device)
            self.data = torch.from_numpy(np.ascontiguousarray(csr.data, dtype=np.float32)).to(device, value_dtype)

    def bags(self, start, end):
        """(indices, offsets, weights) of rows [start, end) in embedding_bag format."""
        a, b = int(self.indptr_np[start]), int(self.indptr_np[end])
        offsets = (self.indptr[start:end] - a).to(torch.int32)
        return self.indices[a:b], offsets, self.data[a:b]

    def free(self):
        del self.indptr, self.indices, self.data
        if self.device.type == "cuda":
            torch.cuda.empty_cache()


def rows_times_table(tcsr, start, end, table):
    """(CSR rows start..end) @ table   ->   (end-start, table.shape[1])"""
    idx, offs, w = tcsr.bags(start, end)
    if idx.numel() == 0:
        return torch.zeros(end - start, table.shape[1], device=table.device, dtype=table.dtype)
    return F.embedding_bag(idx, table, offs, mode="sum", per_sample_weights=w.to(table.dtype))


def csr_rows_to_dense(csr, rows, device, dtype=torch.float32):
    """Rows of a (numpy) CSR -> dense matrix (len(rows), n_cols) on device."""
    offsets, idx, val = csr.gather(rows)
    lens = np.diff(np.append(offsets, len(idx)))
    r = np.repeat(np.arange(len(rows), dtype=np.int64), lens)
    out = torch.zeros(len(rows), csr.n_cols, device=device, dtype=dtype)
    if len(idx):
        out[torch.from_numpy(r).to(device), torch.from_numpy(idx.astype(np.int64)).to(device)] = \
            torch.from_numpy(val.astype(np.float32)).to(device, dtype)
    return out


def _merge_topk(best_s, best_i, s, i, k, dim):
    if best_s is None:
        return s, i
    cat_s = torch.cat([best_s, s], dim=dim)
    cat_i = torch.cat([best_i, i], dim=dim)
    kk = min(k, cat_s.shape[dim])
    s2, pos = torch.topk(cat_s, kk, dim=dim)
    return s2, torch.gather(cat_i, dim, pos)


@torch.no_grad()
def search_with_query_table(doc_tcsr, table, k, doc_chunk=1_000_000):
    """table: (n_cols, nq) = queries as (dense) COLUMNS. Returns (scores, rows) of shape (nq, k)."""
    best_s = best_i = None
    for ds in range(0, doc_tcsr.n_rows, doc_chunk):
        de = min(doc_tcsr.n_rows, ds + doc_chunk)
        S = rows_times_table(doc_tcsr, ds, de, table).T.contiguous()   # (nq, n_doc_chunk)
        kk = min(k, de - ds)
        s, i = torch.topk(S, kk, dim=1)
        best_s, best_i = _merge_topk(best_s, best_i, s, i + ds, k, dim=1)
        del S
    return best_s, best_i


@torch.no_grad()
def sparse_search(doc_tcsr, query_csr, k, q_batch=256, doc_chunk=1_000_000, query_rows=None,
                  verbose=True):
    """Exact search of sparse queries (numpy CSR) over sparse documents (TorchCSR).
    Returns scores (nq, k) float32 and document rows (nq, k) int64 (numpy)."""
    rows_all = np.arange(query_csr.n_rows) if query_rows is None else np.asarray(query_rows)
    nq = len(rows_all)
    k = min(k, doc_tcsr.n_rows)
    out_s = np.empty((nq, k), dtype=np.float32)
    out_i = np.empty((nq, k), dtype=np.int64)
    step = max(1, (nq // q_batch) // 10)
    for b, qs in enumerate(range(0, nq, q_batch)):
        qe = min(nq, qs + q_batch)
        table = csr_rows_to_dense(query_csr, rows_all[qs:qe], doc_tcsr.device).T.contiguous()
        s, i = search_with_query_table(doc_tcsr, table, k, doc_chunk)
        out_s[qs:qe] = s.float().cpu().numpy()
        out_i[qs:qe] = i.cpu().numpy()
        if verbose and b % step == 0:
            log(f"  sparse search: {qe:,}/{nq:,} queries")
    return out_s, out_i


@torch.no_grad()
def project_rows(tcsr, W, chunk=500_000, out_dtype=torch.float16, out_device=None):
    """g(x) = W . x for all rows of a CSR (e.g. all 8.8M documents).
    W has shape (n_cols, k). Returns a tensor (n_rows, k)."""
    out_device = out_device or W.device
    out = torch.empty(tcsr.n_rows, W.shape[1], dtype=out_dtype, device=out_device)
    for s in range(0, tcsr.n_rows, chunk):
        e = min(tcsr.n_rows, s + chunk)
        out[s:e] = rows_times_table(tcsr, s, e, W).to(out_dtype).to(out_device)
    return out


@torch.no_grad()
def dense_search(D, Q, k, q_batch=512, doc_chunk=1_000_000, verbose=True):
    """Exact inner-product search. D: (N, dim) tensor (already on the device), Q: (nq, dim).
    Returns scores (nq, k) and document rows (nq, k) as numpy."""
    if not torch.is_tensor(Q):
        Q = torch.from_numpy(np.asarray(Q))
    nq, N = Q.shape[0], D.shape[0]
    k = min(k, N)
    out_s = np.empty((nq, k), dtype=np.float32)
    out_i = np.empty((nq, k), dtype=np.int64)
    step = max(1, (nq // q_batch) // 10)
    for b, qs in enumerate(range(0, nq, q_batch)):
        qe = min(nq, qs + q_batch)
        q = Q[qs:qe].to(D.device, D.dtype)
        best_s = best_i = None
        for ds in range(0, N, doc_chunk):
            de = min(N, ds + doc_chunk)
            S = (q @ D[ds:de].T).float()                      # (nq_batch, n_doc_chunk)
            kk = min(k, de - ds)
            s, i = torch.topk(S, kk, dim=1)
            best_s, best_i = _merge_topk(best_s, best_i, s, i + ds, k, dim=1)
            del S
        out_s[qs:qe] = best_s.cpu().numpy()
        out_i[qs:qe] = best_i.cpu().numpy()
        if verbose and b % step == 0:
            log(f"  dense search: {qe:,}/{nq:,} queries")
    return out_s, out_i


def gpu_fits(n_bytes, device, margin=0.85):
    if device.type != "cuda":
        return True
    free, _ = torch.cuda.mem_get_info()
    return n_bytes < free * margin
