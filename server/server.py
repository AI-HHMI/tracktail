#!/usr/bin/env python3
"""
FastAPI inference server for TrackerEncoder.

Start with the default Hugging Face model, a Hugging Face repository, a wandb run
directory, or explicit config/checkpoint paths:

    python server/server.py
    python server/server.py --hf-repo ai-hhmi/posetail-static --revision 2026-08-24
    python server/server.py --wandb /path/to/wandb/run-YYYYMMDD_HHMMSS-XXXXXXXX
    python server/server.py --config files/config.toml --checkpoint files/checkpoints/checkpoint_00010000.pth
"""

import argparse
import asyncio
import io
import json
import os
import sys
from contextlib import asynccontextmanager

import cv2
import numpy as np
import torch
from fastapi import FastAPI, File, Form, HTTPException, UploadFile
from fastapi.responses import Response

sys.path.insert(0, os.path.dirname(os.path.dirname(os.path.abspath(__file__))))

from posetail.inference.inference_utils import (load_model_from_base_folder,
                             load_model_from_hub, resize_camera_group,
                             resolve_config_and_checkpoint)
from posetail.posetail.scorer_encoder import ScorerEncoder
from posetail.posetail.tracker_encoder import TrackerEncoder
from posetail.posetail.train_utils import load_checkpoint, load_config, _warn_unfilled_video_encoder

_gpu_lock = asyncio.Lock()
DEFAULT_HF_REPO = 'ai-hhmi/posetail-static-animal'


def load_scorer_model(*, wandb=None, config=None, checkpoint=None,
                      checkpoint_number=None, device=None):
    """Build a ScorerEncoder from config.scorer + config.model and load its checkpoint.

    The scorer can't go through load_checkpoint's auto-instantiation (that only builds
    tracker variants), so we construct it manually — mirroring scripts/score_ratcity_tracklets.py.
    """
    if wandb:
        config_path, checkpoint_path = resolve_config_and_checkpoint(
            wandb, checkpoint=checkpoint_number)
    else:
        config_path, checkpoint_path = config, checkpoint

    cfg = load_config(config_path)
    if device is None:
        device = cfg.devices.device if torch.cuda.is_available() else 'cpu'

    if 'scorer' not in cfg:
        raise RuntimeError(
            f'Scorer config {config_path} has no [scorer] table — is this a tracker config?'
        )
    sk = dict(cfg.scorer)
    # load_checkpoint below always loads a full model_state right after construction, so the
    # public VJEPA2 download would be discarded.
    model = ScorerEncoder(
        pool_num_heads=sk.get('pool_num_heads', 8),
        score_hidden=sk.get('score_hidden', 64),
        use_precision=sk.get('use_precision', True),
        **{**cfg.model, 'video_encoder_pretrained': False},
    )
    model.to(device)
    checkpoint_dict = load_checkpoint(config_path, checkpoint_path, model=model, device=device)
    model = checkpoint_dict['model']
    # load_checkpoint was passed an already-built model, so its own built_here guard is a
    # no-op; check video-encoder coverage explicitly using the keys it returns.
    _warn_unfilled_video_encoder(checkpoint_dict.get('missing_keys', []),
                                 checkpoint_dict.get('dropped_keys', []))
    if not isinstance(model, ScorerEncoder):
        raise RuntimeError(f'Scorer must be a ScorerEncoder, got {type(model).__name__}')
    model.eval()
    return model, config_path, checkpoint_path


