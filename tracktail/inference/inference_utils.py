import os
import cv2
import glob
import json
import yaml

import torch

import numpy as np
from tqdm import tqdm
from easydict import EasyDict

from collections import defaultdict

from decord import VideoReader, cpu
from aniposelib.cameras import CameraGroup, Camera

from tracktail.datasets.utils import get_dirs, disassemble_extrinsics
from tracktail.model.cube import project_points_torch
from tracktail.model.tracker_encoder import TrackerEncoder
from tracktail.model.train_utils import *
from tracktail.model.train_utils import _warn_unfilled_video_encoder



def get_checkpoint(wandb_prefix, run_id, checkpoint = None):

    if checkpoint is not None: 
        checkpoint_fmt = str(checkpoint).zfill(8)
        checkpoint_path = os.path.join(
            wandb_prefix, run_id, 'files', 'checkpoints', 
            f'checkpoint_{checkpoint_fmt}.pth')
        
    else:
        checkpoints = sorted(glob.glob(
            os.path.join(wandb_prefix, run_id, 'files', 'checkpoints', '*.pth')))
        checkpoint_path = checkpoints[-1]

    return checkpoint_path


def load_predictions(data_path, device):

    data = np.load(data_path) 

    coords_pred = torch.from_numpy(data['coords_pred']).to(device)
    vis_pred = torch.from_numpy(data['vis_pred']).to(device)
    conf_pred = torch.from_numpy(data['conf_pred']).to(device)

    coords_true = torch.from_numpy(data['coords_true']).to(device)
    vis_true = torch.from_numpy(data['vis_true']).to(device)

    fnums = torch.from_numpy(data['fnums']).to(device)
    video_path = ''.join(data['video_path'])

    return coords_pred, vis_pred, conf_pred, coords_true, vis_true, fnums, video_path


def combine_predictions(prefix): 

    # traverse results for a particular dataset
    for session in get_dirs(prefix): 

        session_path = os.path.join(prefix, session)

        for trial in get_dirs(session_path): 

            trial_path = os.path.join(session_path, trial)

            # skip if there are no npz prediction files
            prediction_paths = sorted(glob.glob(os.path.join(trial_path, 'predictions', 'predictions_*.npz')))
            if len(prediction_paths) == 0:
                print(f'skipping... no prediction paths found at {trial_path}')
                continue

            data = [np.load(p) for p in prediction_paths] 

            # extract metadata 
            keys_to_exclude = ['coords_pred', 'vis_pred', 'conf_pred',
                               'coords_true', 'vis_true', 'fnums']

            sample_info = {k: data[0][k] for k in data[0].keys() if k not in keys_to_exclude}

            # combine predictions from each consecutive time period
            coords_pred = np.concatenate([d['coords_pred'] for d in data], axis = 0)

            vis_pred = np.concatenate([d['vis_pred'] for d in data], axis = 0)
            conf_pred = np.concatenate([d['conf_pred']for d in data], axis = 0)
            coords_true = np.concatenate([d['coords_true'] for d in data], axis = 0)
            vis_true = np.concatenate([d['vis_true'] for d in data], axis = 0)
            fnums = np.concatenate([d['fnums'] for d in data], axis = 0)

            results = {
                'coords_pred': coords_pred, 
                'vis_pred': vis_pred, 
                'conf_pred': conf_pred,
                'coords_true': coords_true,
                'vis_true': vis_true,
                'fnums': fnums, 
            }

            results.update(sample_info)

            # save combined data 
            predictions_fname = os.path.join(prefix, session, trial, f'predictions.npz')
            np.savez(predictions_fname, **results)
            print(f'predictions saved to {predictions_fname}')


def predict_on_dataset_3d(model, dataloader, outpath, device, 
                          max_kpts = 1000, debug_ix = None):

    torch.set_float32_matmul_precision('high')
    model.eval()

    for j, batch in enumerate(dataloader):

        if debug_ix and j == debug_ix: 
            break

        views = [view.to(device) for view in batch.views]
        coords = batch.coords.to(device)
        vis = batch.vis
        fnums = batch.fnums.cpu().numpy()
        cgroup = batch.cgroup 
        sample_info = batch.sample_info
        
        # fallback if visibilities are not provided
        if vis is None: 
            vis = get_vis_true(coords)

        if cgroup: 
            cgroup = [dict_to_device(cam_dict, device) for cam_dict in cgroup]
        
        # can do multiple passes if there are a lot of keypoints to predict 
        # (helps reduce memory)
        n_passes = np.ceil(coords.shape[2] / max_kpts).astype(int)
        coords_pred = []
        vis_pred = []
        conf_pred = []
        coords_true = []
        vis_true = []

        for i in range(n_passes): 

            coords_subset = coords[:, :, i * max_kpts : i * max_kpts + max_kpts, :]
            vis_subset = vis[:, :, i * max_kpts : i * max_kpts + max_kpts, :]

             # mask NaNs, don't want to pass in coords that are NaN in the first frame
            coords_first = coords_subset[:, 0, :, :]  # B, N, R
            valid_mask = ~torch.isnan(coords_first).any(dim = -1)  # B, N
            coords_valid = coords_first[:, valid_mask[0], :]  # B, n, R

            # get model predictions given coords in the first frame
            with torch.no_grad():

                outputs = model(
                    views = views, 
                    coords = coords_valid, 
                    camera_group = cgroup
                )

                # populate valid predictions in side of coords
                B, S, N, R = coords_subset.shape
                output_coords_valid = torch.full((B, S, N, R), float('nan'),
                    device = coords_subset.device, dtype = coords_subset.dtype)
                output_vis_valid = torch.full((B, S, N, 1), float('nan'), 
                    device = coords_subset.device, dtype = coords_subset.dtype)
                output_conf_valid = torch.full((B, S, N, 1), float('nan'),
                    device = coords_subset.device, dtype = coords_subset.dtype)

                output_coords_valid[:, :, valid_mask[0], :] = outputs['coords_pred']
                output_vis_valid[:, :, valid_mask[0], :] = outputs['vis_pred']
                output_conf_valid[:, :, valid_mask[0], :] = outputs['conf_pred']

                print('true', coords_subset[:, :, 0, :])
                print('pred', outputs['coords_pred'][:, :, 0, :])

                coords_pred.append(torch.squeeze(outputs['coords_pred'], dim = 0).cpu().numpy())
                vis_pred.append(torch.squeeze(outputs['vis_pred'], dim = 0).cpu().numpy())
                conf_pred.append(torch.squeeze(outputs['conf_pred'], dim = 0).cpu().numpy())
                coords_true.append(torch.squeeze(coords_subset, dim = 0).cpu().numpy())
                vis_true.append(torch.squeeze(vis_subset, dim = 0).cpu().numpy())

        results = {
            'coords_pred': np.concatenate(coords_pred, axis = 1), 
            'vis_pred': np.concatenate(vis_pred, axis = 1), 
            'conf_pred': np.concatenate(conf_pred, axis = 1),
            'coords_true': np.concatenate(coords_true, axis = 1),
            'vis_true': np.concatenate(vis_true, axis = 1),
        }
        results.update({'fnums': fnums})

        keys_to_exclude = ['fnums']
        if sample_info.subject_ids is not None: 
            results.update({'subject_ids': sample_info.subject_ids})
        else: 
            keys_to_exclude.append('subject_ids')

        results.update({k: sample_info[k] for k in sample_info.keys() if k not in keys_to_exclude})

        # save predictions
        start_ix = str(results['start_ix']).zfill(8)
        predictions_outpath = os.path.join(
            outpath, results['session'], results['trial'], 'predictions')
        os.makedirs(predictions_outpath, exist_ok = True)
        predictions_fname = os.path.join(predictions_outpath, f'predictions_{start_ix}.npz')
        np.savez(predictions_fname, **results)
        print(f'predictions saved to {predictions_fname}')

    return outpath


def generate_video_2d(video_path, results_path, outpath, run_id, scale, device): 
    # NOTE: deprecated for now
    # TODO: get camera group and project coords
    (coords_pred, vis_pred, conf_pred, coords_true, 
    vis_true, fnums, video_path) = load_predictions(results_path, device)

    coords_true = coords_true.cpu().numpy().astype(int)
    coords_true[..., 0] = coords_true[..., 0] * scale[0]
    coords_true[..., 1] = coords_true[..., 1] * scale[1]

    coords_pred = coords_pred.cpu().numpy().astype(int)
    coords_pred[..., 0] = coords_pred[..., 0] * scale[0]
    coords_pred[..., 1] = coords_pred[..., 1] * scale[1]

    cap = cv2.VideoCapture(video_path)
    frame_width = int(cap.get(cv2.CAP_PROP_FRAME_WIDTH))
    frame_height = int(cap.get(cv2.CAP_PROP_FRAME_HEIGHT))
    fps = 30.0 # cap.get(cv2.CAP_PROP_FPS)

    fourcc = cv2.VideoWriter_fourcc(*'mp4v')
    runid = run_id.split('-')[-1]
    video_name = os.path.splitext(os.path.basename(video_path))[0]
    video_outpath = os.path.join(outpath, f'{video_name}_{runid}.mp4')
    out = cv2.VideoWriter(video_outpath, fourcc, fps, (frame_width, frame_height))

    i = 0
    j = 0
    ret = True

    while ret:

        ret, frame = cap.read() 

        if not ret: 
            break
        
        if i not in fnums:
            out.write(frame)

        else:
            for coord_true, coord_pred in zip(coords_true[j], coords_pred[j]):
                cv2.circle(frame, tuple(coord_true), 5, (0, 255, 0), -1)
                cv2.circle(frame, tuple(coord_pred), 5, (0, 0, 255), -1)

            out.write(frame)
            j += 1

        i += 1

    cap.release()
    out.release()

    return video_outpath


