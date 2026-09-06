#!/usr/bin/env python3
"""3D-CLIP-style similarity using Uni3D-Giant + EVA02-E-14-plus.

For every instance in `<results-root>/<model>/`, compute three per-pair
cosine similarities in the shared 1024-dim CLIP-aligned latent:

    text   ↔ 3D     cos(text_encoder(prompt),     uni3d(gen_pcd))
    image  ↔ 3D     cos(image_encoder(ref_image), uni3d(gen_pcd))
    3D     ↔ 3D     cos(uni3d(ref_pcd),           uni3d(gen_pcd))

Encoders:
    Point cloud:  Uni3D-Giant (1B params, EVA-Giant backbone, 8192 pts
                  + 3-channel RGB, ICLR'24, BAAI). Loaded from HF
                  BAAI/Uni3D :: modelzoo/uni3d-g/model.pt.
    Text/Image:   OpenCLIP EVA02-E-14-plus (laion2b_s9b_b144k). 1024-dim
                  output, the same space Uni3D was contrastively
                  aligned to. Loaded via open_clip.

Aggregates (matches image_similarity.py / shape_chamfer.py):
    conditional_mean — over instances where the generated GLB loaded.
    penalized_mean   — failed/missing instances count as 0.

Reference inputs:
    - Reference GLB: data/<inst>/glb/<inst>.glb
    - Reference image: data/<inst>/images/Image_005.png   (the canonical
      "front" view at 45 deg azimuth — the one most likely to look
      like a "product shot" of the object)
    - Prompt text: data/<inst>/prompt_description.txt   (caption-style;
      we don't use prompt_instruction.txt because it's a coding
      command, not a description)

Output:
    <model_dir>/_metrics/shape_uni3d.json
"""

import argparse
import json
import os
import sys
import time
import types
from pathlib import Path

import numpy as np
import torch
import trimesh
from PIL import Image

EVAL_ROOT = Path(os.environ.get("EVAL_ROOT")
                 or Path(__file__).resolve().parent.parent)
DEFAULT_DATA_ROOT = EVAL_ROOT / "data"
# Point UNI3D_REPO at your local clone of https://github.com/baaivision/Uni3D
UNI3D_REPO = Path(os.environ.get("UNI3D_REPO", EVAL_ROOT / "external" / "Uni3D"))
sys.path.insert(0, str(UNI3D_REPO))


# --- Pure-PyTorch FPS replacement for pointnet2_ops dependency ---

def _fps_torch(xyz_BN3, npoint):
    """Farthest-point sampling. Returns indices [B, npoint] (long)."""
    B, N, _ = xyz_BN3.shape
    device = xyz_BN3.device
    centroids = torch.zeros(B, npoint, dtype=torch.long, device=device)
    distance = torch.full((B, N), float("inf"), device=device)
    farthest = torch.randint(0, N, (B,), device=device)
    batch_idx = torch.arange(B, device=device)
    for i in range(npoint):
        centroids[:, i] = farthest
        centroid = xyz_BN3[batch_idx, farthest, :].unsqueeze(1)
        dist = ((xyz_BN3 - centroid) ** 2).sum(-1)
        distance = torch.minimum(distance, dist)
        farthest = distance.argmax(-1)
    return centroids


class _FakePointnet2Utils:
    @staticmethod
    def furthest_point_sample(data, number):
        # Uni3D expects int32 indices (gather_operation needs int)
        return _fps_torch(data, number).int()
    @staticmethod
    def gather_operation(features, idx):
        # features: (B, C, N), idx: (B, M) → (B, C, M)
        idx_long = idx.long()
        return torch.gather(features, 2,
            idx_long.unsqueeze(1).expand(-1, features.size(1), -1))


def _install_fake_pointnet2():
    fake = types.ModuleType("pointnet2_ops")
    sub = types.ModuleType("pointnet2_ops.pointnet2_utils")
    sub.furthest_point_sample = _FakePointnet2Utils.furthest_point_sample
    sub.gather_operation       = _FakePointnet2Utils.gather_operation
    fake.pointnet2_utils = sub
    sys.modules["pointnet2_ops"] = fake
    sys.modules["pointnet2_ops.pointnet2_utils"] = sub


_install_fake_pointnet2()

