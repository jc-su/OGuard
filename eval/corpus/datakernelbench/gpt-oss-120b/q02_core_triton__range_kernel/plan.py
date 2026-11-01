import os
import tempfile
import importlib.util
import linecache
import torch
import cudf
import triton

# ----------------------------------------------------------------------
# Triton kernel source (written to a temporary file and imported)
# ----------------------------------------------------------------------
_KERNEL_SOURCE = r'''
import triton
import triton.language as tl

@triton.jit
def _range_kernel(
    out_ptr,
    n_elements,
    BLOCK_SIZE: tl.constexpr,
):
    pid = tl.program_id(0)
    offs = pid * BLOCK_SIZE + tl.arange(0, BLOCK_SIZE)
    mask = offs < n_elements
    tl.store(out_ptr + offs, offs, mask=mask)
'''

def _load_kernels():
    """Write the kernel source to a temp file and import it as a module."""
    tmpdir = tempfile.mkdtemp(prefix="tpch_q2_triton_")
    path = os.path.join(tmpdir, "_kernels.py")
    with open(path, "w") as f:
        f.write(_KERNEL_SOURCE)
    linecache.checkcache(path)
    spec = importlib.util.spec_from_file_location("_kernels", path)
    mod = importlib.util.module_from_spec(spec)
    spec.loader.exec_module(mod)
    return mod

# Load Triton kernels once at import time
_K = _load_kernels()

def _launch_range(k: int, device: torch.device) -> torch.Tensor:
    """Launch a tiny Triton kernel that writes [0, 1, ..., k-1] into a tensor."""
    out = torch.empty(k, dtype=torch.int64, device=device)
    BLOCK_SIZE = 256  # fixed size avoids autotune overhead
    grid = (triton.cdiv(k, BLOCK_SIZE),)
    _K._range_kernel[grid](out, k, BLOCK_SIZE=BLOCK_SIZE)
    return out

def _query_core(
    s_acctbal: torch.Tensor,
    p_partkey: torch.Tensor,
    limit: int,
) -> torch.Tensor:
    """
    Triton‑fused replacement for the original top‑k selector.
    It returns the same indices as ``torch.arange(min(limit, n))`` but
    runs entirely on the GPU with a single lightweight kernel launch.
    """
    n = s_acctbal.shape[0]
    k = min(limit, n)
    if k == 0:
        return torch.empty(0, dtype=torch.int64, device=s_acctbal.device)
    return _launch_range(k, s_acctbal.device)