@asynccontextmanager
async def lifespan(app: FastAPI):
    args = getattr(app.state, 'cli_args', None)
    if args is None:
        raise RuntimeError(
            'Server must be started via `python server/server.py ...`, not directly via uvicorn.'
        )

    device_arg = args.device  # string or None

    if args.hf_repo:
        model, config = load_model_from_hub(
            args.hf_repo,
            revision=args.revision,
            device=device_arg,
        )
        revision_label = args.revision or 'main'
        config_path = f'hf://{args.hf_repo}/config.toml@{revision_label}'
        checkpoint_path = f'hf://{args.hf_repo}/model.pth@{revision_label}'
    elif args.wandb:
        model, config, config_path, checkpoint_path = load_model_from_base_folder(
            args.wandb, checkpoint=args.checkpoint_number, device=device_arg
        )
    else:
        config = load_config(args.config)
        if device_arg is None:
            device_arg = config.devices.device if torch.cuda.is_available() else 'cpu'
        checkpoint_dict = load_checkpoint(
            config_path=args.config,
            checkpoint_path=args.checkpoint,
            device=device_arg,
        )
        model = checkpoint_dict['model']
        if not isinstance(model, TrackerEncoder):
            raise RuntimeError(
                f'Loaded model must be a TrackerEncoder, got {type(model).__name__}'
            )
        model.eval()
        config_path = args.config
        checkpoint_path = args.checkpoint

    device = next(model.parameters()).device

    app.state.model = model
    app.state.device = device
    app.state.config_path = str(config_path)
    app.state.checkpoint_path = str(checkpoint_path)
    app.state.model_source = (
        f'huggingface:{args.hf_repo}' if args.hf_repo
        else f'wandb:{args.wandb}' if args.wandb
        else 'local'
    )
    app.state.model_revision = args.revision if args.hf_repo else None
    app.state.n_frames = model.n_frames
    app.state.image_size = model.image_size
    app.state.mode_3d = config.model.get('mode_3d', 'encoder')

    print(
        f'Model loaded | n_frames={model.n_frames} | image_size={model.image_size} | device={device}'
    )

    # Optional scorer model — enables /score when scorer args are provided.
    app.state.scorer = None
    app.state.scorer_config_path = None
    app.state.scorer_checkpoint_path = None
    if args.scorer_wandb or args.scorer_config:
        scorer, scorer_cfg, scorer_ckpt = load_scorer_model(
            wandb=args.scorer_wandb, config=args.scorer_config,
            checkpoint=args.scorer_checkpoint,
            checkpoint_number=args.scorer_checkpoint_number,
            device=str(device),  # pin to the tracker's device
        )
        app.state.scorer = scorer
        app.state.scorer_config_path = str(scorer_cfg)
        app.state.scorer_checkpoint_path = str(scorer_ckpt)
        print(f'Scorer loaded | device={next(scorer.parameters()).device}')

    yield


app = FastAPI(title='TrackerEncoder Server', lifespan=lifespan)


@app.get('/info')
async def info():
    return {
        'n_frames': app.state.n_frames,
        'image_size': app.state.image_size,
        'device': str(app.state.device),
        'config_path': app.state.config_path,
        'checkpoint_path': app.state.checkpoint_path,
        'model_source': app.state.model_source,
        'model_revision': app.state.model_revision,
        'mode_3d': app.state.mode_3d,
        'scorer_loaded': app.state.scorer is not None,
        'scorer_config_path': app.state.scorer_config_path,
        'scorer_checkpoint_path': app.state.scorer_checkpoint_path,
    }


async def _parse_scene_request(meta, images, device, n_frames, image_size):
    """Decode uploaded images, build+resize the camera_group, and build per-camera view
    tensors. Shared by /predict and /score (coords parsing differs, so it stays in the
    handlers). Returns (camera_group, views, scales) where scales are the per-camera
    resize factors (only /predict uses them, to un-scale 2d_pred)."""
    cameras_meta = meta['cameras']

    # Decode and group images by camera name
    cam_frames: dict[str, dict[int, np.ndarray]] = {}
    for upload in images:
        fname = upload.filename or ''
        stem = os.path.splitext(fname)[0]
        parts = stem.split('__', 1)
        if len(parts) != 2:
            raise HTTPException(
                400,
                detail=f'Image filename must be <cam_name>__<frame_idx>.<ext>, got: {fname}',
            )
        cam_name, frame_str = parts
        try:
            frame_idx = int(frame_str)
        except ValueError:
            raise HTTPException(400, detail=f'Frame index must be an integer, got: {frame_str}')

        data = await upload.read()
        arr = np.frombuffer(data, dtype=np.uint8)
        img = cv2.imdecode(arr, cv2.IMREAD_COLOR)
        if img is None:
            raise HTTPException(400, detail=f'Failed to decode image: {fname}')
        img = cv2.cvtColor(img, cv2.COLOR_BGR2RGB)

        cam_frames.setdefault(cam_name, {})[frame_idx] = img

    # Build camera group dicts first (needed to compute resize scales before loading views).
    # Image size is read from the actual decoded frames — client need not send 'size'.
    camera_group = []
    for cam_info in cameras_meta:
        cam_name = cam_info['name']
        if cam_name not in cam_frames:
            raise HTTPException(400, detail=f'No images uploaded for camera: {cam_name}')
        first_frame = next(iter(cam_frames[cam_name].values()))
        H, W = first_frame.shape[:2]
        size = torch.tensor([W, H], dtype=torch.int32, device=device)
        ext = torch.tensor(cam_info['ext'], dtype=torch.float32, device=device)
        mat = torch.tensor(cam_info['mat'], dtype=torch.float32, device=device)
        dist = torch.tensor(cam_info['dist'], dtype=torch.float32, device=device)
        offset = torch.tensor(
            cam_info.get('offset', [0.0, 0.0]), dtype=torch.float32, device=device
        )
        ext_inv = torch.linalg.inv(ext)
        R = ext[:3, :3]
        t = ext[:3, 3]
        center = -R.T @ t
        camera_group.append({
            'name': cam_name,
            'type': cam_info.get('type', 'pinhole'),
            'mat': mat,
            'dist': dist,
            'ext': ext,
            'size': size,
            'offset': offset,
            'ext_inv': ext_inv,
            'center': center,
        })

    # Record per-camera scale factors before resize so we can un-scale 2d_pred later
    scales = [float(image_size) / max(cam['size'].tolist()) for cam in camera_group]

    # Scale so max(H,W) == image_size, matching PosetailDataset / inference_video
    camera_group = resize_camera_group(camera_group, image_size)

    # Build per-camera view tensors, resizing frames to the scaled camera size
    views = []
    for cam_idx, cam_info in enumerate(cameras_meta):
        cam_name = cam_info['name']
        frame_dict = cam_frames[cam_name]
        if len(frame_dict) != n_frames:
            raise HTTPException(
                400,
                detail=f'Camera {cam_name}: expected {n_frames} frames, got {len(frame_dict)}',
            )
        target_wh = tuple(camera_group[cam_idx]['size'].tolist())  # (W, H) for cv2.resize
        frames = np.stack(
            [cv2.resize(frame_dict[i], target_wh) for i in sorted(frame_dict)], axis=0
        )  # (T, H, W, 3)
        view_tensor = (
            torch.from_numpy(frames).unsqueeze(0).to(device=device, dtype=torch.float32) / 255.0
        )
        views.append(view_tensor)

    return camera_group, views, scales