# Now safe to import Uni3D's pointcloud encoder. We DON'T import
# `models.uni3d` because that module pulls in losses/datasets/h5py and a
# bunch of training-only code. The `Uni3D` wrapper class itself is tiny
# (just a logit_scale param + delegate to point_encoder), so we inline it
# below instead.
from models.point_encoder import PointcloudEncoder  # noqa: E402
import open_clip  # noqa: E402
import timm  # noqa: E402
from huggingface_hub import hf_hub_download  # noqa: E402


class _Uni3D(torch.nn.Module):
    """Inlined version of Uni3D/models/uni3d.py::Uni3D for inference."""
    def __init__(self, point_encoder):
        super().__init__()
        self.logit_scale = torch.nn.Parameter(torch.ones([]) * np.log(1 / 0.07))
        self.point_encoder = point_encoder
    def encode_pc(self, pc):
        return self.point_encoder(pc[:, :, :3].contiguous(),
                                  pc[:, :, 3:].contiguous())


# --- Config namespace expected by Uni3D's create_uni3d ---

UNI3D_GIANT_CFG = dict(
    pc_model="eva_giant_patch14_560",
    pc_feat_dim=1408,
    embed_dim=1024,
    group_size=64,
    num_group=512,
    pc_encoder_dim=512,
    patch_dropout=0.0,
    drop_path_rate=0.0,
)


def load_uni3d_giant(device, dtype=torch.float32):
    args = types.SimpleNamespace(**UNI3D_GIANT_CFG)
    backbone = timm.create_model(args.pc_model,
                                 drop_path_rate=args.drop_path_rate,
                                 num_classes=0)
    point_encoder = PointcloudEncoder(backbone, args)
    model = _Uni3D(point_encoder=point_encoder)

    weight_path = hf_hub_download("BAAI/Uni3D", "modelzoo/uni3d-g/model.pt")
    sd = torch.load(weight_path, map_location="cpu", weights_only=False)
    if isinstance(sd, dict) and "module" in sd:    sd = sd["module"]
    if isinstance(sd, dict) and "state_dict" in sd: sd = sd["state_dict"]
    sd = {k.replace("module.", ""): v for k, v in sd.items()}
    missing, unexpected = model.load_state_dict(sd, strict=False)
    if unexpected:
        print(f"  Uni3D unexpected keys ({len(unexpected)}): "
              f"{unexpected[:5]}{' ...' if len(unexpected) > 5 else ''}")
    if missing:
        # tolerate small head/proj mismatches
        print(f"  Uni3D missing keys ({len(missing)}): "
              f"{missing[:5]}{' ...' if len(missing) > 5 else ''}")

    model.to(device=device, dtype=dtype).eval()
    return model


def load_clip(device, dtype=torch.float16):
    model, _, image_preprocess = open_clip.create_model_and_transforms(
        "EVA02-E-14-plus",
        pretrained="laion2b_s9b_b144k",
    )
    tokenizer = open_clip.get_tokenizer("EVA02-E-14-plus")
    model.to(device=device, dtype=dtype).eval()
    return model, tokenizer, image_preprocess


# --- Sampling: Uni3D expects 8192 pts + 3-channel RGB in [0, 1] ---

def sample_xyz_rgb(glb_path, n_points, rng):
    try:
        mesh = trimesh.load(glb_path, force="mesh")
    except Exception:
        return None
    if mesh is None or mesh.is_empty: return None
    if mesh.faces is None or len(mesh.faces) == 0: return None
    try:
        pts, face_idx = trimesh.sample.sample_surface(
            mesh, n_points, seed=int(rng.integers(0, 2**31 - 1)))
    except Exception:
        return None
    pts = np.asarray(pts, dtype=np.float32)

    # RGB: try face colors, fall back to mid-gray.
    rgb = np.full((n_points, 3), 0.4, dtype=np.float32)
    try:
        v = mesh.visual
        if hasattr(v, "face_colors") and v.face_colors is not None:
            fc = np.asarray(v.face_colors)
            if fc.ndim == 2 and fc.shape[0] >= len(mesh.faces):
                rgb = (fc[face_idx, :3].astype(np.float32) / 255.0)
        elif hasattr(v, "vertex_colors") and v.vertex_colors is not None:
            vc = np.asarray(v.vertex_colors)
            if vc.ndim == 2:
                # average vertex colors over face vertices
                f = mesh.faces[face_idx]
                rgb = (vc[f].mean(axis=1)[:, :3].astype(np.float32) / 255.0)
    except Exception:
        pass
    return pts, rgb


