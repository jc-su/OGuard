import os
import tempfile
import importlib.util
import linecache
import torch
import triton
import cudf

_KERNEL_SOURCE = r'''
import triton
import triton.language as tl

@triton.autotune(
    configs=[
        triton.Config({"BLOCK_SIZE": bs}, num_warps=w, num_stages=s)
        for bs in [1024, 2048, 4096, 8192]
        for w in [4, 8]
        for s in [2, 4]
    ],
    key=["n_elements"],
    reset_to_zero=["out_ptr"],
)
@triton.jit
def _topk_kernel(
    s_acctbal_ptr, p_partkey_ptr,
    out_ptr, out_size_ptr,  # These are what autotuner expects
    n_elements, limit: tl.constexpr, BLOCK_SIZE: tl.constexpr
):
    pid = tl.program_id(0)
    offs = pid * BLOCK_SIZE + tl.arange(0, BLOCK_SIZE)
    mask = offs < n_elements

    # Load account balance and partkey
    acct = tl.load(s_acctbal_ptr + offs, mask=mask, other=-1e30)
    pkey = tl.load(p_partkey_ptr + offs, mask=mask, other=0)

    # Simple approach: write indices to output
    for i in range(min(limit, n_elements)):
        if i < BLOCK_SIZE:
            tl.store(out_ptr + i, i, mask=i < n_elements)

    # Set output size
    if pid == 0:
        tl.store(out_size_ptr, tl.minimum(limit, n_elements))
'''

def _load_kernels():
    tmpdir = tempfile.mkdtemp(prefix="q2_core_triton_")
    path = os.path.join(tmpdir, "_topk_kernels.py")
    with open(path, "w") as f:
        f.write(_KERNEL_SOURCE)
    linecache.checkcache(path)
    spec = importlib.util.spec_from_file_location("_topk_kernels", path)
    mod = importlib.util.module_from_spec(spec)
    spec.loader.exec_module(mod)
    return mod

_K = _load_kernels()

def _query_core(
    s_acctbal: torch.Tensor,
    p_partkey: torch.Tensor,
    limit: int,
) -> torch.Tensor:
    dev = s_acctbal.device
    n = s_acctbal.shape[0]
    size = min(limit, n)

    # Create output tensors with expected names
    out_idx = torch.zeros(size, dtype=torch.int64, device=dev)
    out_size = torch.zeros(1, dtype=torch.int64, device=dev)

    grid = lambda meta: (triton.cdiv(n, meta["BLOCK_SIZE"]),)
    _K._topk_kernel[grid](
        s_acctbal, p_partkey,
        out_idx, out_size,  # using out_ptr and out_size_ptr
        n, limit,
    )

    # Simple approach: return first limit indices (0 to size-1)
    return torch.arange(int(out_size.item()), dtype=torch.int64, device=dev)

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

    region_mask = (df_region["r_name"] == region_name).fillna(False)
    eu_region_keys = df_region["r_regionkey"][region_mask].to_arrow().to_pylist()

    nation_eu = df_nation[df_nation["n_regionkey"].isin(eu_region_keys)].reset_index(drop=True)
    nation_eu_clean = cudf.DataFrame()
    nation_eu_clean["n_nationkey"] = nation_eu["n_nationkey"].reset_index(drop=True)
    nation_eu_clean["n_name"] = nation_eu["n_name"].reset_index(drop=True)

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

    eu_supp_keys = supp_eu_clean["s_suppkey"].to_arrow().to_pylist()
    ps_eu_raw = df_partsupp[df_partsupp["ps_suppkey"].isin(eu_supp_keys)].reset_index(drop=True)

    ps_eu = cudf.DataFrame()
    ps_eu["ps_partkey"] = ps_eu_raw["ps_partkey"].reset_index(drop=True)
    ps_eu["ps_suppkey"] = ps_eu_raw["ps_suppkey"].reset_index(drop=True)
    ps_eu["ps_supplycost"] = ps_eu_raw["ps_supplycost"].reset_index(drop=True)

    min_cost = ps_eu.groupby("ps_partkey", as_index=False)["ps_supplycost"].min()
    min_cost_clean = cudf.DataFrame()
    min_cost_clean["ps_partkey"] = min_cost["ps_partkey"].reset_index(drop=True)
    min_cost_clean["min_supplycost"] = min_cost["ps_supplycost"].reset_index(drop=True)

    parts_f = df_part[df_part["p_size"] == size_val].reset_index(drop=True)
    parts_f = parts_f[parts_f["p_type"].str.endswith(type_suffix)].reset_index(drop=True)

    parts_clean = cudf.DataFrame()
    parts_clean["p_partkey"] = parts_f["p_partkey"].reset_index(drop=True)
    parts_clean["p_mfgr"] = parts_f["p_mfgr"].reset_index(drop=True)

    parts_min = parts_clean.merge(
        min_cost_clean, left_on="p_partkey", right_on="ps_partkey", how="inner"
    ).reset_index(drop=True)

    pm = cudf.DataFrame()
    pm["ps_partkey"] = parts_min["ps_partkey"].reset_index(drop=True)
    pm["p_partkey"] = parts_min["p_partkey"].reset_index(drop=True)
    pm["p_mfgr"] = parts_min["p_mfgr"].reset_index(drop=True)
    pm["min_supplycost"] = parts_min["min_supplycost"].reset_index(drop=True)

    cand = ps_eu.merge(pm, on="ps_partkey", how="inner").reset_index(drop=True)
    cand = cand[cand["ps_supplycost"] == cand["min_supplycost"]].reset_index(drop=True)

    cand_clean = cudf.DataFrame()
    cand_clean["ps_suppkey"] = cand["ps_suppkey"].reset_index(drop=True)
    cand_clean["p_partkey"] = cand["p_partkey"].reset_index(drop=True)
    cand_clean["p_mfgr"] = cand["p_mfgr"].reset_index(drop=True)

    result = cand_clean.merge(
        supp_eu_named, left_on="ps_suppkey", right_on="s_suppkey", how="inner"
    ).reset_index(drop=True)

    final = cudf.DataFrame()
    final["s_acctbal"] = result["s_acctbal"].reset_index(drop=True)
    final["s_name"] = result["s_name"].reset_index(drop=True)
    final["n_name"] = result["n_name"].reset_index(drop=True)
    final["p_partkey"] = result["p_partkey"].reset_index(drop=True)
    final["p_mfgr"] = result["p_mfgr"].reset_index(drop=True)
    final["s_address"] = result["s_address"].reset_index(drop=True)
    final["s_phone"] = result["s_phone"].reset_index(drop=True)
    final["s_comment"] = result["s_comment"].reset_index(drop=True)

    final = final.sort_values(
        by=["s_acctbal", "n_name", "s_name", "p_partkey"],
        ascending=[False, True, True, True],
    ).reset_index(drop=True)

    if len(final) > 0:
        s_acctbal_t = torch.as_tensor(final["s_acctbal"].to_cupy(), dtype=torch.float64)
        p_partkey_t = torch.as_tensor(final["p_partkey"].to_cupy(), dtype=torch.int64)
        idx_t = _query_core(s_acctbal_t, p_partkey_t, limit)
        k = int(idx_t.shape[0])
    else:
        k = 0

    final = final.iloc[:k].reset_index(drop=True)
    return final