def _npz_response(result: dict, filename: str) -> Response:
    """Serialize a dict of numpy arrays to an .npz download response."""
    buf = io.BytesIO()
    np.savez(buf, **result)
    buf.seek(0)
    return Response(
        content=buf.read(),
        media_type='application/octet-stream',
        headers={'Content-Disposition': f'attachment; filename="{filename}"'},
    )


@app.post('/predict')
async def predict(
    metadata: str = Form(...),
    images: list[UploadFile] = File(...),
):
    try:
        meta = json.loads(metadata)
    except json.JSONDecodeError as e:
        raise HTTPException(400, detail=f'Invalid metadata JSON: {e}')

    if 'cameras' not in meta:
        raise HTTPException(400, detail='metadata must include "cameras"')
    if 'coords' not in meta:
        raise HTTPException(400, detail='metadata must include "coords"')

    coords_list = meta['coords']
    query_times_list = meta.get('query_times', None)

    model = app.state.model
    device = app.state.device
    n_frames = app.state.n_frames
    image_size = app.state.image_size

    if query_times_list is not None and len(query_times_list) != len(coords_list):
        raise HTTPException(
            400,
            detail=(
                f'query_times length {len(query_times_list)} != '
                f'coords length {len(coords_list)}'
            ),
        )

    camera_group, views, scales = await _parse_scene_request(
        meta, images, device, n_frames, image_size)

    coords = torch.tensor(coords_list, dtype=torch.float32, device=device).unsqueeze(0)
    query_times = None
    if query_times_list is not None:
        query_times = torch.tensor(
            query_times_list, dtype=torch.int32, device=device
        ).unsqueeze(0)

    async with _gpu_lock:
        with torch.no_grad():
            outputs = model(
                views=views,
                coords=coords,
                camera_group=camera_group,
                query_times=query_times,
            )

    # Un-scale 2d_pred from resized coords back to the client's sent-image resolution.
    # All other output keys are in 3D world space and are unaffected by image resize.
    if outputs.get('2d_pred') is not None:
        scale_t = torch.tensor(scales, device=device).view(-1, 1, 1, 1, 1)
        outputs['2d_pred'] = outputs['2d_pred'] / scale_t

    result = {}
    for key, val in outputs.items():
        if val is None:
            continue
        result[key] = val.cpu().numpy() if isinstance(val, torch.Tensor) else np.asarray(val)

    return _npz_response(result, 'predictions.npz')