def normalize_points(xyz, scale="unit_sphere"):
    """Center + scale. Uni3D paper / OpenShape preprocess to unit sphere."""
    xyz = xyz - xyz.mean(0, keepdims=True)
    if scale == "unit_sphere":
        r = np.linalg.norm(xyz, axis=1).max()
        if r > 1e-9: xyz = xyz / r
    return xyz


def encode_pcd(model, xyz_rgb, device, dtype):
    """Encode one (xyz, rgb) tuple to 1024-d L2-normalized embedding."""
    xyz, rgb = xyz_rgb
    pcd = np.concatenate([xyz, rgb], axis=-1)  # N x 6
    pcd_t = torch.from_numpy(pcd).to(device=device, dtype=dtype).unsqueeze(0)
    with torch.no_grad():
        emb = model.encode_pc(pcd_t)
    emb = emb / emb.norm(dim=-1, keepdim=True).clamp_min(1e-8)
    return emb.squeeze(0).float().cpu()


def encode_text(clip_model, tokenizer, text, device, dtype):
    toks = tokenizer([text]).to(device)
    with torch.no_grad():
        emb = clip_model.encode_text(toks).to(dtype=dtype)
    emb = emb / emb.norm(dim=-1, keepdim=True).clamp_min(1e-8)
    return emb.squeeze(0).float().cpu()


def encode_image(clip_model, preprocess, img_path, device, dtype):
    img = Image.open(img_path).convert("RGB")
    img_t = preprocess(img).unsqueeze(0).to(device=device, dtype=dtype)
    with torch.no_grad():
        emb = clip_model.encode_image(img_t)
    emb = emb / emb.norm(dim=-1, keepdim=True).clamp_min(1e-8)
    return emb.squeeze(0).float().cpu()


# --- Per-instance pipeline ---

def list_instances(model_dir, override=None):
    insts = sorted(d for d in model_dir.iterdir()
                   if d.is_dir() and not d.name.startswith("_"))
    if override:
        keep = set(override); insts = [d for d in insts if d.name in keep]
    return insts


def detect_task(results_root):
    """Infer task from results-root path. Used to choose text vs image side."""
    s = str(results_root)
    if "image_to_3D" in s: return "image_to_3d"
    if "text_to_3D"  in s: return "text_to_3d"
    return None  # unknown — score 3D-3D only


def parse_args():
    p = argparse.ArgumentParser(description=__doc__,
        formatter_class=argparse.RawDescriptionHelpFormatter)
    # Single-dir mode
    p.add_argument("--model",        default=None,
                   help="Single model dir name under --results-root.")
    p.add_argument("--results-root", type=Path, default=None,
                   help="Single mode: process <results-root>/<model>.")
    # Batch mode
    p.add_argument("--targets", nargs="+", default=None,
                   help="Batch mode: any number of <results-root>/<model> dirs "
                        "(or glob patterns). Loads encoders once and processes "
                        "each in turn. Skips dirs that already have a "
                        "shape_uni3d.json unless --overwrite.")
    p.add_argument("--overwrite", action="store_true",
                   help="In batch mode, re-process dirs that already have "
                        "shape_uni3d.json.")
    # Common
    p.add_argument("--data-root",    type=Path, default=DEFAULT_DATA_ROOT)
    p.add_argument("--gt-renders-subdir", default="images",
                   help="Reference render directory below each GT instance "
                        "(default: images).")
    p.add_argument("--gt-glb-relpath", default="glb/{instance}.glb",
                   help="Reference GLB path relative to <data-root>/<instance>; "
                        "supports {instance} (default: glb/{instance}.glb).")
    p.add_argument("--task", choices=["text_to_3d", "image_to_3d", "auto"],
                   default="auto")
    p.add_argument("--n-points",     type=int, default=8192,
                   help="Uni3D paper used 10000; 8192 is plenty + faster.")
    p.add_argument("--seed",         type=int, default=0)
    p.add_argument("--device",       default="cuda")
    p.add_argument("--instances",    nargs="*", default=None)
    p.add_argument("--limit",        type=int, default=None)
    p.add_argument("--ref-view",     default="Image_005.png",
                   help="Which reference view to use for image-3D cosine.")
    p.add_argument("--no-clip",      action="store_true",
                   help="Skip CLIP loading; only do 3D-3D paired cosine.")
    return p.parse_args()


