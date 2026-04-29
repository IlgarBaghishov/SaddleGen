"""
Mode-1 trajectory visualizer for the LiC defective-graphene case.

Plots — for ONE chosen Li-site minimum — every Mode-1 trajectory the model
can produce by being conditioned on each known partner endpoint of that
site. No velocity field; trajectories only.

How the partners are gathered:
  1. Group the (train ∪ test) triplets by R∪P Li site (`group_triplets_by_site`
     with `endpoints="RP"`). Each `SiteGroup` lists every triplet that touches
     this site and on which side ("R" or "P") it touches.
  2. Pick one site (`--site-idx` or the site with the most members).
  3. For each member triplet, extract:
       start  = the Atoms frame of the side that matches our chosen site
                (so all trajectories share the same Li starting position),
       saddle = the triplet's S frame (used only for plotting "ground-truth"
                stars; not fed to the model in Mode 1),
       partner = the OTHER endpoint of the triplet
                  (R → partner = P, P → partner = R).
  4. Run `sample_saddles(start, partner_pos=partner, sigma_inf=0,
     n_perturbations=1)` per (start, partner). Mode 1 is deterministic given
     the partner; one trajectory per partner is enough.

Run:
    CUDA_VISIBLE_DEVICES=0 python examples/LiC/visualize_mode1.py \\
        --ckpt-dir examples/LiC/runs/mode1_v0/checkpoint_final
"""

from __future__ import annotations

import argparse
import json
from pathlib import Path

import numpy as np
import torch

import matplotlib
matplotlib.use("Agg")
import matplotlib.pyplot as plt
from matplotlib.patches import Rectangle

from saddlegen.data import (
    atoms_to_sample_dict, load_validated_triplets, mic_unwrap,
)
from saddlegen.flow.sampler import sample_saddles
from saddlegen.models import GlobalAttn, VelocityHead
from saddlegen.utils import (
    group_triplets_by_site, load_ema_weights, load_uma_backbone,
)


# Atom layout for the LiC test case (see CLAUDE.md §"First test case").
LI_INDEX = 126


def parse_args():
    here = Path(__file__).resolve().parent
    p = argparse.ArgumentParser(
        description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter,
    )
    p.add_argument("--ckpt-dir",
                   default=str(here / "runs" / "mode1_v0" / "checkpoint_final"))
    p.add_argument("--no-ema", action="store_true",
                   help="load raw point-estimate weights instead of EMA shadow.")
    p.add_argument("--train-traj", default=str(here / "train_set.traj"))
    p.add_argument("--test-traj", default=str(here / "test_set.traj"))

    p.add_argument("--site-idx", type=int, default=None,
                   help="0-based index into the ordered site list (sorted by member "
                        "count, descending). Default: site with the most members.")
    p.add_argument("--site-group-threshold", type=float, default=0.02)

    p.add_argument("--sigma-inf", type=float, default=0.0,
                   help="Å. Inference-time Gaussian perturbation around start. "
                        "0 = fully deterministic Mode-1 (recommended). >0 spreads "
                        "the starts; one trajectory per perturbation per partner.")
    p.add_argument("--n-perturbations", type=int, default=1,
                   help="How many ε draws per partner. 1 with sigma_inf=0 is deterministic.")
    p.add_argument("--K", type=int, default=50, help="Euler steps")

    p.add_argument("--seed", type=int, default=0)
    p.add_argument("--device", default="cuda" if torch.cuda.is_available() else "cpu")
    p.add_argument("--out-dir", default=None,
                   help="default: same directory as --ckpt-dir.")
    return p.parse_args()


