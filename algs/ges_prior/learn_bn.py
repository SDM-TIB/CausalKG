"""GES / GES-Prior structure learning with optional hard edge constraints.

This module is the controlled implementation of GES (and its LLM-prior
extensions) that the rest of the project re-routes constrained GES to.  The
``constraint`` argument is duck-typed: it only needs to expose ``allowed`` (an
``(n, n)`` boolean matrix) and, optionally, ``to_expert_knowledge()``.
"""

import os
from concurrent.futures import ThreadPoolExecutor, as_completed
from typing import Optional

import numpy as np
import pandas as pd
from tqdm import tqdm

from pgmpy.models import DiscreteBayesianNetwork
from pgmpy.estimators import MaximumLikelihoodEstimator

from .llm_prior import causal_discovery_prompt, extract_probabilities
from .scores.structure_score_prior import StructureScoreWithPrior
from .ges_prior import run_ges_prior, run_ges_hl
from .llm_call import LLMClient


def _call_llm(client, prompt: str) -> str:
    if hasattr(client, "query_response"):
        return client.query_response(prompt=prompt)
    elif hasattr(client, "text_generate"):
        return client.text_generate(prompt=prompt)
    elif hasattr(client, "ask"):
        return client.ask(question=prompt)
    else:
        raise ValueError(
            f"Unsupported LLM client type: {type(client)}. "
            "Must have query_response(), text_generate(), or ask() method."
        )


def _estimate_priors(
    columns: list,
    var_meta: Optional[dict],
    pair_meta: Optional[dict],
    domain: str,
    llm_client,
    max_workers: int = 16,
    allowed: Optional[np.ndarray] = None,
) -> Optional[dict]:
    if var_meta is None and pair_meta is None:
        return None

    n = len(columns)
    A = np.full((n, n), np.nan)
    C = np.full((n, n), np.nan)
    D = np.full((n, n), np.nan)

    pairs = []
    for i_idx in range(n):
        for j_idx in range(i_idx + 1, n):
            # Skip LLM queries for topologically forbidden pairs; they stay NaN
            # and the masking below writes the neutral 0.5 prior.
            if allowed is not None and not (allowed[i_idx, j_idx] or allowed[j_idx, i_idx]):
                continue
            pairs.append((i_idx, j_idx))

    def _query_pair(i_idx, j_idx):
        var_a = columns[i_idx]
        var_b = columns[j_idx]

        context_a = var_meta.get(var_a, var_a) if var_meta else var_a
        context_b = var_meta.get(var_b, var_b) if var_meta else var_b

        key_forward = (var_a, var_b)
        key_reverse = (var_b, var_a)
        causal_knowledge = ""
        if pair_meta:
            if key_forward in pair_meta:
                causal_knowledge = pair_meta[key_forward]
            elif key_reverse in pair_meta:
                causal_knowledge = pair_meta[key_reverse]

        prompt = causal_discovery_prompt(
            domain=domain,
            var_a=var_a,
            var_b=var_b,
            context_a=context_a,
            context_b=context_b,
            causal_knowledge=causal_knowledge,
            repeat=True,
        )

        answer = _call_llm(llm_client, prompt)
        probs = extract_probabilities(answer)
        return (i_idx, j_idx, probs)

    futures = {}
    with ThreadPoolExecutor(max_workers=max_workers) as executor:
        for i_idx, j_idx in pairs:
            fut = executor.submit(_query_pair, i_idx, j_idx)
            futures[fut] = (i_idx, j_idx)

        for fut in tqdm(
            as_completed(futures), total=len(futures), desc="LLM queries", unit="pair"
        ):
            i_idx, j_idx = futures[fut]
            try:
                _, _, probs = fut.result()
            except Exception as e:
                var_a, var_b = columns[i_idx], columns[j_idx]
                print(f"\nWarning: LLM query failed for ({var_a}, {var_b}): {e}")
                continue

            if probs is None:
                continue

            try:
                if "P(A - B)" in probs:
                    val = float(probs["P(A - B)"])
                    A[i_idx, j_idx] = val
                    A[j_idx, i_idx] = val

                if "P(A <-> B | A - B)" in probs:
                    val = float(probs["P(A <-> B | A - B)"])
                    C[i_idx, j_idx] = val
                    C[j_idx, i_idx] = val

                if "P(A -> B | A <-> B)" in probs:
                    val = float(probs["P(A -> B | A <-> B)"])
                    D[i_idx, j_idx] = val
                    D[j_idx, i_idx] = 1.0 - val
            except (ValueError, TypeError) as e:
                var_a, var_b = columns[i_idx], columns[j_idx]
                print(f"\nWarning: invalid probability for ({var_a}, {var_b}): {e}")

    if np.all(np.isnan(A)):
        return None

    M = A * C
    nan_mask_A = np.isnan(A) | np.isnan(A.T)
    nan_mask_C = np.isnan(C) | np.isnan(C.T)
    nan_mask_M = nan_mask_A | nan_mask_C
    M[nan_mask_M] = 0.5
    M = (M + M.T) / 2

    B = M * D
    nan_mask_D = np.isnan(D)
    B[nan_mask_D] = M[nan_mask_D]
    B[nan_mask_M] = 0.5

    return {"M": M, "B": B}