# ---------------------------------------------------------------------------
# Video / multi-view inference library (moved from the inference_video.py CLI)
# ---------------------------------------------------------------------------

class ImageFolderReader:
    """Mimics the VideoReader interface but reads from a folder of images."""

    def __init__(self, folder_path):
        self.folder_path = folder_path
        extensions = {'.jpg', '.jpeg', '.png', '.bmp', '.tif', '.tiff'}
        self.filenames = sorted([
            f for f in os.listdir(folder_path)
            if os.path.splitext(f)[1].lower() in extensions
        ])
        if len(self.filenames) == 0:
            raise FileNotFoundError(f'No images found in {folder_path}')

    def __len__(self):
        return len(self.filenames)

    def get_batch(self, frame_ids):
        imgs = []
        for idx in frame_ids:
            path = os.path.join(self.folder_path, self.filenames[idx])
            img = cv2.imread(path)
            if img is None:
                raise IOError(f'Failed to read image: {path}')
            img = cv2.cvtColor(img, cv2.COLOR_BGR2RGB)
            imgs.append(img)
        return np.stack(imgs, axis=0)

    def __getitem__(self, key):
        if isinstance(key, slice):
            indices = range(*key.indices(len(self.filenames)))
            return self.get_batch(list(indices))
        elif isinstance(key, int):
            return self.get_batch([key])[0]
        else:
            raise TypeError(f'Invalid key type: {type(key)}')


def build_video_readers(video_paths):
    readers = []
    for video_path in video_paths:
        if os.path.isdir(video_path):
            readers.append(ImageFolderReader(video_path))
        else:
            readers.append(VideoReader(video_path, ctx=cpu(0)))
    lengths = [len(reader) for reader in readers]
    return readers, lengths


def camera_group_to_device(camera_group, device):
    return [dict_to_device(cam_dict, device) for cam_dict in camera_group]


def crop_frames_with_padding(frames, x1, y1, x2, y2, pad_value=0):
    """Crop frames[..., y1:y2, x1:x2] with zero-padding for out-of-frame regions.

    Unlike a raw numpy slice (which wraps for negative coords and truncates for
    coords past the edge), this returns exactly a (x2-x1) x (y2-y1) crop with any
    off-frame area filled with ``pad_value``, so the pixels stay aligned with the
    camera geometry that assumes the crop spans [x1,x2) x [y1,y2).

    ``frames`` is (..., H, W, C); x/y are ints that may fall outside [0, W)/[0, H).
    """
    *lead, H, W, C = frames.shape
    out = np.full((*lead, y2 - y1, x2 - x1, C), pad_value, dtype=frames.dtype)
    sx1, sy1 = max(x1, 0), max(y1, 0)
    sx2, sy2 = min(x2, W), min(y2, H)
    if sx2 > sx1 and sy2 > sy1:
        out[..., sy1 - y1:sy2 - y1, sx1 - x1:sx2 - x1, :] = frames[..., sy1:sy2, sx1:sx2, :]
    return out


def load_multiview_clip(readers, start_frame, n_frames, crop_boxes=None, target_sizes=None):
    max_available = min(len(reader) for reader in readers)
    end_frame = min(start_frame + n_frames, max_available)

    if end_frame <= start_frame:
        raise ValueError(f'No synchronized frames available for start_frame={start_frame}')

    views = []

    for cam_idx, reader in enumerate(readers):
        frames = reader[start_frame:end_frame]
        if hasattr(frames, 'asnumpy'):
            frames = frames.asnumpy()

        if crop_boxes is not None:
            x1, y1, x2, y2 = crop_boxes[cam_idx].cpu().to(torch.int32).tolist()
            frames = crop_frames_with_padding(frames, x1, y1, x2, y2)

        if target_sizes is not None:
            target_size_cam = target_sizes[cam_idx]
            resized = [cv2.resize(frame, target_size_cam) for frame in frames]
            frames = np.stack(resized, axis=0)

        views.append(torch.from_numpy(frames))

    return views, end_frame - start_frame