@app.post('/score')
async def score(
    metadata: str = Form(...),
    images: list[UploadFile] = File(...),
):
    if app.state.scorer is None:
        raise HTTPException(
            404,
            detail='No scorer model loaded (start the server with --scorer-wandb or --scorer-config)',
        )

    try:
        meta = json.loads(metadata)
    except json.JSONDecodeError as e:
        raise HTTPException(400, detail=f'Invalid metadata JSON: {e}')

    if 'cameras' not in meta:
        raise HTTPException(400, detail='metadata must include "cameras"')
    if 'coords' not in meta:
        raise HTTPException(400, detail='metadata must include "coords"')

    scorer = app.state.scorer
    device = app.state.device
    n_frames = app.state.n_frames
    image_size = app.state.image_size

    # Scorer coords are a FULL-SEQUENCE trajectory [T, K, 3] (not query points [N, 3]).
    coords_arr = np.asarray(meta['coords'], dtype=np.float32)
    if coords_arr.ndim != 3 or coords_arr.shape[-1] != 3:
        raise HTTPException(
            400,
            detail=f'/score coords must be a full-sequence trajectory [T, K, 3], got shape {list(coords_arr.shape)}',
        )
    if coords_arr.shape[0] != n_frames:
        raise HTTPException(
            400,
            detail=f'/score expects T={n_frames} frames, got {coords_arr.shape[0]}',
        )

    camera_group, views, _scales = await _parse_scene_request(
        meta, images, device, n_frames, image_size)

    coords_full = torch.from_numpy(coords_arr).to(device).unsqueeze(0)  # [1, T, K, 3]

    async with _gpu_lock:
        with torch.no_grad():
            scores, precision = scorer(
                views=views,
                coords=coords_full,
                camera_group=camera_group,
            )

    result = {
        'scores': scores.cpu().numpy(),
        'precision': precision.cpu().numpy(),
    }
    return _npz_response(result, 'scores.npz')


def parse_args():
    parser = argparse.ArgumentParser(description='TrackerEncoder inference server')
    group = parser.add_mutually_exclusive_group(required=False)
    group.add_argument(
        '--hf-repo', type=str,
        help=f'Hugging Face model repository (default: {DEFAULT_HF_REPO})',
    )
    group.add_argument(
        '--wandb', type=str,
        help='Path to a wandb run directory (same as --base-folder in inference_video.py)',
    )
    group.add_argument(
        '--config', type=str,
        help='Path to config.toml (requires --checkpoint)',
    )
    parser.add_argument(
        '--revision', type=str, default=None,
        help='Hugging Face branch, commit, or date tag (only with --hf-repo; default: latest)',
    )
    parser.add_argument('--checkpoint', type=str,
                        help='Path to checkpoint .pth (required with --config)')
    parser.add_argument(
        '--checkpoint-number', type=int, default=None,
        help='Checkpoint number to load (only with --wandb; default: latest)',
    )
    parser.add_argument('--host', type=str, default='0.0.0.0')
    parser.add_argument('--port', type=int, default=8000)
    parser.add_argument(
        '--device', type=str, default=None,
        help='Device string, e.g. cuda:0 (default: from config, or cpu if CUDA unavailable)',
    )
    # Optional scorer model — enables the /score endpoint.
    parser.add_argument(
        '--scorer-wandb', type=str, default=None,
        help='wandb run dir for a ScorerEncoder (enables /score)',
    )
    parser.add_argument(
        '--scorer-config', type=str, default=None,
        help='config.toml for the scorer (requires --scorer-checkpoint)',
    )
    parser.add_argument('--scorer-checkpoint', type=str, default=None,
                        help='Scorer checkpoint .pth (required with --scorer-config)')
    parser.add_argument(
        '--scorer-checkpoint-number', type=int, default=None,
        help='Scorer checkpoint number to load (only with --scorer-wandb; default: latest)',
    )
    args = parser.parse_args()
    if args.config and not args.checkpoint:
        parser.error('--checkpoint is required when using --config')
    if args.checkpoint and not args.config:
        parser.error('--config is required when using --checkpoint')
    if args.revision and not args.hf_repo:
        parser.error('--revision is only valid with --hf-repo')
    if args.checkpoint_number is not None and not args.wandb:
        parser.error('--checkpoint-number is only valid with --wandb')
    if not args.hf_repo and not args.wandb and not args.config:
        args.hf_repo = DEFAULT_HF_REPO
    if args.scorer_config and not args.scorer_checkpoint:
        parser.error('--scorer-checkpoint is required when using --scorer-config')
    if args.scorer_checkpoint and not args.scorer_config:
        parser.error('--scorer-config is required when using --scorer-checkpoint')
    if args.scorer_wandb and args.scorer_config:
        parser.error('use either --scorer-wandb or --scorer-config, not both')
    if args.scorer_checkpoint_number is not None and not args.scorer_wandb:
        parser.error('--scorer-checkpoint-number is only valid with --scorer-wandb')
    return args


if __name__ == '__main__':
    import uvicorn

    args = parse_args()
    app.state.cli_args = args
    uvicorn.run(app, host=args.host, port=args.port)