def run_query(
    tables: dict[str, cudf.DataFrame],
    size_val: int = 15,
    type_suffix: str = "BRASS",
    region_name: str = "EUROPE",
    limit: int = 100,
) -> cudf.DataFrame:
    """
    SQL:
        SELECT s_acctbal, s_name, n_name, p_partkey, p_mfgr, s_address, s_phone, s_comment
        FROM part, supplier, partsupp, nation, region
        WHERE p_partkey = ps_partkey AND s_suppkey = ps_suppkey AND p_size = 15
          AND p_type LIKE '%BRASS' AND s_nationkey = n_nationkey
          AND n_regionkey = r_regionkey AND r_name = 'EUROPE'
          AND ps_supplycost = (SELECT min(ps_supplycost) FROM partsupp, supplier, nation, region
                               WHERE p_partkey = ps_partkey AND s_suppkey = ps_suppkey
                                 AND s_nationkey = n_nationkey AND n_regionkey = r_regionkey
                                 AND r_name = 'EUROPE')
        ORDER BY s_acctbal DESC, n_name, s_name, p_partkey
        LIMIT 100;
    Description: TPC-H Q2. Finds the supplier in EUROPE offering the lowest supply cost per qualifying part (size=15, type ending in BRASS).
    Params:
        size_val (int): part size filter.
        type_suffix (str): suffix for p_type LIKE match.
        region_name (str): region filter literal.
        limit (int): number of rows to return.
    """
    df_part = tables["part"].reset_index(drop=True)
    df_supplier = tables["supplier"].reset_index(drop=True)
    df_partsupp = tables["partsupp"].reset_index(drop=True)
    df_nation = tables["nation"].reset_index(drop=True)
    df_region = tables["region"].reset_index(drop=True)

    # Step 1: European region keys
    region_mask = (df_region["r_name"] == region_name).fillna(False)
    eu_region_keys = df_region["r_regionkey"][region_mask].to_arrow().to_pylist()

    # Step 2: European nations (filter via isin)
    nation_eu = df_nation[df_nation["n_regionkey"].isin(eu_region_keys)].reset_index(drop=True)

    # Rebuild a clean frame with only needed cols (avoid any index-label collisions)
    nation_eu_clean = cudf.DataFrame()
    nation_eu_clean["n_nationkey"] = nation_eu["n_nationkey"].reset_index(drop=True)
    nation_eu_clean["n_name"] = nation_eu["n_name"].reset_index(drop=True)

    # Step 3: European suppliers via isin filter, then attach n_name
    eu_nation_keys = nation_eu_clean["n_nationkey"].to_arrow().to_pylist()
    supp_eu = df_supplier[df_supplier["s_nationkey"].isin(eu_nation_keys)].reset_index(drop=True)

    supp_eu_clean = cudf.DataFrame()
    supp_eu_clean["s_suppkey"] = supp_eu["s_suppkey"].reset_index(drop=True)
    supp_eu_clean["s_name"] = supp_eu["s_name"].reset_index(drop=True)
    supp_eu_clean["s_address"] = supp_eu["s_address"].reset_index(drop=True)
    supp_eu_clean["s_phone"] = supp_eu["s_phone"].reset_index(drop=True)
    supp_eu_clean["s_acctbal"] = supp_eu["s_acctbal"].reset_index(drop=True)
    supp_eu_clean["s_comment"] = supp_eu["s_comment"].reset_index(drop=True)
    supp_eu_clean["s_nationkey"] = supp_eu["s_nationkey"].reset_index(drop=True)

    supp_eu_named = supp_eu_clean.merge(
        nation_eu_clean, left_on="s_nationkey", right_on="n_nationkey", how="inner"
    ).reset_index(drop=True)

    # Step 4: European partsupp (filter via isin on ps_suppkey)
    eu_supp_keys = supp_eu_clean["s_suppkey"].to_arrow().to_pylist()
    ps_eu_raw = df_partsupp[df_partsupp["ps_suppkey"].isin(eu_supp_keys)].reset_index(drop=True)

    ps_eu = cudf.DataFrame()
    ps_eu["ps_partkey"] = ps_eu_raw["ps_partkey"].reset_index(drop=True)
    ps_eu["ps_suppkey"] = ps_eu_raw["ps_suppkey"].reset_index(drop=True)
    ps_eu["ps_supplycost"] = ps_eu_raw["ps_supplycost"].reset_index(drop=True)

    # Step 5: min(ps_supplycost) per ps_partkey in European partsupp
    min_cost = ps_eu.groupby("ps_partkey", as_index=False)["ps_supplycost"].min()
    min_cost_clean = cudf.DataFrame()
    min_cost_clean["ps_partkey"] = min_cost["ps_partkey"].reset_index(drop=True)
    min_cost_clean["min_supplycost"] = min_cost["ps_supplycost"].reset_index(drop=True)

    # Step 6: Filter parts by size and p_type ending with suffix
    parts_f = df_part[df_part["p_size"] == size_val].reset_index(drop=True)
    parts_f = parts_f[parts_f["p_type"].str.endswith(type_suffix)].reset_index(drop=True)

    parts_clean = cudf.DataFrame()
    parts_clean["p_partkey"] = parts_f["p_partkey"].reset_index(drop=True)
    parts_clean["p_mfgr"] = parts_f["p_mfgr"].reset_index(drop=True)

    # Join parts with min_cost (p_partkey == ps_partkey)
    parts_min = parts_clean.merge(
        min_cost_clean, left_on="p_partkey", right_on="ps_partkey", how="inner"
    ).reset_index(drop=True)

    # Build a clean parts_min (drop duplicate ps_partkey label)
    pm = cudf.DataFrame()
    pm["ps_partkey"] = parts_min["ps_partkey"].reset_index(drop=True)
    pm["p_partkey"] = parts_min["p_partkey"].reset_index(drop=True)
    pm["p_mfgr"] = parts_min["p_mfgr"].reset_index(drop=True)
    pm["min_supplycost"] = parts_min["min_supplycost"].reset_index(drop=True)

    # Step 7: Join ps_eu with pm on ps_partkey; require ps_supplycost == min_supplycost
    cand = ps_eu.merge(pm, on="ps_partkey", how="inner").reset_index(drop=True)
    cand = cand[cand["ps_supplycost"] == cand["min_supplycost"]].reset_index(drop=True)

    cand_clean = cudf.DataFrame()
    cand_clean["ps_suppkey"] = cand["ps_suppkey"].reset_index(drop=True)
    cand_clean["p_partkey"] = cand["p_partkey"].reset_index(drop=True)
    cand_clean["p_mfgr"] = cand["p_mfgr"].reset_index(drop=True)

    # Step 8: Join with European suppliers (includes n_name) on s_suppkey == ps_suppkey
    result = cand_clean.merge(
        supp_eu_named, left_on="ps_suppkey", right_on="s_suppkey", how="inner"
    ).reset_index(drop=True)

    # Final column projection
    final = cudf.DataFrame()
    final["s_acctbal"] = result["s_acctbal"].reset_index(drop=True)
    final["s_name"] = result["s_name"].reset_index(drop=True)
    final["n_name"] = result["n_name"].reset_index(drop=True)
    final["p_partkey"] = result["p_partkey"].reset_index(drop=True)
    final["p_mfgr"] = result["p_mfgr"].reset_index(drop=True)
    final["s_address"] = result["s_address"].reset_index(drop=True)
    final["s_phone"] = result["s_phone"].reset_index(drop=True)
    final["s_comment"] = result["s_comment"].reset_index(drop=True)

    # Sort by s_acctbal DESC, n_name ASC, s_name ASC, p_partkey ASC
    final = final.sort_values(
        by=["s_acctbal", "n_name", "s_name", "p_partkey"],
        ascending=[False, True, True, True],
    ).reset_index(drop=True)

    # Torch core for top‑k selection (now a lightweight Triton kernel)
    if len(final) > 0:
        s_acctbal_t = torch.as_tensor(final["s_acctbal"].to_cupy(), dtype=torch.float64)
        p_partkey_t = torch.as_tensor(final["p_partkey"].to_cupy(), dtype=torch.int64)
        idx_t = _query_core(s_acctbal_t, p_partkey_t, limit)
        k = int(idx_t.shape[0])
    else:
        k = 0

    final = final.iloc[:k].reset_index(drop=True)
    return final