def expand_targets(patterns):
    """Each `pattern` can be a literal dir or a glob. Returns sorted, deduped
    list of pathlib.Path model dirs."""
    import glob
    out = []
    for pat in patterns:
        # Allow literal dir
        p = Path(pat)
        if p.is_dir():
            out.append(p); continue
        # Otherwise try glob from cwd
        for m in glob.glob(pat):
            mp = Path(m)
            if mp.is_dir(): out.append(mp)
    seen = set(); ret = []
    for p in out:
        rp = p.resolve()
        if rp in seen: continue
        seen.add(rp); ret.append(p)
    return ret


def process_dir(model_dir, task_override, args, encoders, rng):
    """Encode all instances in `model_dir`, write _metrics/shape_uni3d.json.
    `encoders` is a dict with `uni3d`, `clip_model`, `clip_tokenizer`,
    `clip_preprocess`. Returns the summary dict."""
    uni3d = encoders["uni3d"]
    clip_model = encoders["clip_model"]
    clip_tokenizer = encoders["clip_tokenizer"]
    clip_preprocess = encoders["clip_preprocess"]
    device = encoders["device"]

    # Detect task per dir from its results-root path (parent of model_dir).
    results_root = model_dir.parent
    task = (detect_task(results_root) if task_override == "auto"
            else task_override)

    insts = list_instances(model_dir, args.instances)
    if args.limit: insts = insts[:args.limit]
    if not insts:
        print(f"  [{model_dir}] no instances; skipping")
        return None
    print(f"[{model_dir.parent.name}/{model_dir.name}]  "
          f"task={task}  n={len(insts)}")

    per_instance = []
    t0 = time.time()
    for i, inst in enumerate(insts):
        try:
            gt_relpath = args.gt_glb_relpath.format(instance=inst.name)
        except (KeyError, ValueError) as exc:
            raise ValueError(f"Invalid --gt-glb-relpath: {exc}") from exc
        ref_glb = args.data_root / inst.name / gt_relpath
        gen_glb = inst / "glb" / f"{inst.name}.glb"
        prompt_p = args.data_root / inst.name / "prompt_description.txt"
        ref_img_p = (args.data_root / inst.name / args.gt_renders_subdir
                     / args.ref_view)

        rec = {"instance": inst.name,
               "cos_text_3d":  None,
               "cos_image_3d": None,
               "cos_3d_3d":    None,
               "status":       None}

        if not gen_glb.exists():
            rec["status"] = "NO_GEN_GLB"
            per_instance.append(rec); continue

        gen_xr = sample_xyz_rgb(gen_glb, args.n_points, rng)
        if gen_xr is None:
            rec["status"] = "BAD_GEN_MESH"
            per_instance.append(rec); continue
        gen_xyz = normalize_points(gen_xr[0]); gen_rgb = gen_xr[1]
        gen_emb = encode_pcd(uni3d, (gen_xyz, gen_rgb), device,
                             dtype=torch.float32)

        if ref_glb.exists():
            ref_xr = sample_xyz_rgb(ref_glb, args.n_points, rng)
            if ref_xr is not None:
                ref_xyz = normalize_points(ref_xr[0]); ref_rgb = ref_xr[1]
                ref_emb = encode_pcd(uni3d, (ref_xyz, ref_rgb), device,
                                     dtype=torch.float32)
                rec["cos_3d_3d"] = float((gen_emb * ref_emb).sum())

        if clip_model is not None:
            if task == "text_to_3d" and prompt_p.exists():
                prompt = prompt_p.read_text().strip()
                t_emb = encode_text(clip_model, clip_tokenizer, prompt,
                                    device, dtype=torch.float16)
                rec["cos_text_3d"] = float((gen_emb * t_emb).sum())
            if task == "image_to_3d" and ref_img_p.exists():
                i_emb = encode_image(clip_model, clip_preprocess, ref_img_p,
                                     device, dtype=torch.float16)
                rec["cos_image_3d"] = float((gen_emb * i_emb).sum())

        rec["status"] = "OK"
        per_instance.append(rec)
        if (i + 1) % 50 == 0 or i == len(insts) - 1:
            ok = sum(1 for r in per_instance if r["status"] == "OK")
            print(f"  [{i+1}/{len(insts)}]  ok={ok}  "
                  f"elapsed={time.time()-t0:.0f}s")

    n = len(per_instance)
    ok = [r for r in per_instance if r["status"] == "OK"]

    def agg(field):
        valid = [r[field] for r in ok if r[field] is not None]
        cond = float(np.mean(valid)) if valid else None
        pen_vals = [r[field] if (r["status"] == "OK" and r[field] is not None)
                    else 0.0
                    for r in per_instance]
        return {"conditional_mean": cond,
                "n_valid":          len(valid),
                "penalized_mean":   float(np.mean(pen_vals))}

    summary = {
        "model":         model_dir.name,
        "results_root":  str(results_root),
        "task":          task,
        "n_instances":   n,
        "n_ok":          len(ok),
        "n_points":      args.n_points,
        "ref_view":      args.ref_view,
        "encoder_3d":    "Uni3D-Giant",
        "encoder_clip":  "EVA02-E-14-plus_laion2b_s9b_b144k",
        "cos_3d_3d":    agg("cos_3d_3d"),
        "cos_text_3d":  agg("cos_text_3d"),
        "cos_image_3d": agg("cos_image_3d"),
        "per_instance": per_instance,
    }
    out_dir = model_dir / "_metrics"
    out_dir.mkdir(exist_ok=True)
    out_path = out_dir / "shape_uni3d.json"
    out_path.write_text(json.dumps(summary, indent=2))

    def fmt(s, k="conditional_mean"):
        v = s[k]
        return f"{v:.4f}" if isinstance(v, float) else "  --  "
    print(f"  3d-3d   cond={fmt(summary['cos_3d_3d']):>9}  "
          f"pen={fmt(summary['cos_3d_3d'],'penalized_mean'):>9}  "
          f"text-3d cond={fmt(summary['cos_text_3d']):>9}  "
          f"image-3d cond={fmt(summary['cos_image_3d']):>9}")
    return summary