def _adj_to_edges(adj: np.ndarray, columns: list) -> list:
    edges = []
    n = len(columns)
    for i in range(n):
        for j in range(i + 1, n):
            if adj[i, j] == 1 and adj[j, i] == 0:
                edges.append((columns[i], columns[j]))
            elif adj[j, i] == 1 and adj[i, j] == 0:
                edges.append((columns[j], columns[i]))
            elif adj[i, j] == 1 and adj[j, i] == 1:
                edges.append((columns[i], columns[j]))
    return edges


_ALGORITHM_ORIENT_MAP = {
    "GES": 0,
    "GES-M": 0,
    "GES-B": 0,
    "GES-M-B": 1,
    "GES-M-B-HL": 2,
    "GES-M-B-Greedy": 3,
}

_ALGORITHM_HL = {"GES-HL", "GES-M-HL", "GES-B-HL"}


def estimate_priors(
    df: pd.DataFrame,
    var_meta: Optional[dict] = None,
    pair_meta: Optional[dict] = None,
    domain: str = "general domain",
    llm_client=None,
    max_workers: int = 16,
    cache_path: Optional[str] = None,
    allowed: Optional[np.ndarray] = None,
) -> Optional[dict]:
    """Estimate ``M`` and ``B`` prior matrices from LLM queries.

    Forbidden pairs (per ``allowed``) are skipped and left at the neutral 0.5.
    Results are cached to ``cache_path`` if provided.
    """
    columns = df.columns.tolist()

    if cache_path and os.path.exists(cache_path):
        print(f"Loading cached priors from {cache_path}")
        return _load_priors(cache_path, columns)

    priors = _estimate_priors(
        columns, var_meta, pair_meta, domain, llm_client, max_workers, allowed=allowed
    )

    if cache_path and priors is not None:
        _save_priors(priors, columns, cache_path)
        print(f"Saved priors to {cache_path}")

    return priors


def _save_priors(priors, columns, path):
    import json

    os.makedirs(os.path.dirname(path) or ".", exist_ok=True)
    data = {
        "columns": columns,
        "M": [
            [None if np.isnan(x) else x for x in row] for row in priors["M"].tolist()
        ],
        "B": [
            [None if np.isnan(x) else x for x in row] for row in priors["B"].tolist()
        ],
    }
    with open(path, "w") as f:
        json.dump(data, f)


def _load_priors(path, columns):
    import json

    with open(path, "r") as f:
        data = json.load(f)
    M = np.array(data["M"], dtype=float)
    B = np.array(data["B"], dtype=float)
    return {"M": M, "B": B}