def load_model(ckpt_dir: str, device: str, use_ema: bool):
    """Re-build the architecture matching the training run, load EMA weights."""
    cfg_path = Path(ckpt_dir).parent / "config.json"
    if not cfg_path.is_file():
        raise FileNotFoundError(
            f"could not find {cfg_path} — needed to recover head/attn config "
            f"for this checkpoint."
        )
    extras = json.loads(cfg_path.read_text()).get("extras", {})
    attn_layers = int(extras.get("attn_layers", 0))
    attn_heads = int(extras.get("attn_heads", 8))
    head_depth = int(extras.get("head_depth", 1))
    delta_C = int(extras.get("delta_endpoint_channels", 0))
    mode = int(extras.get("mode", -1))
    print(f"[viz] checkpoint cfg: mode={mode}  attn_layers={attn_layers}  "
          f"head_depth={head_depth}  delta_endpoint_channels={delta_C}")
    if mode != 1:
        raise SystemExit(
            f"this script visualises Mode-1 trajectories, but the checkpoint "
            f"reports mode={mode}. Use the corresponding visualize.py instead."
        )

    backbone = load_uma_backbone("uma-s-1p2", device=device, freeze=True, eval_mode=True)
    sc, lmax = backbone.sphere_channels, backbone.lmax
    attn = GlobalAttn(sphere_channels=sc, lmax=lmax,
                      num_heads=attn_heads, num_layers=attn_layers).to(device)
    head = VelocityHead(
        sphere_channels=sc, input_lmax=lmax, depth=head_depth,
        delta_endpoint_channels=delta_C,
    ).to(device)
    load_ema_weights(ckpt_dir, [attn, head], device=device, use_ema=use_ema)
    print(f"[viz] loaded {'EMA' if use_ema else 'raw'} weights from {ckpt_dir}")
    for m in (attn, head):
        m.eval()
    return backbone, attn, head


def collect_partners_for_site(site, triplets, cell):
    """For each member of `site`, return the (start_atoms, saddle_xy_unwrapped,
    partner_un_pos, member_endpoint) tuple to feed the sampler.

    - start_atoms: ASE Atoms whose Li sits at the chosen site (= member's
      R-side or P-side, depending on `member_endpoints[i]`).
    - saddle_xy_unwrapped: (N, 3) saddle position MIC-unwrapped relative to
      `start_atoms.positions`. Used for plotting reference stars only.
    - partner_un_pos: (N, 3) the OTHER endpoint of the triplet, MIC-unwrapped
      relative to start. Fed to `sample_saddles(partner_pos=...)`.
    - member_endpoint: "R" or "P" — diagnostic only.
    """
    out = []
    for tid, ep in zip(site.member_triplets, site.member_endpoints):
        triplet = triplets[tid]
        if ep == "R":
            start_atoms = triplet[0]
            other_atoms = triplet[2]   # partner is P
        else:
            start_atoms = triplet[2]
            other_atoms = triplet[0]   # partner is R
        start_pos = start_atoms.get_positions().astype(np.float32)
        saddle_un = mic_unwrap(start_pos, triplet[1].get_positions(), cell).astype(np.float32)
        partner_un = mic_unwrap(start_pos, other_atoms.get_positions(), cell).astype(np.float32)
        out.append((start_atoms, saddle_un, partner_un, ep, tid))
    return out


def run_one_trajectory(start_atoms, partner_un, backbone, attn, head, *,
                       sigma_inf, n_perturbations, K, device, generator):
    sample = atoms_to_sample_dict(start_atoms)
    partner_t = torch.tensor(partner_un, dtype=torch.float32)
    final, traj = sample_saddles(
        sample, backbone, attn, head,
        sigma_inf=sigma_inf,
        n_perturbations=n_perturbations,
        K=K,
        device=device,
        generator=generator,
        partner_pos=partner_t,
        return_trajectory=True,
    )
    return final.cpu().numpy(), traj.cpu().numpy()


def _pbc_split(li_xy, cell):
    """Insert NaN breaks where consecutive points jump by > half a cell."""
    lx, ly = cell[0, 0], cell[1, 1]
    dx = np.diff(li_xy[:, 0])
    dy = np.diff(li_xy[:, 1])
    jump = (np.abs(dx) > lx / 2) | (np.abs(dy) > ly / 2)
    if not jump.any():
        return li_xy
    out = [li_xy[0]]
    for i in range(len(li_xy) - 1):
        if jump[i]:
            out.append([np.nan, np.nan])
        out.append(li_xy[i + 1])
    return np.asarray(out)