def main():
    args = parse_args()

    # Build target list
    if args.targets:
        target_dirs = expand_targets(args.targets)
        if not target_dirs:
            raise SystemExit("--targets matched no directories.")
    elif args.model and args.results_root:
        d = args.results_root / args.model
        if not d.exists(): raise SystemExit(f"No such dir: {d}")
        target_dirs = [d]
    else:
        raise SystemExit("Use either --targets <dirs...> or --model + --results-root.")

    # Filter already-done in batch mode
    if not args.overwrite:
        before = len(target_dirs)
        target_dirs = [d for d in target_dirs
                       if not (d / "_metrics" / "shape_uni3d.json").exists()]
        if len(target_dirs) < before:
            print(f"Skipping {before - len(target_dirs)} dirs that already "
                  f"have shape_uni3d.json (use --overwrite to redo).")
    if not target_dirs:
        print("Nothing to do.")
        return

    print(f"Will process {len(target_dirs)} dir(s).")
    for d in target_dirs[:10]:
        print(f"  {d}")
    if len(target_dirs) > 10:
        print(f"  ... and {len(target_dirs) - 10} more")

    device = torch.device(args.device)
    print("\nLoading Uni3D-Giant…")
    t0 = time.time()
    uni3d = load_uni3d_giant(device, dtype=torch.float32)
    print(f"  loaded in {time.time()-t0:.0f}s")

    clip_model = clip_tokenizer = clip_preprocess = None
    if not args.no_clip:
        print("Loading EVA02-E-14-plus CLIP…")
        t0 = time.time()
        clip_model, clip_tokenizer, clip_preprocess = load_clip(
            device, dtype=torch.float16)
        print(f"  loaded in {time.time()-t0:.0f}s")

    encoders = dict(uni3d=uni3d,
                    clip_model=clip_model,
                    clip_tokenizer=clip_tokenizer,
                    clip_preprocess=clip_preprocess,
                    device=device)

    rng = np.random.default_rng(args.seed)
    t_batch = time.time()
    for k, d in enumerate(target_dirs):
        try:
            process_dir(d, args.task, args, encoders, rng)
        except Exception as e:
            print(f"  [{d}] FAILED: {type(e).__name__}: {e}")
        print(f"  ({k+1}/{len(target_dirs)} dirs done, "
              f"batch elapsed {time.time()-t_batch:.0f}s)")
    print(f"\nAll done in {time.time()-t_batch:.0f}s.")


if __name__ == "__main__":
    main()