def crop_camera_group_to_queries(camera_group, query_coords, min_crop_dim, padding=20, is_2d=False):
    if is_2d:
        # 2D queries are already pixel coords in the (single) camera frame; no
        # projection. Shape to (cams=1, ..., 2) so the cropping math below matches.
        p2d = query_coords.reshape(1, -1, 2)
    else:
        p2d = project_points_torch(camera_group, query_coords)
    crops = []

    for cnum in range(p2d.shape[0]):
        size = camera_group[cnum]['size']
        pflat = p2d[cnum].reshape(-1, 2)
        good = torch.all(torch.isfinite(pflat), dim=1)
        pflat = pflat[good]

        if pflat.shape[0] == 0:
            low = torch.tensor([0, 0], dtype=torch.int32, device=size.device)
            high = size.to(torch.int32)
        else:
            low = torch.clamp(
                torch.min(pflat, dim=0).values - padding,
                torch.tensor([0, 0], device=pflat.device),
                size.to(pflat.device),
            ).to(torch.int32)
            high = torch.clamp(
                torch.max(pflat, dim=0).values + padding,
                torch.tensor([0, 0], device=pflat.device),
                size.to(pflat.device),
            ).to(torch.int32)

            current_width = high[0] - low[0]
            current_height = high[1] - low[1]

            # Cap each axis at the image dimension so the crop never exceeds the
            # frame (matches tracktail_dataset.crop_cgroup_to_points). Without the
            # per-axis cap, a wide bbox forces min_dim > frame height, and
            # `low = high - min_dim` yields a negative offset -> load_multiview_clip's
            # numpy slice wraps instead of padding, breaking the 2D<->3D geometry.
            base = max(min_crop_dim, int(current_width), int(current_height))
            min_dim_x = min(base, int(size[0]))
            min_dim_y = min(base, int(size[1]))

            if current_width < min_dim_x:
                center_x = (low[0] + high[0]) // 2
                low[0] = torch.clamp(center_x - min_dim_x // 2, 0, size[0] - min_dim_x)
                high[0] = low[0] + min_dim_x

            if current_height < min_dim_y:
                center_y = (low[1] + high[1]) // 2
                low[1] = torch.clamp(center_y - min_dim_y // 2, 0, size[1] - min_dim_y)
                high[1] = low[1] + min_dim_y

        crops.append(torch.cat([low, high]))

    camera_group_cropped = []
    for cnum in range(len(camera_group)):
        x1, y1, x2, y2 = crops[cnum]
        cam = dict(camera_group[cnum])
        cam['offset'] = cam['offset'] + torch.tensor(
            [x1, y1],
            dtype=torch.int32,
            device=cam['offset'].device,
        )
        cam['size'] = torch.tensor(
            [x2 - x1, y2 - y1],
            dtype=torch.int32,
            device=cam['size'].device,
        )
        camera_group_cropped.append(cam)

    return camera_group_cropped, crops


def resize_camera_group(camera_group, target_res):
    camera_group_scaled = []

    for cnum in range(len(camera_group)):
        cam = dict(camera_group[cnum])
        size = cam['size']
        scale = float(target_res) / max(size)
        cam['size'] = torch.round(size * scale).to(torch.int32)
        cam['mat'] = cam['mat'] * scale
        cam['mat'][2, 2] = 1

        if 'offset' in cam:
            # Keep offset float (matches tracktail_dataset.resize_camera_group).
            # Rounding to int here left a sub-pixel (<0.5px) mismatch against the
            # exact `mat * scale`, since project_cam does `mat @ X - offset`.
            cam['offset'] = cam['offset'] * scale

        camera_group_scaled.append(cam)

    return camera_group_scaled


def resolve_config_and_checkpoint(base_folder, checkpoint=None):
    checkpoint_dir = os.path.join(base_folder, 'files', 'checkpoints')

    if checkpoint is None:
        checkpoint_paths = sorted(glob.glob(os.path.join(checkpoint_dir, '*.pth')))
        if len(checkpoint_paths) == 0:
            raise FileNotFoundError(f'No checkpoints found in {checkpoint_dir}')
        checkpoint_path = checkpoint_paths[-1]
    else:
        checkpoint_name = f'checkpoint_{str(checkpoint).zfill(8)}.pth'
        checkpoint_path = os.path.join(checkpoint_dir, checkpoint_name)
        if not os.path.exists(checkpoint_path):
            raise FileNotFoundError(f'Checkpoint not found: {checkpoint_path}')

    config_path = os.path.join(base_folder, 'files', 'config.toml')
    if not os.path.exists(config_path):
        raise FileNotFoundError(f'Config not found: {config_path}')

    return config_path, checkpoint_path


def load_camera_group_from_metadata(metadata_path, device='cpu'):
    """Build a camera group from a trial's metadata.yaml.

    Honours `moving_cams: true` (per-frame extrinsics), mirroring what the TRAINING loader
    already does. Without this, a metadata file that says the rig moves trained one way and
    inferred another from the same file, with no diagnostic: format_camera_group's documented
    fallback ("cameras absent from the dict fall back to their static extrinsic") is right as a
    fallback and wrong as a default here, because EVERY camera falls back, the rig is treated as
    static, and the pose simply does not follow the subject -- which reads as a model problem.
    """
    with open(metadata_path, 'r') as f:
        cam_metadata = yaml.safe_load(f)

    offset_dict = cam_metadata.get('offset_dict', None)
    cam_type = cam_metadata.get('cam_type', 'pinhole')
    moving = cam_metadata.get('moving_cams', False)

    intrinsics_dict = cam_metadata['intrinsic_matrices']
    extrinsics_dict = cam_metadata['extrinsic_matrices']
    distortions_dict = cam_metadata['distortion_matrices']
    heights_dict = cam_metadata['camera_heights']
    widths_dict = cam_metadata['camera_widths']

    cam_names = list(intrinsics_dict.keys())
    if all(cam_name.isdigit() for cam_name in cam_names):
        cam_names = sorted(cam_names, key=int)
    else:
        cam_names = sorted(cam_names)

    # Per-frame extrinsics. Intrinsics/distortion are time-invariant, so the aniposelib Camera is
    # built from the frame-0 pose and the full (T,4,4) stack is passed via moving_ext.
    moving = bool(cam_metadata.get('moving_cams', False))
    moving_ext = {} if moving else None

    cams = []
    for cam_name in cam_names:
        mat_raw = intrinsics_dict[cam_name]
        dist_raw = distortions_dict[cam_name]

        if moving:
            ext_full = np.asarray(extrinsics_dict[cam_name], dtype=np.float64)  # (T,4,4)
            if ext_full.ndim != 3 or ext_full.shape[-2:] != (4, 4):
                # RAISE rather than degrade: silently using a static extrinsic for a rig the
                # metadata says is moving is exactly the failure this branch exists to prevent.
                raise ValueError(
                    f'{metadata_path}: moving_cams=true but extrinsics for {cam_name} have '
                    f'shape {tuple(ext_full.shape)} (expected (T,4,4)). Refusing to fall back '
                    f'to a static extrinsic, which would make the pose lag the subject with no '
                    f'diagnostic.')
            moving_ext[cam_name] = ext_full
            rvec, tvec = disassemble_extrinsics(ext_full[0])
            mat_arr = np.asarray(mat_raw, dtype=np.float64)
            mat_raw = mat_arr[0] if mat_arr.ndim == 3 else mat_arr
            dist_arr = np.asarray(dist_raw, dtype=np.float64)
            dist_raw = dist_arr[0] if dist_arr.ndim == 2 else dist_arr
        else:
            rvec, tvec = disassemble_extrinsics(extrinsics_dict[cam_name])

        cam = Camera(
            matrix=mat_raw,
            dist=dist_raw,
            rvec=rvec,
            tvec=tvec,
            name=cam_name,
        )

        width = widths_dict[cam_name]
        height = heights_dict[cam_name]
        cam.set_size((width, height))
        cams.append(cam)

    camera_group = CameraGroup(cams)
    camera_group = format_camera_group(camera_group, offset_dict, cam_type, device=device,
                                       moving_ext=moving_ext)

    return camera_group


def load_camera_group_2d(video_paths, metadata_path=None, device='cpu'):
    """Build a single-camera group for a 2D (uncalibrated) trial.

    Mirrors TracktailDataset._build_2d_cgroup:
      (1) fully-calibrated metadata.yaml -> real camera;
      (2) metadata.yaml with only camera_widths/heights -> nominal pinhole;
      (3) no usable metadata -> read one image to get the size -> nominal pinhole.
    """
    from tracktail.datasets.tracktail_dataset import _make_nominal_2d_camera

    cam_meta = None
    if metadata_path is not None and os.path.exists(metadata_path):
        with open(metadata_path, 'r') as f:
            cam_meta = yaml.safe_load(f)

    if cam_meta is not None and all(
            k in cam_meta for k in ('intrinsic_matrices', 'extrinsic_matrices',
                                    'distortion_matrices',
                                    'camera_heights', 'camera_widths')):
        # fully calibrated 2D metadata — use the real camera(s)
        return load_camera_group_from_metadata(metadata_path, device=device)

    if cam_meta is not None and 'camera_widths' in cam_meta and 'camera_heights' in cam_meta:
        widths, heights = cam_meta['camera_widths'], cam_meta['camera_heights']
        key = next(iter(widths))
        w, h = int(widths[key]), int(heights[key])
    else:
        # fall back to reading one image from the (single) camera folder
        cam_dir = video_paths[0]
        if os.path.isdir(cam_dir):
            sample = sorted(os.listdir(cam_dir))[0]
            from PIL import Image
            w, h = Image.open(os.path.join(cam_dir, sample)).size
        else:
            reader = VideoReader(cam_dir, ctx=cpu(0))
            frame = reader[0]
            if hasattr(frame, 'asnumpy'):
                frame = frame.asnumpy()
            h, w = frame.shape[:2]

    cgroup = _make_nominal_2d_camera(w, h)
    return camera_group_to_device(cgroup, device)


def load_model_from_base_folder(base_folder, checkpoint=None, device=None):
    config_path, checkpoint_path = resolve_config_and_checkpoint(base_folder, checkpoint=checkpoint)

    config = load_config(config_path)

    if device is None:
        device = torch.device(config.devices.device) if torch.cuda.is_available() else torch.device('cpu')

    checkpoint_dict = load_checkpoint(
        config_path=config_path,
        checkpoint_path=checkpoint_path,
        device=device,
    )

    model = checkpoint_dict['model']
    model.eval()

    return model, config, config_path, checkpoint_path


def load_model_from_hub(repo_id, device=None, revision=None, cache_dir=None):
    """Load a packaged TrackerEncoder from the Hugging Face Hub.

    Returns ``(model, config)`` where ``config.model`` contains the embedded model
    constructor configuration. The returned config intentionally has no dataset or
    training sections because a packaged inference checkpoint does not need them.

    Args:
        repo_id: Hugging Face repository ID, such as ``ai-hhmi/tracktail-static``.
        device: Device for the model. Defaults to CUDA when available.
        revision: Hub branch, commit, or date tag such as ``2026-10-12``.
        cache_dir: Optional Hugging Face cache directory.
    """
    model = TrackerEncoder.from_pretrained(
        repo_id,
        revision=revision,
        device=device,
        cache_dir=cache_dir,
    )
    config = EasyDict({"model": model._pretrained_model_config})
    return model, config


def run_tracker_encoder_on_videos(
    model,
    video_paths,
    camera_group,
    query_points_3d,
    start_frame=0,
    n_frames=128,
    n_overlap=2,
    max_kpts=None,
    device=None,
    pred_key_3d='coords_pred',
    clip_len=None,
    occlusion_gt=None,
    query_times=None,
    motion_margin=True,
    conf_crop_thresh=0.1,
):
    """Windowed multi-view tracking whose per-chunk crop FOLLOWS the subject.

    Each chunk re-crops the video on the current (re-anchored) query so a moving subject
    stays in the model's field of view — the long-horizon fix that a single static crop
    over the whole clip lacks.

    query_times (per-point, window-relative to start_frame; None -> all zeros): each point
    is SEEDED in the chunk containing its query frame (mvtracker / query-first) and, once
    seeded, propagated forward by re-anchoring on the previous chunk's prediction. With all
    query_times == 0 (and motion_margin off) this reduces bit-for-bit to the legacy
    all-points-at-start behavior.

    Keypoint chunking is delegated to the model's internal ``kpt_chunk`` (scene encoded
    ONCE per window, reused across point slices — numerically identical, lower memory).
    NOTE: the model disables ``kpt_chunk`` for ``output_mode='gridnorm'`` (its per-camera
    gauge couples points), so ``max_kpts`` is a no-op there and a large point set may OOM.

    motion_margin: expand each chunk's crop by the previous chunk's per-point velocity
    (a causal approximation of the training trajectory-bounded crop) so a fast subject
    stays in-frame across the window; ~inert for slow subjects.
    conf_crop_thresh: active points whose predicted visibility (sigmoid) falls below this
    are excluded from the crop-bbox computation so a lost point can't drag the crop off the
    still-tracked cluster. None disables the exclusion.
    """

    # Dimensionality of the queries: R==3 -> 3D world coords (multi-view), R==2 ->
    # 2D pixel coords in a single camera frame. The model supports both.
    # pred_key_3d selects which 3D model output to use as the prediction (and the
    # recurrence query) — e.g. 'coords_pred' (default) or '3d_pred_triangulate'.
    R = query_points_3d.shape[-1]
    is_2d = (R == 2)

    if device is None:
        device = next(model.parameters()).device

    model = model.to(device)
    model.eval()

    camera_group = camera_group_to_device(camera_group, device)

    readers, reader_lengths = build_video_readers(video_paths)

    max_available = min(reader_lengths)
    if start_frame < 0:
        raise ValueError('start_frame must be >= 0')
    if n_frames <= 0:
        raise ValueError('n_frames must be > 0')
    if n_overlap < 1:
        raise ValueError('n_overlap must be >= 1')
    if not hasattr(model, 'image_size'):
        raise AttributeError('model does not have an image_size attribute')
    if not hasattr(model, 'n_frames'):
        raise AttributeError('model does not have an n_frames attribute')
    if n_overlap >= model.n_frames:
        raise ValueError(f'n_overlap ({n_overlap}) must be less than model.n_frames ({model.n_frames})')
    if start_frame >= max_available:
        raise ValueError('start_frame is beyond the available frames in at least one video')

    current_frame = start_frame
    end_frame = min(start_frame + n_frames, max_available)

    current_queries = query_points_3d.to(device=device, dtype=torch.float32)
    if current_queries.ndim == 2:
        current_queries = current_queries.unsqueeze(0)
    N = current_queries.shape[1]
    # True query coordinate per point; seeded / not-yet-appeared points anchor on this
    # (their re-anchored prediction is only meaningful once they are active).
    original_queries = current_queries.clone()

    # Per-point ABSOLUTE first-visible frame (query-first). None -> everyone at start_frame,
    # which makes `before` always False and `seeded` true in chunk 0 -> the legacy path.
    if query_times is None:
        qt_abs = torch.full((N,), start_frame, device=device, dtype=torch.int64)
    else:
        qt_abs = start_frame + query_times.to(device=device, dtype=torch.int64).view(-1)

    # Logit written for not-yet-appeared / absent points so sigmoid() -> ~0 (invisible, no conf).
    LOGIT_INVISIBLE = -30.0

    coords_pred_all = []
    vis_pred_all = []
    conf_pred_all = []
    vis_pred_2d_all = []          # per-camera visibility logits (cams,b,t,n), for occlusion eval
    frame_numbers_all = []
    crop_history = []
    is_first_chunk = True
    # Cross-chunk continuity is provided by query re-anchoring (current_queries below):
    # each chunk re-seeds its query on the previous chunk's prediction.
    clip_len = clip_len if clip_len is not None else model.n_frames

    # Cross-chunk crop-robustness state: per-point velocity (world/pixel per frame) and
    # per-point predicted visibility at the previous chunk's last frame.
    prev_vel = None                                  # (1, N, R)
    prev_vis = None                                  # (1, N)

    # Occlusion carried across chunks (occlusion_embedding). First chunk (and each point's
    # SEED chunk) uses the GT occlusion at the query frame ({0,1,-1}) when available, else
    # unknown (-1); already-active points use the model's PREDICTED per-camera visibility
    # ({0,1}), which propagates window-to-window even when no GT vis exists. None -> all-unknown.
    occ_gt_dev = occlusion_gt.to(device=device).unsqueeze(0) if occlusion_gt is not None else None  # (1,N,cams)
    occ_pred = None                                  # predicted occ carried from previous chunk

    with torch.no_grad():
        pbar = tqdm(total=end_frame - start_frame, desc='Tracking', unit='frames')
        while current_frame < end_frame:
            remaining = end_frame - current_frame
            current_clip_len = clip_len
            win_end = current_frame + current_clip_len

            # Per-point role this chunk (query-first, forward-only seeding):
            before = qt_abs < current_frame                          # active (from earlier)
            seeded = (qt_abs >= current_frame) & (qt_abs < win_end)  # query frame lands here
            appeared = before | seeded                               # produced this chunk

            # Anchor coord per point: active -> carried prediction, else true query coord.
            coords_chunk = torch.where(before.view(1, N, 1), current_queries, original_queries)

            # Model query time (offset within the window): seed offset for points seeded
            # here, the re-anchor overlap offset for active points, 0 otherwise. With every
            # qt_abs == start_frame this is 0 in chunk 0 and n_overlap-1 after (legacy).
            seed_off = (qt_abs - current_frame).clamp(0, current_clip_len - 1)
            active_off = torch.full_like(qt_abs, n_overlap - 1)
            times_chunk = torch.where(before, active_off,
                                      torch.where(seeded, seed_off, torch.zeros_like(qt_abs)))
            times_chunk = times_chunk.to(torch.int32).unsqueeze(0)   # (1, N)

            # --- Crop point set: appeared anchors, minus lost (low-vis) active points, plus
            # a causal motion look-ahead so a fast subject stays in-frame over the window.
            crop_mask = appeared.clone()
            if conf_crop_thresh is not None and prev_vis is not None:
                lost = before & (torch.sigmoid(prev_vis[0]) < conf_crop_thresh)
                if bool((crop_mask & ~lost).any()):        # never empty the crop
                    crop_mask = crop_mask & ~lost
            crop_pts = coords_chunk[:, crop_mask]
            if motion_margin and prev_vel is not None:
                act = before & crop_mask
                if bool(act.any()):
                    look = current_queries[:, act] + prev_vel[:, act] * float(current_clip_len)
                    crop_pts = torch.cat([crop_pts, look], dim=1)
            if crop_pts.shape[1] == 0:
                crop_pts = coords_chunk                     # fallback (e.g. all not-yet)

            camera_group_chunk, crop_boxes = crop_camera_group_to_queries(
                camera_group=camera_group,
                query_coords=crop_pts,
                min_crop_dim=model.image_size,
                padding=20,
                is_2d=is_2d,
            )
            camera_group_chunk = resize_camera_group(
                camera_group_chunk,
                model.image_size,
            )

            # For 2D, queries are pixel coords in the ORIGINAL frame; the model
            # expects them in the cropped+resized model-input frame. resize_camera_group
            # scales by target/max(width,height), so use the SAME max here (crops are
            # non-square after the per-axis cap; width-only would mis-scale portrait crops).
            if is_2d:
                crop_low = crop_boxes[0][:2].to(device=device, dtype=torch.float32)
                crop_wh = (crop_boxes[0][2:] - crop_boxes[0][:2]).to(torch.float32)
                crop_side = torch.max(crop_wh)
                model_scale = float(model.image_size) / float(crop_side)
                queries_model = (coords_chunk - crop_low) * model_scale
            else:
                queries_model = coords_chunk

            target_sizes = [
                tuple(cam['size'].tolist())
                for cam in camera_group_chunk
            ]

            views, actual_clip_len = load_multiview_clip(
                readers,
                current_frame,
                current_clip_len,
                crop_boxes=crop_boxes,
                target_sizes=target_sizes,
            )

            if actual_clip_len == 0:
                break

            for i in range(len(views)):
                if views[i].shape[0] != actual_clip_len:
                    raise ValueError('All videos must provide the same number of frames')

            # Model requires exactly model.n_frames; pad if we got fewer
            if actual_clip_len < model.n_frames:
                pad_len = model.n_frames - actual_clip_len
                for i in range(len(views)):
                    last_frame = views[i][-1:]  # (1, H, W, 3)
                    padding = last_frame.expand(pad_len, -1, -1, -1)
                    views[i] = torch.cat([views[i], padding], dim=0)

            # Only keep predictions for frames we actually need
            keep_len = min(actual_clip_len, remaining)

            crop_history.append({
                'start_frame': current_frame,
                'n_frames': actual_clip_len,
                'crop_boxes': crop_boxes,
            })

            views = [v.unsqueeze(0).to(device=device, dtype=torch.float32) / 255.0 for v in views]

            # Occlusion fed to the model this chunk. Active points carry the previous chunk's
            # PREDICTED per-camera occlusion so the visibility state propagates across windows;
            # points whose query frame lands in THIS chunk are (re)seeded with GT occlusion when
            # available, else marked unknown (-1). occ_pred is only ever set when the model uses
            # the occlusion term (see below), so a model without it always takes the first
            # branch and this reduces to the legacy GT-or-None behavior.
            if is_first_chunk or occ_pred is None:
                occ_chunk = occ_gt_dev.clone() if occ_gt_dev is not None else None
            else:
                occ_chunk = occ_pred.clone()
                if bool(seeded.any()):
                    occ_chunk[:, seeded] = (occ_gt_dev[:, seeded] if occ_gt_dev is not None
                                            else -1)

            # Query-first: run the model on ONLY the points that have appeared by this
            # window (before | seeded). A not-yet-appeared point is neither fed to the model
            # -- so it cannot perturb the scene encoding / cross-point attention -- nor
            # stored; it is scattered back below as NaN coords / invisible logits. With every
            # query_time == 0 (legacy) every point is 'appeared' every window, so active_idx
            # == arange(N) and this is bit-for-bit identical to feeding the full set.
            active_idx = appeared.nonzero(as_tuple=True)[0]          # (M,)
            M = int(active_idx.numel())

            def _scatter(sub, kdim, fill):
                """Scatter a subset tensor (keypoint axis of length M at kdim) into a full-N
                tensor, filling the not-yet-appeared points with `fill`."""
                shape = list(sub.shape)
                shape[kdim] = N
                full = sub.new_full(shape, fill)
                if M > 0:
                    full.index_copy_(kdim, active_idx, sub)
                return full

            # Points fed to the model this window: the appeared set, or -- when nothing has
            # appeared yet (only possible if no point is visible at start_frame) -- a single
            # dummy point (index 0) so the model still returns correctly-shaped outputs; its
            # result is discarded by the fill-only scatter below (M==0 -> no index_copy_).
            run_idx = active_idx if M > 0 else active_idx.new_zeros(1)
            outputs = model(
                views=views,
                coords=queries_model[:, run_idx],
                query_times=times_chunk[:, run_idx],
                camera_group=camera_group_chunk,
                kpt_chunk=max_kpts,
                occlusion=(occ_chunk[:, run_idx] if occ_chunk is not None else None),
            )

            if is_2d:
                # 2D predictions live in model-input pixel space; map back to the
                # original full-image frame so outputs and the recurrence stay there.
                coords_pred = outputs['2d_pred'][0]  # single cam: (b, t, m, 2)
                coords_pred = crop_low + coords_pred / model_scale
                coords_pred = coords_pred[:, :keep_len]
            else:
                coords_pred = outputs[pred_key_3d][:, :keep_len]
            vis_pred = outputs['vis_pred'][:, :keep_len]
            conf_pred = outputs['conf_pred'][:, :keep_len]
            # Per-camera visibility logits (cams,b,t,n); time axis is dim 2, not dim 1.
            vis_pred_2d = (outputs['vis_pred_2d'][:, :, :keep_len]
                           if 'vis_pred_2d' in outputs else None)

            if coords_pred.shape[1] == 0:
                break

            # Scatter the appeared points' outputs back to full N, filling not-yet-appeared
            # points with NaN coords / invisible logits. Keypoint axis is dim 2 for
            # coords/vis/conf and dim 3 for the per-camera vis_pred_2d. `_scatter` copies only
            # when M>0, so the M==0 dummy output is dropped and every point is filled.
            coords_pred = _scatter(coords_pred, 2, float('nan'))
            vis_pred = _scatter(vis_pred, 2, LOGIT_INVISIBLE)
            conf_pred = _scatter(conf_pred, 2, LOGIT_INVISIBLE)
            if vis_pred_2d is not None:
                vis_pred_2d = _scatter(vis_pred_2d, 3, LOGIT_INVISIBLE)

            # Drop the overlap frames already emitted by the previous chunk (temporal
            # dedup); the first chunk keeps everything from its start.
            discard = 0 if is_first_chunk else min(n_overlap, keep_len)

            coords_pred_all.append(coords_pred[:, discard:].cpu())
            vis_pred_all.append(vis_pred[:, discard:].cpu())
            conf_pred_all.append(conf_pred[:, discard:].cpu())
            if vis_pred_2d is not None:
                vis_pred_2d_all.append(vis_pred_2d[:, :, discard:].cpu())
            frame_numbers_all.append(torch.arange(current_frame + discard, current_frame + keep_len, dtype=torch.int64))

            # --- Carry state to the next chunk.
            # Re-anchor appeared points on this chunk's last prediction; not-yet points keep
            # their true query coord for a later chunk to seed.
            appeared_by_end = (qt_abs < current_frame + keep_len).view(1, N, 1)
            current_queries = torch.where(appeared_by_end, coords_pred[:, -1], original_queries)

            # Per-point velocity (per frame, from the last two kept frames) for the next
            # chunk's causal motion margin, and predicted visibility for low-conf exclusion.
            prev_vel = (coords_pred[:, -1] - coords_pred[:, -2]) if keep_len >= 2 else None
            prev_vis = vis_pred[:, -1, :, 0] if vis_pred.dim() == 4 else vis_pred[:, -1]

            # Predicted per-camera occlusion for the re-anchored queries of the NEXT chunk:
            # threshold the model's vis_pred_2d at the last kept frame (same frame the
            # re-anchor query comes from). visible(sigmoid>=0.5)->1, occluded->0 (no -1 from
            # a prediction). Only fed forward when the model uses the occlusion term.
            if getattr(model, 'occlusion_embedding', False) and 'vis_pred_2d' in outputs:
                vp2d = outputs['vis_pred_2d']                    # (cams, b, t, M) logits
                vp2d_last = vp2d[:, :, keep_len - 1]             # (cams, b, M)
                occ_p = (torch.sigmoid(vp2d_last) >= 0.5).to(torch.int64)
                occ_p = occ_p.permute(1, 2, 0).contiguous()      # (cams,b,M) -> (b,M,cams)
                # Scatter to full N; not-yet points -> -1 (unknown). They are never read as
                # active occlusion (a point is 'before' only after its real seed chunk).
                occ_full = occ_p.new_full((occ_p.shape[0], N, occ_p.shape[2]), -1)
                if M > 0:
                    occ_full.index_copy_(1, active_idx, occ_p)
                occ_pred = occ_full
            else:
                occ_pred = None

            current_frame += keep_len - n_overlap
            pbar.update(keep_len - discard)
            is_first_chunk = False

            # Release this chunk's GPU tensors before the next window builds its own
            # full-N outputs; holding them across the next model() call would keep two
            # full-N sets live and double peak memory (the OOM on dense point sets).
            del coords_pred, vis_pred, conf_pred, outputs
            if vis_pred_2d is not None:
                del vis_pred_2d

            # If we've reached or passed the end, stop
            if current_frame + n_overlap >= end_frame:
                break

        pbar.close()

    del readers

    if len(coords_pred_all) == 0:
        return {
            'coords_pred': torch.empty((0, 0, 0, R)),
            'vis_pred': torch.empty((0, 0, 0, 1)),
            'conf_pred': torch.empty((0, 0, 0, 1)),
            'vis_pred_2d': torch.empty((0, 0, 0, 0)),
            'frame_numbers': torch.empty((0,), dtype=torch.int64),
            'crop_history': crop_history,
        }

    result = {
        'coords_pred': torch.cat(coords_pred_all, dim=1),
        'vis_pred': torch.cat(vis_pred_all, dim=1),
        'conf_pred': torch.cat(conf_pred_all, dim=1),
        'frame_numbers': torch.cat(frame_numbers_all, dim=0),
        'crop_history': crop_history,
    }
    if len(vis_pred_2d_all) > 0:
        # (cams, b, t, n) -> concat over the time axis (dim 2)
        result['vis_pred_2d'] = torch.cat(vis_pred_2d_all, dim=2)

    # A point exists only from its query frame forward (query-first). The per-window subselect
    # above already drops it from windows before it appears, but the window that SEEDS it is
    # 'appeared' for its whole span, so the frames in that window before the point's actual
    # query offset survive as backward extrapolation. Mask every frame strictly before each
    # point's absolute query frame. No-op for the legacy path (qt_abs == start_frame <= every
    # frame_number), so all-zero-query runs are unchanged.
    fn = result['frame_numbers']                                  # (T,) absolute, CPU
    pre = fn[:, None] < qt_abs.cpu()[None, :]                     # (T, N) bool
    if bool(pre.any()):
        result['coords_pred'][0][pre] = float('nan')
        result['vis_pred'][0][pre] = LOGIT_INVISIBLE
        result['conf_pred'][0][pre] = LOGIT_INVISIBLE
        if 'vis_pred_2d' in result:
            result['vis_pred_2d'][:, 0][:, pre] = LOGIT_INVISIBLE
    return result


def load_tracker_encoder_checkpoint(checkpoint_path, model_kwargs, device=None,
                                    config_path=None):
    if device is None:
        device = 'cuda' if torch.cuda.is_available() else 'cpu'

    # Both branches below load a full checkpoint into this model right after construction, so
    # the public VJEPA2 download would be discarded; override rather than trust model_kwargs.
    model = TrackerEncoder(**{**model_kwargs, 'video_encoder_pretrained': False}).to(device)

    # When a config is available, route through load_checkpoint so schedule-free runs get the
    # averaged EVAL weights (eval_weights defaults to 'auto' -> swaps since optimizer is None).
    if config_path is not None:
        # load_checkpoint was passed an already-built model, so its own built_here guard is a
        # no-op; check coverage here instead using the missing/dropped keys it returns.
        checkpoint_dict = load_checkpoint(config_path, checkpoint_path, model=model, device=device)
        _warn_unfilled_video_encoder(checkpoint_dict.get('missing_keys', []),
                                     checkpoint_dict.get('dropped_keys', []))
        model.eval()
        return model

    # No config: fall back to a raw model_state load (uses raw training weights for schedule-free).
    print('  [warn] no config_path given; loading raw model_state '
          '(schedule-free averaged eval weights will NOT be applied)')
    checkpoint = torch.load(checkpoint_path, map_location=device)
    state_dict = checkpoint.get('model_state', checkpoint)
    missing_keys, _ = model.load_state_dict(state_dict, strict=False)
    _warn_unfilled_video_encoder(missing_keys, [])
    model.eval()

    return model


def sort_by_camera_name(paths):
    """Sort paths using the same camera name ordering as load_camera_group_from_metadata."""
    names = [os.path.splitext(os.path.basename(p))[0] for p in paths]
    if all(n.isdigit() for n in names):
        return [p for _, p in sorted(zip(names, paths), key=lambda x: int(x[0]))]
    else:
        return [p for _, p in sorted(zip(names, paths))]


def resolve_video_paths(video_paths):
    """If a single directory is given that contains subdirectories (one per camera),
    expand it into a list of per-camera image folder paths, matching the
    TracktailDataset convention of img_path/cam_name/frame.png."""
    if len(video_paths) == 1 and os.path.isdir(video_paths[0]):
        root = video_paths[0]
        subdirs = [
            d for d in os.listdir(root)
            if os.path.isdir(os.path.join(root, d))
        ]
        if all(d.isdigit() for d in subdirs):
            subdirs = sorted(subdirs, key=int)
        else:
            subdirs = sorted(subdirs)
        if len(subdirs) > 0:
            return [os.path.join(root, d) for d in subdirs]
    return video_paths


def compute_query_first(coords, vis_gt, start_frame, n_frames):
    """mvtracker/training 'query_first': anchor each point at its FIRST valid frame.

    A frame is valid for a point when its coord is finite AND (if vis available) the point
    is visible in >=1 camera. Returns per-point:
      query_time (N,) int  -- index within [start_frame, start_frame+n_frames) of the first
                              valid frame (0 for points that are never valid; they are dropped
                              via `valid`),
      query_coord (N, R)   -- the coordinate at that frame,
      valid (N,) bool      -- point has at least one valid frame in the window.

    coords: (T_full, N, R) for one subject. vis_gt: (T_full, N, cams) or None.
    """
    T_full = coords.shape[0]
    hi = T_full if n_frames is None else min(T_full, start_frame + n_frames)
    sl = slice(start_frame, hi)
    c = coords[sl]                                       # (T, N, R)
    good = np.all(np.isfinite(c), axis=-1)              # (T, N)
    if vis_gt is not None:
        good = good & vis_gt[sl].any(axis=-1)
    valid = good.any(axis=0)                            # (N,)
    query_time = np.argmax(good, axis=0).astype(np.int32)   # first True frame (0 if none)
    query_coord = c[query_time, np.arange(c.shape[1])]      # (N, R)
    return query_time, query_coord, valid


def occlusion_at_query(vis_used_s, query_time_valid, valid_mask, start_frame):
    """Per-camera GT occlusion at each valid point's query frame, for the
    occlusion_embedding query term.

    vis_used_s: (T_full, n_kpts, cams) GT visibility for one subject (NaN=unknown), on
        the cameras ACTUALLY USED (already camera-subsampled), or None.
    query_time_valid: (N_valid,) window-relative query frame per VALID point (0 ==
        start_frame), in the same order as valid_mask's selected keypoints (this is what
        load_trial stores in per_subject_query_times).
    valid_mask: (n_kpts,) bool selecting the tracked points (its nonzero indices give the
        original keypoint columns, aligned with query_time_valid).
    start_frame: absolute offset added to the window-relative query time.

    Returns an int64 tensor (N_valid, cams) with values {0=occluded, 1=visible,
    -1=unknown}, or None when no GT visibility is available.
    """
    if vis_used_s is None:
        return None
    kpt_idx = np.nonzero(valid_mask)[0]                            # (N_valid,) original columns
    frames = np.clip(start_frame + np.asarray(query_time_valid),
                     0, vis_used_s.shape[0] - 1)                   # (N_valid,) absolute frames
    v = vis_used_s[frames, kpt_idx]                               # (N_valid, cams), NaN-bearing
    occ = np.where(np.isnan(v), -1.0, (v > 0.5).astype(np.float32))  # NaN->-1, else 0/1
    return torch.as_tensor(occ, dtype=torch.int64)


def load_trial(trial_path, start_frame=0, n_frames=None, query_first=True,
               max_points=None, seed=0, pose_file=None, cam_names_filter=None):
    """Load metadata, video/image paths, and query points from a trial directory,
    following the TracktailDataset convention.

    Detects 2D vs 3D from which pose file is present: pose3d.npz -> 3D (multi-view,
    metadata.yaml required), pose2d.npz -> 2D (single camera, metadata optional).
    pose_file overrides the default 'pose3d.npz' filename (e.g. 'pose3d_100.npz').
    Query points have last dim 3 (3D world coords) or 2 (2D pixel coords) accordingly.

    query_first (3D only): anchor each point at its first valid+visible frame (mvtracker /
    training convention) instead of all points at start_frame. Returns per-point query_times.
    With cam_names_filter, visible means visible in at least one of those cameras (default: any camera of the file).

    max_points (per subject): if set and a subject has more than this many valid query points,
    randomly subsample its valid mask down to max_points (seeded by `seed`). This genuinely
    shrinks N fed to the tracker -- unlike max_kpts chunking, which retains full-N latent/grid --
    so it bounds memory/time on dense sets (e.g. point-odyssey, ~40k-76k pts/subject). The cull
    lands on the valid mask before queries/query_times are built, so every downstream consumer
    (GT extraction, occlusion_at_query) stays consistent automatically.

    Returns a dict with keys: 'mode', 'metadata_path', 'cam_names', 'video_paths',
    'query_points', 'per_subject_queries', 'coords', 'vis_gt', 'valid_flat',
    'per_subject_valid_masks', 'query_times_flat', 'per_subject_query_times'.
    """

    pose3d_name = pose_file if pose_file is not None else 'pose3d.npz'
    pose3d_path = os.path.join(trial_path, pose3d_name)
    pose2d_path = os.path.join(trial_path, 'pose2d.npz')
    if os.path.exists(pose3d_path):
        mode = '3d'
        pose_path = pose3d_path
    elif os.path.exists(pose2d_path):
        mode = '2d'
        pose_path = pose2d_path
    else:
        raise FileNotFoundError(f'No pose3d.npz or pose2d.npz found in {trial_path}')

    # metadata.yaml required for 3D; optional for 2D (uncalibrated single camera)
    metadata_path = os.path.join(trial_path, 'metadata.yaml')
    if mode == '3d' and not os.path.exists(metadata_path):
        raise FileNotFoundError(f'metadata.yaml not found in {trial_path}')
    if not os.path.exists(metadata_path):
        metadata_path = None

    # determine image or video paths
    img_path = os.path.join(trial_path, 'img')
    vid_path = os.path.join(trial_path, 'vid')

    # Camera ordering: from metadata when available (3D, or calibrated 2D),
    # otherwise from the img/ subdirectories (uncalibrated 2D -> single camera).
    if metadata_path is not None:
        with open(metadata_path, 'r') as f:
            cam_metadata = yaml.safe_load(f)
        cam_names = list(cam_metadata['intrinsic_matrices'].keys())
    elif os.path.exists(img_path):
        cam_names = [d for d in os.listdir(img_path)
                     if os.path.isdir(os.path.join(img_path, d))]
    else:
        cam_names = [os.path.splitext(f)[0] for f in os.listdir(vid_path)]
    if all(n.isdigit() for n in cam_names):
        cam_names = sorted(cam_names, key=int)
    else:
        cam_names = sorted(cam_names)
    if mode == '2d':
        cam_names = cam_names[:1]  # 2D trials are always single-camera

    if os.path.exists(img_path) and len(os.listdir(img_path)) > 0:
        # Sort image subdirectories using camera names from metadata
        # to ensure alignment with the camera group
        video_paths = [os.path.join(img_path, cam_name) for cam_name in cam_names]
        for vp in video_paths:
            if not os.path.exists(vp):
                raise FileNotFoundError(f'Expected image folder {vp} not found')
    elif os.path.exists(vid_path):
        video_paths = [os.path.join(vid_path, f'{cam_name}.mp4') for cam_name in cam_names]
        for vp in video_paths:
            if not os.path.exists(vp):
                raise FileNotFoundError(f'Expected video file {vp} not found')
    else:
        raise FileNotFoundError(f'Neither img/ nor vid/ folder found in {trial_path}')


    data = np.load(pose_path)
    coords = data['pose']  # (subjects, time, n_kpts, R), R=3 for 3D / 2 for 2D
    vis_gt = data['vis'] if 'vis' in data else None  # 2D trials never have vis

    R = coords.shape[-1]
    n_subjects = coords.shape[0]
    n_kpts = coords.shape[2]

    # query_first is 3D-only (needs vis to define first-visible frame); 2D falls back.
    use_query_first = query_first and mode == '3d'

    # visibility that defines the first visible frame: only the cameras that are used, when they are given
    vis_query = vis_gt
    if use_query_first and cam_names_filter is not None and vis_gt is not None:
        missing = [n for n in cam_names_filter if n not in cam_names]
        if missing:
            raise ValueError(f'Requested cameras not in trial: {missing}')
        if vis_gt.shape[-1] != len(cam_names):
            # e.g. the 31 vis columns of the standard panoptic pose3d.npz (by camera id) for 27 cameras
            print(f'[warn] {pose_path}: vis has {vis_gt.shape[-1]} columns but the trial has {len(cam_names)} cameras; '
                  f'the vis columns cannot be matched to the cameras in use, query frames use all of them')
        else:
            vis_query = vis_gt[..., [cam_names.index(n) for n in cam_names_filter]]

    per_subject_queries = []
    per_subject_valid_masks = []
    per_subject_query_times = []
    subsample_rng = np.random.default_rng(seed) if max_points is not None else None
    for s in range(n_subjects):
        if use_query_first:
            qt_s, qc_s, valid = compute_query_first(
                coords[s], vis_query[s] if vis_query is not None else None, start_frame, n_frames)
        else:
            qc_s = coords[:, start_frame, :, :][s]              # (n_kpts, R)
            valid = np.all(np.isfinite(qc_s), axis=1)
            qt_s = np.zeros(qc_s.shape[0], dtype=np.int32)
        # Optionally cap this subject's tracked points (random, one shared seeded RNG). Applied
        # to the valid mask before slicing so queries/query_times/GT all stay aligned.
        if subsample_rng is not None and int(valid.sum()) > max_points:
            on = np.flatnonzero(valid)
            drop = subsample_rng.choice(on, on.size - max_points, replace=False)
            valid = valid.copy()
            valid[drop] = False
        per_subject_valid_masks.append(valid)
        per_subject_queries.append(torch.as_tensor(qc_s[valid], dtype=torch.float32))
        per_subject_query_times.append(torch.as_tensor(qt_s[valid], dtype=torch.int32))

    # flat (all subjects concatenated, s-major then kpt) — matches GT-extraction ordering
    query_points = torch.cat(per_subject_queries, dim=0) if per_subject_queries \
        else torch.empty((0, R))
    query_times_flat = torch.cat(per_subject_query_times, dim=0) if per_subject_query_times \
        else torch.empty((0,), dtype=torch.int32)
    valid_flat = np.concatenate(per_subject_valid_masks) if per_subject_valid_masks \
        else np.zeros(0, dtype=bool)

    if query_points.shape[0] == 0:
        raise ValueError(f'No valid query points in trial {trial_path}')

    return {
        'mode': mode,
        'metadata_path': metadata_path,
        'cam_names': cam_names,
        'video_paths': video_paths,
        'query_points': query_points,
        'per_subject_queries': per_subject_queries,
        'coords': coords,
        'vis_gt': vis_gt,
        'valid_flat': valid_flat,
        'per_subject_valid_masks': per_subject_valid_masks,
        'query_times_flat': query_times_flat,
        'per_subject_query_times': per_subject_query_times,
    }


def run_inference(
    model,
    config_path,
    checkpoint_path,
    trial_path,
    start_frame=0,
    n_frames=128,
    n_overlap=2,
    n_views=None,
    seed=None,
    max_kpts=None,
    per_subject=False,
    device=None,
    outpath=None,
    pred_key_3d='coords_pred',
    clip_len=None,
    query_first=True,
    motion_margin=True,
    max_points=None,
    cam_names_filter=None,
    pose_file=None,
):
    """Run inference on one trial with an already-loaded model.

    Factored out of main() so a caller (e.g. a batch driver) can load the model
    once and reuse it across many trials. If outpath is given the outputs are
    saved as .npz; the outputs dict is always returned.

    query_first (3D only): seed each point at its first valid+visible frame (mvtracker /
    training convention) within the windowed, per-chunk re-cropping tracker, instead of all
    points at start_frame. motion_margin: expand each chunk's crop by the previous chunk's
    per-point velocity so fast subjects stay in-frame (disable for the legacy-identical path).

    max_points (per subject): random-subsample each subject's tracked points to this cap
    (seeded by `seed`, shared with camera subsampling) -- bounds memory/time on dense sets.
    See load_trial for details.
    """
    if device is None:
        device = next(model.parameters()).device

    trial = load_trial(trial_path, start_frame=start_frame, n_frames=n_frames,
                       query_first=query_first, max_points=max_points, seed=seed,
                       pose_file=pose_file, cam_names_filter=cam_names_filter)
    mode                    = trial['mode']
    metadata_path           = trial['metadata_path']
    cam_names               = trial['cam_names']
    video_paths             = trial['video_paths']
    query_points_3d         = trial['query_points']
    per_subject_queries     = trial['per_subject_queries']
    coords_gt               = trial['coords']
    vis_gt_raw              = trial['vis_gt']
    valid_flat              = trial['valid_flat']
    per_subject_valid_masks = trial['per_subject_valid_masks']
    query_times_flat        = trial['query_times_flat']
    per_subject_query_times = trial['per_subject_query_times']
    use_query_first = query_first and mode == '3d'

    R = coords_gt.shape[-1]

    if mode == '2d':
        camera_group = load_camera_group_2d(video_paths, metadata_path, device='cpu')
    else:
        camera_group = load_camera_group_from_metadata(metadata_path, device='cpu')

    if len(video_paths) != len(camera_group):
        raise ValueError(
            f'Number of video paths ({len(video_paths)}) does not match '
            f'number of cameras ({len(camera_group)}) in metadata'
        )
    
    # subsample cameras
    n_cams_total = len(camera_group)
    cam_indices_used = list(range(n_cams_total))

    if cam_names_filter is not None:
        pass  # skip random subsampling; cam_names_filter selects cameras explicitly below
    elif n_views is not None and n_views < n_cams_total:
        rng = np.random.default_rng(seed)
        cam_indices_used = sorted(rng.choice(n_cams_total, n_views, replace=False).tolist())
        print(f'Subsampling {n_views}/{n_cams_total} cameras: indices {cam_indices_used}')
        camera_group = [camera_group[i] for i in cam_indices_used]
        video_paths  = [video_paths[i] for i in cam_indices_used]
    elif n_views is not None:
        print(f'--n-views={n_views} >= available cameras ({n_cams_total}); using all cameras')

    # Record the cameras actually used, after any subsampling above.
    cam_names_used = [cam_names[i] for i in cam_indices_used]

    if cam_names_filter is not None:
        missing = [n for n in cam_names_filter if n not in cam_names_used]
        if missing:
            raise ValueError(f'Requested cameras not in trial: {missing}')
        filter_idx = [cam_names_used.index(n) for n in cam_names_filter]
        cam_indices_used = [cam_indices_used[j] for j in filter_idx]
        camera_group = [camera_group[j] for j in filter_idx]
        video_paths = [video_paths[j] for j in filter_idx]
        cam_names_used = list(cam_names_filter)
        print(f'Using explicit cameras: {cam_names_used}')

    # GT visibility restricted to the cameras actually used, for the occlusion query term.
    # vis_gt_raw is (subjects, time, kpts, n_cams_total); index the camera axis so the
    # occlusion cams dim matches the model input. None when the trial has no visibility.
    vis_gt_used = vis_gt_raw[..., cam_indices_used] if vis_gt_raw is not None else None

    def _subject_occlusion(s):
        vis_used_s = vis_gt_used[s] if vis_gt_used is not None else None
        return occlusion_at_query(vis_used_s, per_subject_query_times[s],
                                  per_subject_valid_masks[s], start_frame)

    if per_subject:
        all_subject_outputs = []
        for subj_idx, subj_queries in enumerate(per_subject_queries):
            if subj_queries.shape[0] == 0:
                print(f'Skipping subject {subj_idx}: no valid query points')
                continue
            print(f'Tracking subject {subj_idx} ({subj_queries.shape[0]} keypoints)')
            subj_occlusion = _subject_occlusion(subj_idx)
            subj_out = run_tracker_encoder_on_videos(
                model=model,
                video_paths=video_paths,
                camera_group=camera_group,
                query_points_3d=subj_queries,
                start_frame=start_frame,
                n_frames=n_frames,
                n_overlap=n_overlap,
                max_kpts=max_kpts,
                device=device,
                pred_key_3d=pred_key_3d,
                clip_len=clip_len,
                occlusion_gt=subj_occlusion,
                query_times=per_subject_query_times[subj_idx] if use_query_first else None,
                motion_margin=motion_margin,
            )
            subj_out['subject_idx'] = subj_idx
            all_subject_outputs.append(subj_out)

        # Combine per-subject results: stack along a new subject dimension
        if len(all_subject_outputs) == 0:
            outputs = {
                'coords_pred': torch.empty((0, 0, 0, R)),
                'vis_pred': torch.empty((0, 0, 0, 1)),
                'conf_pred': torch.empty((0, 0, 0, 1)),
                'frame_numbers': torch.empty((0,), dtype=torch.int64),
                'crop_history': [],
            }
        else:
            # Use frame_numbers from the first subject (all should be identical
            # since they share start_frame / n_frames / n_overlap)
            outputs = {
                'frame_numbers': all_subject_outputs[0]['frame_numbers'],
                'crop_history': [],
            }
            # Stack per-subject predictions: each is (1, T, K, D) -> collect into lists
            coords_list = []
            vis_list = []
            conf_list = []
            vp2d_list = []          # per-camera logits, each (cams, 1, T, K_s)
            for so in all_subject_outputs:
                coords_list.append(so['coords_pred'])
                vis_list.append(so['vis_pred'])
                conf_list.append(so['conf_pred'])
                if 'vis_pred_2d' in so:
                    vp2d_list.append(so['vis_pred_2d'])
                outputs['crop_history'].extend(so['crop_history'])

            # Concatenate along the keypoint dimension (dim=2) with batch dim=0
            # Result shape: (1, T, total_kpts, D) but grouped by subject
            outputs['coords_pred'] = torch.cat(coords_list, dim=2)
            outputs['vis_pred'] = torch.cat(vis_list, dim=2)
            outputs['conf_pred'] = torch.cat(conf_list, dim=2)
            # vis_pred_2d is (cams, b, t, n): keypoints are dim 3. Only when every
            # subject produced it (same camera/time layout across subjects).
            if len(vp2d_list) == len(all_subject_outputs) and len(vp2d_list) > 0:
                outputs['vis_pred_2d'] = torch.cat(vp2d_list, dim=3)

            # Also store per-subject slicing info
            subject_kpt_counts = [so['coords_pred'].shape[2] for so in all_subject_outputs]
            subject_indices = [so['subject_idx'] for so in all_subject_outputs]
            outputs['subject_kpt_counts'] = np.array(subject_kpt_counts, dtype=np.int32)
            outputs['subject_indices'] = np.array(subject_indices, dtype=np.int32)
    else:
        # Flat (all subjects concatenated, s-major): build occlusion in the same order as
        # query_points (torch.cat of per_subject_queries). None if the trial has no vis.
        if vis_gt_used is not None:
            occ_parts = [_subject_occlusion(s) for s in range(len(per_subject_queries))]
            occlusion_flat = (torch.cat(occ_parts, dim=0)
                              if len(occ_parts) > 0 else None)
        else:
            occlusion_flat = None

        outputs = run_tracker_encoder_on_videos(
            model=model,
            video_paths=video_paths,
            camera_group=camera_group,
            query_points_3d=query_points_3d,
            start_frame=start_frame,
            n_frames=n_frames,
            n_overlap=n_overlap,
            max_kpts=max_kpts,
            device=device,
            pred_key_3d=pred_key_3d,
            clip_len=clip_len,
            occlusion_gt=occlusion_flat,
            query_times=query_times_flat if use_query_first else None,
            motion_margin=motion_margin,
        )

    # --- Ground-truth extraction ---
    frame_nums = (outputs['frame_numbers'].numpy()
                  if isinstance(outputs['frame_numbers'], torch.Tensor)
                  else np.asarray(outputs['frame_numbers']))
    n_time_gt = coords_gt.shape[1]
    frame_nums_gt = np.clip(frame_nums, 0, n_time_gt - 1)

    if per_subject and 'subject_indices' in outputs:
        coords_true_parts, vis_true_parts, vis_cam_parts = [], [], []
        for s_idx in outputs['subject_indices']:
            vmask = per_subject_valid_masks[s_idx]
            subj_coords = coords_gt[s_idx, frame_nums_gt]          # (T, n_kpts, 3)
            subj_coords = subj_coords[:, vmask, :]                 # (T, K_s, 3)
            coords_true_parts.append(subj_coords)

            if vis_gt_used is not None:
                # OR over only the cameras actually fed to the model, so the global label is
                # consistent with vis_true_cams / vis_pred under camera subsampling (n_views).
                subj_vis = vis_gt_used[s_idx, frame_nums_gt]       # (T, n_kpts, n_cams_used)
                subj_vis = subj_vis[:, vmask, :].any(axis=-1, keepdims=True)  # (T, K_s, 1)
            else:
                subj_vis = np.all(np.isfinite(subj_coords), axis=-1, keepdims=True)
            vis_true_parts.append(subj_vis)

            # Per-camera GT visibility on the USED cameras (NaN=unknown preserved), for the
            # per-camera occlusion metric. Aligned to vis_pred_2d's camera axis.
            if vis_gt_used is not None:
                vis_cam_parts.append(vis_gt_used[s_idx, frame_nums_gt][:, vmask, :])  # (T, K_s, cams)

        coords_true = np.concatenate(coords_true_parts, axis=1)[np.newaxis]  # (1, T, K, 3)
        vis_true    = np.concatenate(vis_true_parts,    axis=1)[np.newaxis]  # (1, T, K, 1)
        vis_true_cams = (np.concatenate(vis_cam_parts, axis=1)[np.newaxis]   # (1, T, K, cams)
                         if vis_cam_parts else None)

    else:
        n_subj, n_time_full, n_kpts_full, _ = coords_gt.shape

        # coords_gt is (n_subj, n_time, n_kpts, R)
        # transpose to (n_subj, n_kpts, n_time, R) before flattening subjects+kpts
        coords_flat_all = coords_gt.transpose(0, 2, 1, 3)                    # (n_subj, n_kpts, n_time, R)
        coords_flat_all = coords_flat_all.reshape(n_subj * n_kpts_full, n_time_full, R)  # (S*K, n_time, R)
        coords_flat_all = coords_flat_all[valid_flat]                         # (K_valid, n_time, R)
        coords_true = coords_flat_all[:, frame_nums_gt, :].transpose(1, 0, 2)[np.newaxis]  # (1, T, K_valid, R)

        if vis_gt_used is not None:
            # OR over only the cameras actually fed to the model (vis_gt_used), not the full
            # trial rig (vis_gt_raw) -- keeps the global label consistent with vis_true_cams /
            # vis_pred under camera subsampling (n_views); otherwise vis_true stays pinned to
            # the full-rig visible rate regardless of how many cameras the model actually sees.
            # vis_gt_used is (n_subj, n_time, n_kpts, n_cams_used) — aggregate across cameras
            vis_agg = vis_gt_used.any(axis=-1)                                # (n_subj, n_time, n_kpts)
            vis_flat_all = vis_agg.transpose(0, 2, 1)                        # (n_subj, n_kpts, n_time)
            vis_flat_all = vis_flat_all.reshape(n_subj * n_kpts_full, n_time_full)  # (S*K, n_time)
            vis_flat_all = vis_flat_all[valid_flat]                           # (K_valid, n_time)
            vis_true = vis_flat_all[:, frame_nums_gt].T[:, :, np.newaxis][np.newaxis]  # (1, T, K_valid, 1)
        else:
            vis_true = np.all(np.isfinite(coords_true), axis=-1, keepdims=True)

        # Per-camera GT (NaN=unknown preserved) on the USED cameras, mirroring the coords_true
        # reshape but keeping the camera axis: (n_subj,n_time,n_kpts,cams) -> (1,T,K_valid,cams).
        if vis_gt_used is not None:
            n_cams_used = vis_gt_used.shape[-1]
            vc = vis_gt_used.transpose(0, 2, 1, 3)                            # (n_subj, n_kpts, n_time, cams)
            vc = vc.reshape(n_subj * n_kpts_full, n_time_full, n_cams_used)   # (S*K, n_time, cams)
            vc = vc[valid_flat]                                              # (K_valid, n_time, cams)
            vis_true_cams = vc[:, frame_nums_gt, :].transpose(1, 0, 2)[np.newaxis]  # (1, T, K_valid, cams)
        else:
            vis_true_cams = None

    # per-point query times, in the same keypoint order as coords_pred/coords_true
    if per_subject and 'subject_indices' in outputs:
        qt_parts = [np.asarray(per_subject_query_times[s]) for s in outputs['subject_indices']]
        query_times_out = np.concatenate(qt_parts) if qt_parts else np.zeros(0, dtype=np.int32)
    else:
        query_times_out = np.asarray(query_times_flat)
    outputs['query_times'] = query_times_out.astype(np.int32)   # (K,)
    outputs['query_first'] = bool(use_query_first)

    outputs['coords_true'] = coords_true   # (1, T, K, 3)
    outputs['vis_true'] = vis_true      # (1, T, K, 1)
    # Per-camera GT visibility for the per-camera occlusion metric; paired with the model's
    # vis_pred_2d (already in outputs from the tracker). Both omitted when GT vis is absent.
    if vis_true_cams is not None:
        outputs['vis_true_cams'] = vis_true_cams   # (1, T, K, cams_used), NaN=unknown
    outputs['video_paths'] = np.array(video_paths, dtype=str)
    outputs['mode'] = mode
    outputs['metadata_path'] = metadata_path if metadata_path is not None else ''
    outputs['trial_path'] = trial_path
    outputs['config_path'] = config_path
    outputs['checkpoint_path'] = checkpoint_path
    outputs['start_frame'] = start_frame
    outputs['n_frames_requested'] = n_frames
    outputs['n_overlap'] = n_overlap
    outputs['per_subject'] = per_subject
    outputs['n_cams_total'] = n_cams_total
    outputs['cam_indices_used'] = np.array(cam_indices_used, dtype=np.int32)
    outputs['cam_names_used'] = np.array(cam_names_used, dtype=str)

    if isinstance(outputs['coords_pred'], torch.Tensor) and outputs['coords_pred'].ndim >= 2:
        outputs['n_frames_returned'] = outputs['coords_pred'].shape[1]
    else:
        outputs['n_frames_returned'] = 0

    if outpath is not None:
        save_dict = {}
        for k, v in outputs.items():
            if isinstance(v, torch.Tensor):
                save_dict[k] = v.cpu().numpy()
            else:
                save_dict[k] = v

        crop_history_serializable = [
            {
                'start_frame': int(ch['start_frame']),
                'n_frames': int(ch['n_frames']),
                'crop_boxes': [cb.cpu().numpy().tolist() for cb in ch['crop_boxes']],
            }
            for ch in outputs['crop_history']
        ]
        save_dict['crop_history'] = json.dumps(crop_history_serializable)

        outdir = os.path.dirname(outpath)
        if outdir != '':
            os.makedirs(outdir, exist_ok=True)
        np.savez(outpath, **save_dict)
        print(f'Saved outputs to {outpath}')
    else:
        print('Inference completed.')
        print(f'checkpoint_path: {checkpoint_path}')
        print(f'config_path: {config_path}')
        print(f'n_frames_returned: {outputs["coords_pred"].shape[1] if outputs["coords_pred"].ndim >= 2 else 0}')

    return outputs