def plot(per_partner_data, c_xy, start_li_xy, cell, out: Path,
         title: str = ""):
    fig, ax = plt.subplots(figsize=(11, 12))
    ax.add_patch(Rectangle((0, 0), cell[0, 0], cell[1, 1],
                            fill=False, edgecolor="black", linewidth=0.6))
    ax.scatter(c_xy[:, 0], c_xy[:, 1], s=28, c="0.55", marker="o",
               edgecolors="none", alpha=0.85, zorder=2, label="C atoms")

    cmap = plt.colormaps.get_cmap("tab10")

    # Reference saddles (filled stars), partner positions (open squares).
    saddle_handle = None
    partner_handle = None
    for i, d in enumerate(per_partner_data):
        c = cmap(i % 10)
        sad_xy = d["saddle_un"][LI_INDEX, :2]
        par_xy = d["partner_un"][LI_INDEX, :2]
        h_s = ax.scatter(sad_xy[0], sad_xy[1], marker="*", s=240,
                          c=[c], edgecolors="black", linewidths=0.5, zorder=6)
        h_p = ax.scatter(par_xy[0], par_xy[1], marker="s", s=80,
                          facecolors="none", edgecolors=c, linewidths=1.2,
                          zorder=5)
        saddle_handle = saddle_handle or h_s
        partner_handle = partner_handle or h_p

    # Trajectories (one or more per partner) and final-position dots.
    for i, d in enumerate(per_partner_data):
        c = cmap(i % 10)
        traj = d["traj"]   # (K+1, n_pert, N, 3)
        for p_idx in range(traj.shape[1]):
            li_xy = traj[:, p_idx, LI_INDEX, :2]
            path = _pbc_split(li_xy, cell)
            ax.plot(path[:, 0], path[:, 1], color=c,
                    alpha=0.85, linewidth=1.4, zorder=4)
        # Final landing position(s).
        final_xy = traj[-1, :, LI_INDEX, :2]
        ax.scatter(final_xy[:, 0], final_xy[:, 1], marker="o", s=40,
                   color=c, edgecolors="black", linewidths=0.4, zorder=4.5)

    # Starting Li position — bigger red dot on top.
    ax.scatter(start_li_xy[0], start_li_xy[1], marker="o", s=170,
               c="red", edgecolors="black", linewidths=0.8, zorder=7,
               label="start (chosen site)")

    handles, labels = ax.get_legend_handles_labels()
    if saddle_handle is not None:
        handles += [saddle_handle, partner_handle]
        labels += ["reference saddles (NEB)", "partner endpoints"]
    ax.legend(handles, labels, loc="upper right", fontsize=9, framealpha=0.95)

    ax.set_xlim(-0.5, cell[0, 0] + 0.5)
    ax.set_ylim(-0.5, cell[1, 1] + 0.5)
    ax.set_aspect("equal")
    ax.set_xlabel("x (Å)")
    ax.set_ylabel("y (Å)")
    ax.set_title(title)
    fig.tight_layout()
    fig.savefig(out, dpi=200)
    print(f"[viz] wrote {out}")