def discover_structure(
    df: pd.DataFrame,
    algorithm: str = "GES",
    var_meta: Optional[dict] = None,
    pair_meta: Optional[dict] = None,
    domain: str = "general domain",
    llm_client=None,
    llm_model: str = "deepseek-v4-flash-vision-exp",
    max_workers: int = 12,
    priors: Optional[dict] = None,
    lambda_prior: float = 1.0,
    base_score: str = "bic-d",
    constraint=None,
) -> np.ndarray:
    """Discover a structure and return its adjacency matrix.

    ``constraint`` is duck-typed (needs ``allowed``, optionally
    ``to_expert_knowledge()``).  When priors are needed and no ``llm_client`` is
    given, an :class:`LLMClient` is built with ``llm_model``.
    """
    columns = df.columns.tolist()
    data = df.astype(str)

    allowed = getattr(constraint, "allowed", None) if constraint is not None else None
    expert_knowledge = (
        constraint.to_expert_knowledge()
        if (constraint is not None and hasattr(constraint, "to_expert_knowledge"))
        else None
    )

    if priors is None and (var_meta is not None or pair_meta is not None):
        if llm_client is None:
            llm_client = LLMClient(model=llm_model)
        priors = _estimate_priors(
            columns, var_meta, pair_meta, domain, llm_client, max_workers,
            allowed=allowed,
        )

    if algorithm in _ALGORITHM_HL:
        if priors is not None:
            score1 = StructureScoreWithPrior(
                data, base_score, B=priors["M"], lambda_prior=lambda_prior
            )
        else:
            score1 = base_score
        adj = run_ges_hl(data=data, scoring_method=score1, expert_knowledge=expert_knowledge)
    elif algorithm in _ALGORITHM_ORIENT_MAP:
        orient_strategy = _ALGORITHM_ORIENT_MAP[algorithm]
        if priors is not None:
            score1 = StructureScoreWithPrior(
                data, base_score, B=priors["M"], lambda_prior=lambda_prior
            )
            score2 = StructureScoreWithPrior(
                data, base_score, B=priors["B"], lambda_prior=lambda_prior
            )
        else:
            score1 = base_score
            score2 = base_score
        adj = run_ges_prior(
            data=data,
            scoring_method_i=score1,
            scoring_method_ii=score2,
            orient_strategy=orient_strategy,
            allowed=allowed,
            expert_knowledge=expert_knowledge,
        )
    else:
        raise ValueError(
            f"Unknown algorithm '{algorithm}'. Choose from: "
            f"{list(_ALGORITHM_ORIENT_MAP.keys()) + list(_ALGORITHM_HL)}"
        )

    return adj


def learn_bayesian_network(
    df: pd.DataFrame,
    var_meta: Optional[dict] = None,
    pair_meta: Optional[dict] = None,
    algorithm: str = "GES-M-B-HL",
    lambda_prior: float = 1.0,
    base_score: str = "bic-d",
    domain: str = "general domain",
    llm_client=None,
    llm_model: str = "deepseek-v4-flash-vision-exp",
    max_workers: int = 12,
    priors: Optional[dict] = None,
    constraint=None,
) -> DiscreteBayesianNetwork:
    """Estimate a causal graph and learn the fitted :class:`DiscreteBayesianNetwork`.

    See :func:`discover_structure` for the ``constraint`` and ``llm_model``
    behaviour; all other arguments are unchanged from the original signature.
    """
    columns = df.columns.tolist()
    data = df.astype(str)

    adj = discover_structure(
        df=df,
        algorithm=algorithm,
        var_meta=var_meta,
        pair_meta=pair_meta,
        domain=domain,
        llm_client=llm_client,
        llm_model=llm_model,
        max_workers=max_workers,
        priors=priors,
        lambda_prior=lambda_prior,
        base_score=base_score,
        constraint=constraint,
    )

    edges = _adj_to_edges(adj, columns)

    model = DiscreteBayesianNetwork(edges)
    model.add_nodes_from(columns)

    isolated = [c for c in columns if c not in model.nodes()]
    if isolated:
        model.add_nodes_from(isolated)

    model.fit(data, estimator=MaximumLikelihoodEstimator)

    return model