def main():
    args = parse_args()
    device = args.device

    out_dir = Path(args.out_dir or Path(args.ckpt_dir).parent)
    out_dir.mkdir(parents=True, exist_ok=True)

    print(f"[viz] loading triplets …")
    train_triplets = load_validated_triplets(args.train_traj)
    test_triplets = load_validated_triplets(args.test_traj)
    triplets = train_triplets + test_triplets
    cell = np.asarray(triplets[0][0].cell[:], dtype=np.float64)
    print(f"[viz] {len(train_triplets)} train + {len(test_triplets)} test triplets, "
          f"cell diag = {[float(cell[i,i]) for i in range(3)]}")

    sites = group_triplets_by_site(triplets, cell=cell,
                                   threshold=args.site_group_threshold,
                                   endpoints="RP")
    sites = sorted(sites, key=lambda s: s.num_saddles, reverse=True)
    print(f"[viz] {len(sites)} unique sites; member counts: "
          f"{[s.num_saddles for s in sites[:10]]} ...")

    site_idx = args.site_idx if args.site_idx is not None else 0
    if site_idx >= len(sites):
        raise SystemExit(f"--site-idx {site_idx} ≥ {len(sites)} sites")
    site = sites[site_idx]
    print(f"[viz] chose site {site_idx}: rep_triplet={site.rep_triplet_idx} "
          f"({site.rep_endpoint}-side), {site.num_saddles} saddles "
          f"({site.member_endpoints.count('R')} R + "
          f"{site.member_endpoints.count('P')} P)")

    backbone, attn, head = load_model(args.ckpt_dir, device, use_ema=not args.no_ema)

    items = collect_partners_for_site(site, triplets, cell)
    # Sanity: every "start" should have its Li within `threshold` of the
    # representative — they are the same site. Use the first one as the
    # canonical start for plotting.
    rep_start_atoms = items[0][0]
    rep_start_pos = rep_start_atoms.get_positions()
    start_li_xy = rep_start_pos[LI_INDEX, :2]

    per_partner = []
    rng = np.random.default_rng(args.seed)
    for i, (start_atoms, saddle_un, partner_un, ep, tid) in enumerate(items):
        gen = torch.Generator(device="cpu").manual_seed(int(rng.integers(0, 2**31 - 1)))
        final, traj = run_one_trajectory(
            start_atoms, partner_un, backbone, attn, head,
            sigma_inf=args.sigma_inf, n_perturbations=args.n_perturbations,
            K=args.K, device=device, generator=gen,
        )
        per_partner.append({
            "triplet_id": tid, "endpoint": ep,
            "saddle_un": saddle_un, "partner_un": partner_un,
            "final": final, "traj": traj,
        })
        # Per-trajectory diagnostic: distance from final-Li to known saddle-Li.
        sad_li = saddle_un[LI_INDEX]
        for p in range(traj.shape[0] if traj.ndim == 3 else 1):
            pass
        for p in range(traj.shape[1]):
            fin_li = traj[-1, p, LI_INDEX, :]
            d = np.linalg.norm(fin_li - sad_li)
            print(f"[viz]   triplet {tid:3d} ({ep}-side, p={p}): "
                  f"|final - ref_S|_Li = {d:.3f} Å")

    # Save raw arrays alongside the plot so we can re-render without GPU.
    cache_path = out_dir / f"trajectories_site{site_idx}.npz"
    np.savez_compressed(
        cache_path,
        cell=cell,
        c_xy=rep_start_pos[:LI_INDEX, :2],   # 0..125 are C atoms
        start_li_xy=start_li_xy,
        triplet_ids=np.array([d["triplet_id"] for d in per_partner], dtype=np.int64),
        endpoints=np.array([d["endpoint"] for d in per_partner], dtype=object),
        saddles_un=np.stack([d["saddle_un"] for d in per_partner], axis=0),
        partners_un=np.stack([d["partner_un"] for d in per_partner], axis=0),
        finals=np.stack([d["final"] for d in per_partner], axis=0),
        trajs=np.stack([d["traj"] for d in per_partner], axis=0),
    )
    print(f"[viz] cached arrays → {cache_path}")

    out_png = out_dir / f"trajectories_site{site_idx}_mode1.png"
    plot(
        per_partner,
        c_xy=rep_start_pos[:LI_INDEX, :2],
        start_li_xy=start_li_xy,
        cell=cell,
        out=out_png,
        title=(f"LiC Mode-1 — site {site_idx}: 1 start × "
               f"{len(per_partner)} partners (≈saddles in this orbit)"),
    )


if __name__ == "__main__":
    main()
