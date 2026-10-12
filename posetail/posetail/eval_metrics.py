import torch
import numpy as np
from posetail.posetail.losses import get_vis_true


def get_direct_depth_metrics(pred_cams_direct, tri_pred, rays_c, coords_true,
                             vis_true_cams, prefix='eval/', cgroup=None):
    '''Decompose the per-camera DIRECT-head 3D error into along-ray (depth) vs
    in-plane components, in world units, in each camera's ray-local frame
    (rays_c maps world -> ray-local; axis 2 = viewing ray = depth, axes 0:1 =
    image plane). Masked by (per-camera visible) AND (finite GT).

    Always returns the SAME three keys (nan when inputs are missing / not
    applicable: non-grid mode has no rays_c, 2D batches, no per-camera direct),
    so the per-dataset averaging never hits a missing key.

    parameters:
        pred_cams_direct: (cams, b, t, n, 3) per-camera direct world points, or None
        tri_pred:         (b, t, n, 3) fused triangulate world point, or None (control)
        rays_c:           (cams, 4, 4) world -> ray-local SE(3), or None
        coords_true:      (b, t, n, 3) GT world coords
        vis_true_cams:    (b, t, n, cams, 1) per-camera visibility, or None
    '''
    keys = [f'{prefix}dir_depth_rms', f'{prefix}dir_inplane_rms', f'{prefix}tri_depth_rms']
    out = {k: float('nan') for k in keys}
    if (pred_cams_direct is None or rays_c is None or coords_true is None
            or coords_true.shape[-1] != 3):
        return out

    from posetail.posetail.cube import to_homogeneous, from_homogeneous, is_point_visible

    with torch.no_grad():
        # float64: far rigs (johnson-fly ~6.5e5 units) make these ray-local einsums form ~6.5e5 coords
        # whose TF32 noise doesn't cancel in pred_rl-gt_rl -> spurious dir_depth_rms ~200. float64 = exact.
        rays_c = rays_c.to(torch.float64)                            # (cams,4,4)
        n_cams = rays_c.shape[0]
        ct = coords_true.to(torch.float64)                          # (b,t,n,3)
        B, T, N = ct.shape[:3]
        gt_rl = from_homogeneous(torch.einsum(
            'cxr,btnr->cbtnx', rays_c, to_homogeneous(ct)))          # (cams,b,t,n,3)

        # per-camera visibility mask: prefer supplied vis_true_cams; else derive it
        # from the cameras exactly as the loss does (is_point_visible, margin=2);
        # else fall back to finite-GT only. Combined with finite GT throughout.
        finite = torch.isfinite(ct[..., 0])                          # (b,t,n)
        if vis_true_cams is not None:
            vc = (vis_true_cams[..., 0].to(rays_c.device) > 0.5).permute(3, 0, 1, 2)
        elif cgroup is not None:
            # keep time explicit (b,t,n,3) so per-frame (moving-cam) extrinsics align;
            # cast to fp32 since extrinsics are fp32 (is_point_visible returns (b,t,n))
            vc = torch.stack([is_point_visible(cam, ct.to(torch.float32), margin=2) for cam in cgroup])
        else:
            vc = finite[None].expand(n_cams, B, T, N)
        mask = vc & finite[None]
        if mask.sum() == 0:
            return out

        def rms(x):
            return float(torch.sqrt((x[mask] ** 2).mean()).item())

        pw = pred_cams_direct.to(torch.float64)                       # (cams,b,t,n,3)
        pred_rl = from_homogeneous(torch.einsum(
            'cxr,cbtnr->cbtnx', rays_c, to_homogeneous(pw)))
        err = pred_rl - gt_rl
        out[f'{prefix}dir_depth_rms'] = rms(err[..., 2].abs())
        out[f'{prefix}dir_inplane_rms'] = rms(err[..., :2].norm(dim=-1))

        if tri_pred is not None:
            tw = tri_pred.to(torch.float64)[None].expand(n_cams, *tri_pred.shape)
            tri_rl = from_homogeneous(torch.einsum(
                'cxr,cbtnr->cbtnx', rays_c, to_homogeneous(tw)))
            out[f'{prefix}tri_depth_rms'] = rms((tri_rl - gt_rl)[..., 2].abs())

    return out


def _sigmoid(x):
    # vis_pred is emitted as a raw logit (noisy-OR over per-camera logits, see
    # cube.noisy_or_logit); convert to a probability so the 0.5 threshold below
    # matches the decision boundary the BCE-with-logits vis loss optimizes toward.
    return 1.0 / (1.0 + np.exp(-x))

def get_eval_metrics(vis_pred, vis_true, coords_pred,
                     coords_true, thresholds = None,
                     survival_threshold = 50, prefix = 'eval/',
                     cube_scale = None, delta_x_multiplier = 1.0,
                     query_times = None, vis_pred_2d = None,
                     vis_true_cams = None):

    # cube_scale: optional (B,) world-units-per-pixel (median over cameras). When given, the
    # delta_x thresholds become k * cube_scale * delta_x_multiplier world units, i.e. delta_x_k
    # = "fraction within (k * multiplier) pixels at the model's resolution" -- cross-dataset
    # comparable (multiplier=1 -> the standard TAP-Vid pixel thresholds). None -> raw world-unit
    # thresholds (backward compatible).
    if vis_true is None:
        vis_true = get_vis_true(coords_true)

    if thresholds is None:
        thresholds = [1, 2, 4, 8, 16]

    if cube_scale is not None and isinstance(cube_scale, torch.Tensor):
        cube_scale = cube_scale.detach().cpu().to(torch.float32).numpy()

    vis_pred = vis_pred.detach().cpu().to(torch.float32).numpy()
    vis_true = vis_true.detach().cpu().numpy().astype(bool)
    coords_pred = coords_pred.detach().cpu().to(torch.float32).numpy()
    coords_true = coords_true.detach().cpu().to(torch.float32).numpy()

    # `valid` = frames that count at all: GT is finite AND (query_first) at/after the point's
    # query time. This drops invalid GT (e.g. cleaned (0,0,-1)->NaN placeholders) and pre-query
    # frames, matching the mvtracker convention. Occlusion accuracy is masked by `valid` (both
    # visible AND occluded valid frames count); the position metrics additionally require the
    # point to be VISIBLE, so they use vis_eff = valid & vis_true.
    valid = np.isfinite(coords_true).all(axis=-1, keepdims=True)      # B,T,N,1
    if query_times is not None:
        if isinstance(query_times, torch.Tensor):
            query_times = query_times.detach().cpu().numpy()
        qt = np.asarray(query_times)                                  # (N,) or (B,N)
        B, T, N = valid.shape[0], valid.shape[1], valid.shape[2]
        qt = np.broadcast_to(qt.reshape(-1, N) if qt.ndim > 1 else qt.reshape(1, N), (B, N))
        at_or_after = np.arange(T)[None, :, None] >= qt[:, None, :]    # B,T,N
        valid = valid & at_or_after[..., None]
    vis_eff = vis_true & valid

    mte = get_mte(coords_pred, coords_true, vis_eff)

    occlusion_acc = get_occlusion_accuracy(vis_pred, vis_true, mask=valid)

    mpjpe = get_mpjpe(coords_pred, coords_true, vis_pred, vis_eff)

    delta_x_avg, delta_x_dict = get_delta_x_avg(coords_pred,
        coords_true, vis_eff, thresholds = thresholds,
        cube_scale = cube_scale, multiplier = delta_x_multiplier)

    survival_rate = get_survival_rate(coords_pred,
        coords_true, vis_eff, threshold = survival_threshold)

    avg_jaccard, avg_jaccard_dict = get_average_jaccard(coords_pred,
        coords_true, vis_pred, vis_eff, thresholds=thresholds,
        cube_scale=cube_scale, multiplier=delta_x_multiplier)

    l1 = get_l1(coords_pred, coords_true, vis_eff)

    metrics = {f'{prefix}mte': mte,
               f'{prefix}delta_x_avg': delta_x_avg,
               f'{prefix}occlusion_acc': occlusion_acc,
               f'{prefix}avg_jaccard': avg_jaccard,
               f'{prefix}survival_rate': survival_rate,
               f'{prefix}mpjpe': mpjpe,
               f'{prefix}l1': l1}

    # Per-camera occlusion accuracy: scores the model's per-camera visibility logits
    # (vis_pred_2d) against per-camera GT (vis_true_cams, NaN=unknown), using the same
    # `valid` frame mask. Only computed when the caller supplies both tensors.
    if vis_pred_2d is not None and vis_true_cams is not None:
        metrics[f'{prefix}occlusion_acc_percam'] = get_occlusion_accuracy_per_cam(
            vis_pred_2d, vis_true_cams, valid=valid)

    # add per-threshold metrics for delta_x and avg_jaccard
    for k, v in delta_x_dict.items(): 
        metrics[f'{prefix}delta_x_{k:.3g}'] = v

    for k, v in avg_jaccard_dict.items():
        metrics[f'{prefix}jaccard_{k:.3g}'] = v

    return metrics


def get_l1(coords_pred, coords_true, vis_true):
    '''Mean L1 norm of 3D tracking error for visible frames (TAPVid-3D).'''
    vis = np.squeeze(vis_true.astype(bool), axis=-1)          # B, T, N
    l1 = np.abs(coords_pred - coords_true).sum(axis=-1)       # B, T, N
    mask = vis & np.isfinite(l1)
    if not mask.any():
        return float('nan')
    return float(np.mean(l1[mask]))


def get_l1_world_coord(coords_pred, coords_true, vis_true, depths):
    """Depth-normalised L1: per-trajectory mean(L1_error) / mean_Z_traj.

    Mirrors the world-coord depth normalisation (per-trajectory mean Z_cam) used
    by all other world-coord metrics, making L1 comparable to D4RT reported values.
    """
    vis  = np.squeeze(vis_true.astype(bool), axis=-1)         # (B, T, N)
    l1   = np.abs(coords_pred - coords_true).sum(axis=-1)     # (B, T, N)
    d    = np.asarray(depths, dtype=np.float64)
    if d.ndim == 2:
        d = d[np.newaxis]                                      # (1, T, N)
    B, _, N = l1.shape
    track_vals = []
    for b in range(B):
        for n in range(N):
            mask     = vis[b, :, n] & np.isfinite(l1[b, :, n])
            depth_ok = (d[b, :, n] > 0) & np.isfinite(d[b, :, n])
            if not (mask & depth_ok).any():
                continue
            mean_z = float(np.mean(d[b, mask & depth_ok, n]))
            track_vals.append(float(np.mean(l1[b, mask, n]) / mean_z))
    return float(np.mean(track_vals)) if track_vals else float('nan')


def get_mte(coords_pred, coords_true, vis_true):
    '''
    Median Trajectory Error: per-track median L2 over visible timesteps,
    then mean across tracks (MVTracker definition).

    parameters:
        coords_pred: B, T, N, 3
        coords_true: B, T, N, 3
        vis_true:    B, T, N, 1  bool
    '''
    vis  = np.squeeze(vis_true.astype(bool), axis=-1)           # B, T, N
    dist = np.linalg.norm(coords_pred - coords_true, axis=-1)   # B, T, N
    B, T, N = dist.shape

    track_mtes = []
    for b in range(B):
        for n in range(N):
            visible = vis[b, :, n]
            if not np.any(visible):
                continue
            track_mtes.append(np.median(dist[b, visible, n]))

    if len(track_mtes) == 0:
        return np.nan
    
    return float(np.mean(track_mtes))


def get_occlusion_accuracy(vis_pred, vis_true, mask=None):
    '''
    parameters:
        vis_pred: B, T, N, 1  (raw logit)
        vis_true: B, T, N, 1  (bool)
        mask:     B, T, N, 1  (bool) frames to count; None -> all frames. Note the
                  mask must NOT be vis_true-derived (occluded frames must count too);
                  pass the finite/at-or-after `valid` mask.

    returns:
        occlusion_acc (float; NaN if no frames are counted)
    '''

    occlusion_pred = _sigmoid(vis_pred) < 0.5
    occlusion_true = ~vis_true

    correct = (occlusion_pred == occlusion_true)
    if mask is not None:
        correct = correct[mask]

    if correct.size == 0:
        return float('nan')
    return float(np.mean(correct))


def get_occlusion_accuracy_per_cam(vis_pred_2d, vis_true_cams, valid=None):
    '''Per-camera occlusion accuracy: parallels get_occlusion_accuracy on the camera axis.

    parameters:
        vis_pred_2d:   (cams, B, T, N) raw per-camera visibility logits.
        vis_true_cams: (B, T, N, cams) per-camera GT visibility; NaN = unknown (not counted).
        valid:         (B, T, N, 1) bool frame mask (finite GT + at/after query); None -> all.

    Predicted-occluded = sigmoid(logit) < 0.5. GT-occluded = (vis <= 0.5) where known.
    Accuracy is over {camera, valid, known} entries. Returns NaN if none.
    '''
    vp = _to_np(vis_pred_2d)                                # (cams, B, T, N)
    vt = _to_np(vis_true_cams)                              # (B, T, N, cams)
    vt = np.moveaxis(vt, -1, 0)                             # (cams, B, T, N)

    occlusion_pred = _sigmoid(vp) < 0.5                    # (cams, B, T, N)
    known = np.isfinite(vt)                                 # NaN -> unknown, excluded
    occlusion_true = vt <= 0.5                              # meaningful only where known

    mask = known
    if valid is not None:
        v = _to_np(valid).astype(bool)[..., 0]             # (B, T, N)
        mask = mask & v[None]                              # broadcast over cams

    correct = (occlusion_pred == occlusion_true)[mask]
    if correct.size == 0:
        return float('nan')
    return float(np.mean(correct))


def get_delta_x(coords_pred, coords_true, vis_true, threshold,
                cube_scale = None, multiplier = 1.0):
    '''
    for points that are visible, measures the fraction of
    points that are within a distance delta pixels from
    their ground truth

    parameters:
        coords_pred: B, T, N, 3
        coords_true: B, T, N, 3
        vis_true: B, T, N, 1
        cube_scale: optional (B,) world-units-per-pixel; when given the threshold is
            threshold * multiplier * cube_scale[b] (world units), i.e. a fixed PIXEL
            threshold comparable across datasets. None -> raw world-unit threshold.
    '''

    dist2 = np.sum((coords_pred - coords_true) ** 2, axis=-1)              # (B, T, N)
    if cube_scale is not None:
        B = coords_pred.shape[0]
        thr = (threshold * multiplier
               * np.asarray(cube_scale, dtype=np.float64).reshape(B, 1, 1))  # (B,1,1) world units
        within_thresh = dist2 < (thr ** 2)
    else:
        within_thresh = dist2 < (threshold ** 2)
    good = within_thresh[..., None] & vis_true
    delta_x = np.sum(good, axis = (0, 1, 2)) / np.sum(vis_true)

    return delta_x


def get_delta_x_avg(coords_pred, coords_true,
                    vis_true, thresholds = None,
                    cube_scale = None, multiplier = 1.0):

    delta_xs = []

    # initialize to default values
    if thresholds is None:
        thresholds = [1, 2, 4, 8, 16]

    for thresh in thresholds:

        delta_x = get_delta_x(
            coords_pred = coords_pred,
            coords_true = coords_true,
            vis_true = vis_true,
            threshold = thresh,
            cube_scale = cube_scale,
            multiplier = multiplier)

        delta_xs.append(delta_x)

    delta_x_avg = np.mean(delta_xs)
    delta_x_dict = dict(zip(thresholds, delta_xs))

    return delta_x_avg, delta_x_dict 


def _to_np(x):
    if isinstance(x, torch.Tensor):
        return x.detach().cpu().to(torch.float32).numpy()
    return np.asarray(x)


def get_metrics_by_horizon(coords_pred, coords_true, vis_true,
                           query_times=None, horizons=None, thresholds=None,
                           prefix='eval/', emit_all=False):
    '''
    Drift-vs-horizon: error and delta_x bucketed by temporal distance from the
    source/query frame, h = |t - t_src|. The aggregate delta_x_avg averages over
    all frames and HIDES drift; this exposes it.

    parameters:
        coords_pred: B, T, N, R
        coords_true: B, T, N, R
        vis_true:    B, T, N, 1  (bool; None -> finite(coords_true))
        query_times: B, N  source-frame index per track (None -> all 0, i.e. h=t)
        horizons:    list of integer horizons to report (default 1,2,4,8,16,24,32
                     clipped to < T)
        thresholds:  delta_x pixel/metric thresholds (default 1,2,4,8,16)
        emit_all:    when True, always emit every requested horizon key (NaN for
                     empty buckets) and mte_fwd/mte_bwd, so the key set is stable
                     across batches (required by average_metrics, which assumes
                     uniform keys). When False, empty buckets are skipped.

    returns a flat dict for logging:
        {prefix}mte_h{h}      = mean L2 over visible points at horizon h
        {prefix}delta_x_{x}_h{h}
        {prefix}n_h{h}        = #points in that bucket
        {prefix}mte_fwd / mte_bwd = mean L2 for h>0 vs h<0 (forward/backward asym.)
    '''
    cp = _to_np(coords_pred)
    ct = _to_np(coords_true)
    vt = (_to_np(vis_true) if vis_true is not None
          else np.isfinite(ct[..., :1])).astype(bool)
    B, T, N, _ = cp.shape

    if query_times is None:
        q = np.zeros((B, N), dtype=np.int64)
    else:
        q = _to_np(query_times).astype(np.int64).reshape(B, N)
    if thresholds is None:
        thresholds = [1, 2, 4, 8, 16]
    if horizons is None:
        horizons = [h for h in (1, 2, 4, 8, 16, 24, 32) if h < T]

    horizon = np.arange(T)[None, :, None] - q[:, None, :]   # B, T, N  (signed)
    absh = np.abs(horizon)
    vis = vt[..., 0]                                         # B, T, N
    err = np.linalg.norm(cp - ct, axis=-1)                  # B, T, N
    finite = np.isfinite(err)

    metrics = {}
    for h in horizons:
        sel = (absh == h) & vis & finite
        nsel = int(sel.sum())
        if nsel == 0 and not emit_all:
            continue
        e = err[sel]
        metrics[f'{prefix}mte_h{h}'] = float(np.mean(e)) if nsel else float('nan')
        for thr in thresholds:
            metrics[f'{prefix}delta_x_{thr:.3g}_h{h}'] = (
                float(np.mean(e < thr)) if nsel else float('nan'))
        metrics[f'{prefix}n_h{h}'] = nsel

    fwd = (horizon > 0) & vis & finite
    bwd = (horizon < 0) & vis & finite
    if fwd.any() or emit_all:
        metrics[f'{prefix}mte_fwd'] = float(np.mean(err[fwd])) if fwd.any() else float('nan')
    if bwd.any() or emit_all:
        metrics[f'{prefix}mte_bwd'] = float(np.mean(err[bwd])) if bwd.any() else float('nan')
    return metrics


def get_metrics_by_motion(coords_pred, coords_true, vis_true, query_times=None,
                          cube_scale=None, prefix='eval/'):
    '''Error binned by each point's DISPLACEMENT from its query frame, normalized by
    cube_scale (world-units-per-pixel) so "fast motion" is in pixel-equivalent units and
    comparable across datasets. This is the watchable "how good on fast motion" signal:
    mte_mo_{slow,med,fast,vfast} (median px error). Bins (px displacement-from-query):
    slow <4, med 4-16, fast 16-64, vfast >=64.

    cube_scale: (B,) world units per pixel (median over cameras); None -> 1 (raw units).
    Keys are STABLE (NaN for empty bins) so average_metrics can aggregate them.'''
    cp = _to_np(coords_pred)
    ct = _to_np(coords_true)
    vt = (_to_np(vis_true) if vis_true is not None else np.isfinite(ct[..., :1])).astype(bool)
    B, T, N, R = cp.shape
    q = (np.zeros((B, N), np.int64) if query_times is None
         else _to_np(query_times).astype(np.int64).reshape(B, N))
    cs = (_to_np(cube_scale).reshape(B) if cube_scale is not None else np.ones(B))
    cs = np.where(cs > 1e-9, cs, 1.0)[:, None, None]                       # (B,1,1)
    qidx = np.broadcast_to(q[:, None, :, None], (B, 1, N, R))
    qc = np.take_along_axis(ct, qidx, axis=1)                             # (B,1,N,R) GT at query
    disp = np.linalg.norm(ct - qc, axis=-1) / cs                         # (B,T,N) px-equiv
    err = np.linalg.norm(cp - ct, axis=-1) / cs
    vis = vt[..., 0]
    finite = np.isfinite(err) & np.isfinite(disp)
    metrics = {}
    for lo, hi, name in [(0, 4, 'slow'), (4, 16, 'med'), (16, 64, 'fast'), (64, 1e18, 'vfast')]:
        sel = (disp >= lo) & (disp < hi) & vis & finite
        n = int(sel.sum())
        metrics[f'{prefix}mte_mo_{name}'] = float(np.median(err[sel])) if n else float('nan')
    return metrics


def get_mpjpe(coords_pred, coords_true, vis_pred, vis_true, eps = 1e-8):
    ''' 
    calculates the mean per joint position error for all 
    keypoints (pixels for 2d, mm for 3d) and timepoints
    in a batch

    parameters: 
        coords_pred: B, T, N, 3
        coords_true: B, T, N, 3
        vis_pred: B, T, N, 1
        vis_true: B, T, N, 1
        eps: a small constant to prevent divide by zero errors
    '''

    # mask = (vis_pred > 0.5) & vis_true
    mask = vis_true
    valid_mask = np.squeeze(mask, axis = -1)

    error_per_kpt = np.linalg.norm(coords_pred - coords_true, axis = -1, keepdims = False)
    error = np.nansum(error_per_kpt, axis = -1) / (np.sum(valid_mask, axis = -1) + eps)
    
    mask = np.sum(valid_mask, axis = -1) == 0
    error[mask] = np.nan

    mpjpe = np.nanmean(error)

    return mpjpe


def get_survival_rate(coords_pred, coords_true, vis_true, threshold = 50):
    '''
    Average frames-until-failure as a ratio of video length, where failure
    is defined as L2 distance exceeding `threshold` on a visible frame.
    Tracks that never fail contribute a ratio of 1.0.
    Only tracks with at least one visible GT frame are counted.

    parameters:
        coords_pred: B, T, N, 3
        coords_true: B, T, N, 3
        vis_true:    B, T, N, 1  bool
        threshold:   failure distance (default 50px at 256x256 resolution)

    returns:
        survival_rate (float) in [0, 1]
    '''
    vis = np.squeeze(vis_true.astype(bool), axis=-1)           # B, T, N
    dist = np.linalg.norm(coords_pred - coords_true, axis=-1)  # B, T, N
    B, T, N = dist.shape

    survival_ratios = []
    for b in range(B):
        for n in range(N):
            if not np.any(vis[b, :, n]):
                continue  # no visible GT frames, skip
            # failure: visible frame where L2 exceeds threshold
            failed_frames = np.where((dist[b, :, n] > threshold) & vis[b, :, n])[0]
            if len(failed_frames) == 0:
                frames_survived = T
            else:
                frames_survived = int(failed_frames[0])  # frames before first failure
            survival_ratios.append(frames_survived / T)

    if len(survival_ratios) == 0:
        return np.nan
    return float(np.mean(survival_ratios))


def get_average_jaccard(coords_pred, coords_true, vis_pred, vis_true, thresholds=None,
                        cube_scale=None, multiplier=1.0):
    '''
    Average Jaccard (MVTracker / TAP-Vid definition).

    Per track i, per threshold x:
        numerator   = sum_t( v_t * v̂_t * α_t )
        denominator = sum_t( v_t + (1−v_t)*v̂_t + v_t*v̂_t*(1−α_t) )
        AJ^i_x = numerator / denominator

    "Both occluded" frames contribute 0 to both — excluded from the ratio.
    AJ per threshold = mean over tracks. AJ = mean over thresholds.

    parameters:
        coords_pred: B, T, N, 3
        coords_true: B, T, N, 3
        vis_pred:    B, T, N, 1  float in [0, 1]
        vis_true:    B, T, N, 1  bool
        cube_scale:  optional (B,) world-units-per-pixel; when given, the closeness
            threshold per track b is thresh * multiplier * cube_scale[b] world units
            (a fixed PIXEL threshold, comparable across datasets, matching delta_x).
    '''
    if thresholds is None:
        thresholds = [1, 2, 4, 8, 16]

    gt_vis  = np.squeeze(vis_true.astype(bool),  axis=-1)   # B, T, N
    pred_vis = np.squeeze(_sigmoid(vis_pred) > 0.5, axis=-1) # B, T, N
    dist    = np.linalg.norm(coords_pred - coords_true, axis=-1)  # B, T, N
    B, T, N = dist.shape
    cs = (np.asarray(cube_scale, dtype=np.float64).reshape(B) if cube_scale is not None
          else np.ones(B))

    per_thresh = {t: [] for t in thresholds}

    for b in range(B):
        for n in range(N):
            vt = gt_vis[b, :, n]    # (T,)
            vh = pred_vis[b, :, n]  # (T,)
            d  = dist[b, :, n]      # (T,)

            for thresh in thresholds:
                alpha = d < (thresh * multiplier * cs[b])  # (T,) bool; cs[b]=1 if no cube_scale

                tp    = np.sum(vt & vh & alpha)
                denom = np.sum(vt) + np.sum(~vt & vh) + np.sum(vt & vh & ~alpha)

                if denom == 0:
                    continue  # all frames both occluded — skip track at this threshold
                per_thresh[thresh].append(float(tp / denom))

    jaccard_dict = {
        t: float(np.mean(vals)) if vals else np.nan
        for t, vals in per_thresh.items()
    }
    aj = float(np.nanmean(list(jaccard_dict.values())))
    return aj, jaccard_dict


# ── Per-trajectory variants of all-points-pooled metrics ─────────────────────
#
# delta_x and occlusion_acc pool over all (point, frame) pairs by default, which
# weights long tracks more heavily.  These variants give every track equal weight,
# matching the MVTracker "Our Metrics" convention.
# Note: get_average_jaccard is already per-trajectory, so avg_jaccard needs no
# separate variant.
# ─────────────────────────────────────────────────────────────────────────────

def get_delta_x_pertraj(coords_pred, coords_true, vis_true, threshold):
    """Fraction of visible frames within threshold, averaged per trajectory."""
    dist2 = np.sum((coords_pred - coords_true) ** 2, axis=-1)    # (B, T, N)
    within = dist2 < (threshold ** 2)
    vis = np.squeeze(vis_true.astype(bool), axis=-1)              # (B, T, N)
    B, _, N = dist2.shape
    track_accs = []
    for b in range(B):
        for n in range(N):
            v = vis[b, :, n]
            if not v.any():
                continue
            track_accs.append(float(within[b, v, n].mean()))
    return float(np.mean(track_accs)) if track_accs else float('nan')


def get_delta_x_avg_pertraj(coords_pred, coords_true, vis_true, thresholds=None):
    """Per-trajectory delta_x averaged over thresholds."""
    if thresholds is None:
        thresholds = [1, 2, 4, 8, 16]
    results = [get_delta_x_pertraj(coords_pred, coords_true, vis_true, th)
               for th in thresholds]
    return float(np.nanmean(results)), dict(zip(thresholds, results))


def get_occlusion_accuracy_pertraj(vis_pred, vis_true, mask=None):
    """Occlusion accuracy averaged per trajectory (equal weight per track)."""
    occ_pred = _sigmoid(vis_pred) < 0.5                           # (B, T, N, 1)
    occ_true = ~vis_true                                          # (B, T, N, 1)
    correct = np.squeeze(occ_pred == occ_true, axis=-1)          # (B, T, N)
    if mask is not None:
        valid = np.squeeze(np.asarray(mask).astype(bool), axis=-1)
    else:
        valid = np.ones(correct.shape, dtype=bool)
    B, _, N = correct.shape
    track_accs = []
    for b in range(B):
        for n in range(N):
            m = valid[b, :, n]
            if not m.any():
                continue
            track_accs.append(float(correct[b, m, n].mean()))
    return float(np.mean(track_accs)) if track_accs else float('nan')


# ── TAPVid-3D depth-relative metrics ─────────────────────────────────────────
#
# Both camera-coordinate (cam) and world-coordinate (world) metrics use the same
# fixed thresholds δ ∈ {0.01, 0.04, 0.16, 0.64, 2.56} from the TAPVid-3D
# supplemental.  A point is within threshold δ when:
#
#   dist / Z_depth < δ  (equivalently: dist < Z_depth * δ)
#
# where dist is the 3D Euclidean prediction error and Z_depth is depth:
#
#   cam-coord  — per-point per-frame Z_cam(t, i): the z-component of the GT
#                point in the camera frame at frame t.  Requires the world→cam
#                extrinsic.  Normalization is fine-grained (each frame has its
#                own scale).
#
#   world-coord (D4RT) — per-trajectory mean depth: mean of Z_cam over all
#                visible frames of that track.  One scale per trajectory, so the
#                metric is comparable to the training-loss depth normalisation.
#                PStudio is excluded (no camera motion → undefined world coord).
#
# Note: losses.py normalises by mean L2 distance from camera center (all T×N)
# for training-loss scale invariance.  Here we need the z-component from the
# extrinsic, which is NOT the same as L2 for off-axis points.
# ──────────────────────────────────────────────────────────────────────────────

def compute_cam_depths(coords_true_world, ext):
    """Z-component (depth) of world-frame GT points in camera frame.

    Args:
        coords_true_world: (T, N, 3) world-frame coords (may contain NaN)
        ext: (4, 4) static world→cam extrinsic, or (T_full, 4, 4) per-frame.
             When per-frame and T_full > T, only the first T rows are used.
    Returns:
        depths: (T, N) z-component in camera frame (NaN propagates from inputs)
    """
    ext = np.asarray(ext, dtype=np.float64)
    P   = np.asarray(coords_true_world, dtype=np.float64)    # (T, N, 3)
    T   = P.shape[0]
    if ext.ndim == 2:
        R = ext[:3, :3]                                       # (3, 3)
        t = ext[:3, 3]                                        # (3,)
        P_cam = P @ R.T + t                                   # (T, N, 3)
    else:
        R = ext[:T, :3, :3]                                   # (T, 3, 3)
        t = ext[:T, :3, 3]                                    # (T, 3)
        P_cam = np.einsum('tij,tnj->tni', R, P) + t[:, np.newaxis, :]   # (T, N, 3)
    return P_cam[..., 2]                                      # (T, N)


# ── Camera-coordinate metrics (per-point per-frame depth normalization) ───────

def get_delta_x_depth_relative(coords_pred, coords_true, vis_true,
                                threshold_m, depths):
    """APD for one threshold using per-point per-frame depth normalization.

    A point at frame t is 'within threshold' when dist / Z_cam(t) < threshold_m.

    Args:
        coords_pred, coords_true: (B, T, N, 3)
        vis_true: (B, T, N, 1) bool
        threshold_m: scalar threshold (e.g. 0.01, 0.04, ... from TAPVid-3D supplemental)
        depths: (B, T, N) or (T, N) GT z-depth in camera frame
    """
    dist2 = np.sum((coords_pred - coords_true) ** 2, axis=-1)    # (B, T, N)
    d = np.asarray(depths, dtype=np.float64)
    if d.ndim == 2:
        d = d[np.newaxis]                                          # (1, T, N)
    thr   = np.clip(d, 0.0, None) * threshold_m                   # (B, T, N)
    good  = (dist2 < thr ** 2)[..., np.newaxis] & vis_true
    total = np.sum(vis_true)
    return float(np.sum(good) / total) if total > 0 else float('nan')


def get_delta_x_avg_depth_relative(coords_pred, coords_true, vis_true,
                                    thresholds_m, depths):
    """Average depth-relative APD over a list of thresholds."""
    results = [
        get_delta_x_depth_relative(coords_pred, coords_true, vis_true,
                                   th, depths)
        for th in thresholds_m
    ]
    return float(np.nanmean(results)), dict(zip(thresholds_m, results))


def get_mte_cam(coords_pred, coords_true, vis_eff, depths):
    """Depth-normalised MTE: per-track median(dist / Z_cam), then mean over tracks.

    Dimensionless — expresses error as a fraction of the point's depth.
    Frames with non-positive or NaN depth are excluded regardless of visibility.

    Args:
        coords_pred, coords_true: (B, T, N, 3)
        vis_eff: (B, T, N, 1) bool (visible AND valid = finite GT)
        depths: (B, T, N) or (T, N) GT depth (z-component in camera frame)
    """
    d   = np.asarray(depths, dtype=np.float64)
    if d.ndim == 2:
        d = d[np.newaxis]                                          # (1, T, N)
    vis  = np.squeeze(vis_eff.astype(bool), axis=-1)              # (B, T, N)
    dist = np.linalg.norm(coords_pred - coords_true, axis=-1)     # (B, T, N)
    ok   = (d > 0) & np.isfinite(d)
    B, _, N = dist.shape
    track_mtes = []
    for b in range(B):
        for n in range(N):
            mask = vis[b, :, n] & ok[b, :, n]
            if not mask.any():
                continue
            track_mtes.append(float(np.median(dist[b, mask, n] / d[b, mask, n])))
    return float(np.mean(track_mtes)) if track_mtes else float('nan')


def get_survival_rate_depth_relative(coords_pred, coords_true, vis_true,
                                      depths, threshold_m):
    """Survival rate with a per-frame depth-relative failure threshold.

    A track fails at frame t when it is visible and dist[t] / Z_cam[t] > threshold_m.
    """
    d   = np.asarray(depths, dtype=np.float64)
    if d.ndim == 2:
        d = d[np.newaxis]                                          # (1, T, N)
    vis  = np.squeeze(vis_true.astype(bool), axis=-1)             # (B, T, N)
    dist = np.linalg.norm(coords_pred - coords_true, axis=-1)     # (B, T, N)
    thr  = np.clip(d, 0.0, None) * threshold_m                    # (B, T, N)
    B, T, N = dist.shape
    ratios = []
    for b in range(B):
        for n in range(N):
            if not vis[b, :, n].any():
                continue
            failed = np.where(vis[b, :, n] & (dist[b, :, n] > thr[b, :, n]))[0]
            ratios.append(int(failed[0]) / T if len(failed) else 1.0)
    return float(np.mean(ratios)) if ratios else float('nan')


def get_average_jaccard_depth_relative(coords_pred, coords_true, vis_pred, vis_true,
                                        thresholds_m, depths):
    """Average Jaccard with per-point per-frame depth-relative thresholds.

    Closeness threshold per point at frame t is Z_cam[t] * threshold_m.
    """
    d        = np.asarray(depths, dtype=np.float64)
    if d.ndim == 2:
        d = d[np.newaxis]                                          # (1, T, N)
    gt_vis   = np.squeeze(vis_true.astype(bool),    axis=-1)      # (B, T, N)
    pred_vis = np.squeeze(_sigmoid(vis_pred) > 0.5, axis=-1)      # (B, T, N)
    dist     = np.linalg.norm(coords_pred - coords_true, axis=-1) # (B, T, N)
    B, _, N  = dist.shape
    per_thresh = {th: [] for th in thresholds_m}
    for b in range(B):
        for n in range(N):
            vt   = gt_vis[b, :, n]
            vh   = pred_vis[b, :, n]
            dd   = dist[b, :, n]
            thr  = np.clip(d[b, :, n], 0.0, None)                 # (T,)
            for th in thresholds_m:
                alpha = dd < (thr * th)
                tp    = np.sum(vt & vh & alpha)
                denom = np.sum(vt) + np.sum(~vt & vh) + np.sum(vt & vh & ~alpha)
                if denom == 0:
                    continue
                per_thresh[th].append(float(tp / denom))
    jaccard_dict = {
        th: float(np.mean(vals)) if vals else float('nan')
        for th, vals in per_thresh.items()
    }
    return float(np.nanmean(list(jaccard_dict.values()))), jaccard_dict


# ── World-coordinate metrics (per-trajectory mean-depth normalization) ────────

def get_delta_x_world_coord(coords_pred, coords_true, vis_true,
                             threshold_m, depths):
    """APD for one threshold using per-trajectory mean-depth normalization.

    A point in trajectory n is 'within threshold' when dist / mean_Z_traj < threshold_m,
    where mean_Z_traj = mean of Z_cam over all visible frames of that track.
    """
    d   = np.asarray(depths, dtype=np.float64)
    if d.ndim == 2:
        d = d[np.newaxis]                                          # (1, T, N)
    vis  = np.squeeze(vis_true.astype(bool), axis=-1)             # (B, T, N)
    dist2 = np.sum((coords_pred - coords_true) ** 2, axis=-1)     # (B, T, N)
    B, _, N = dist2.shape
    n_good = 0
    n_total = 0
    for b in range(B):
        for n in range(N):
            mask = vis[b, :, n] & (d[b, :, n] > 0) & np.isfinite(d[b, :, n])
            if not mask.any():
                continue
            mean_z = float(np.mean(d[b, mask, n]))
            thr2   = (mean_z * threshold_m) ** 2
            n_good  += int(np.sum(dist2[b, mask, n] < thr2))
            n_total += int(np.sum(mask))
    return float(n_good / n_total) if n_total > 0 else float('nan')


def get_delta_x_avg_world_coord(coords_pred, coords_true, vis_true,
                                 thresholds_m, depths):
    """Average world-coord APD over a list of thresholds."""
    results = [
        get_delta_x_world_coord(coords_pred, coords_true, vis_true, th, depths)
        for th in thresholds_m
    ]
    return float(np.nanmean(results)), dict(zip(thresholds_m, results))


def get_mte_world_coord(coords_pred, coords_true, vis_eff, depths):
    """Depth-normalised MTE with per-trajectory mean-depth normalization.

    Per track: median(dist) / mean_Z_traj over visible frames.
    """
    d   = np.asarray(depths, dtype=np.float64)
    if d.ndim == 2:
        d = d[np.newaxis]
    vis  = np.squeeze(vis_eff.astype(bool), axis=-1)              # (B, T, N)
    dist = np.linalg.norm(coords_pred - coords_true, axis=-1)     # (B, T, N)
    B, _, N = dist.shape
    track_mtes = []
    for b in range(B):
        for n in range(N):
            mask = vis[b, :, n] & (d[b, :, n] > 0) & np.isfinite(d[b, :, n])
            if not mask.any():
                continue
            mean_z = float(np.mean(d[b, mask, n]))
            track_mtes.append(float(np.median(dist[b, mask, n]) / mean_z))
    return float(np.mean(track_mtes)) if track_mtes else float('nan')


def get_survival_rate_world_coord(coords_pred, coords_true, vis_true,
                                   depths, threshold_m):
    """Survival rate with a per-trajectory mean-depth failure threshold.

    A track fails at frame t when it is visible and dist[t] / mean_Z_traj > threshold_m.
    """
    d   = np.asarray(depths, dtype=np.float64)
    if d.ndim == 2:
        d = d[np.newaxis]
    vis  = np.squeeze(vis_true.astype(bool), axis=-1)             # (B, T, N)
    dist = np.linalg.norm(coords_pred - coords_true, axis=-1)     # (B, T, N)
    B, T, N = dist.shape
    ratios = []
    for b in range(B):
        for n in range(N):
            if not vis[b, :, n].any():
                continue
            depth_ok = (d[b, :, n] > 0) & np.isfinite(d[b, :, n])
            if not depth_ok.any():
                continue
            mean_z = float(np.mean(d[b, depth_ok, n]))
            thr    = mean_z * threshold_m
            failed = np.where(vis[b, :, n] & (dist[b, :, n] > thr))[0]
            ratios.append(int(failed[0]) / T if len(failed) else 1.0)
    return float(np.mean(ratios)) if ratios else float('nan')


def get_average_jaccard_world_coord(coords_pred, coords_true, vis_pred, vis_true,
                                     thresholds_m, depths):
    """Average Jaccard with per-trajectory mean-depth normalization."""
    d        = np.asarray(depths, dtype=np.float64)
    if d.ndim == 2:
        d = d[np.newaxis]
    gt_vis   = np.squeeze(vis_true.astype(bool),    axis=-1)      # (B, T, N)
    pred_vis = np.squeeze(_sigmoid(vis_pred) > 0.5, axis=-1)      # (B, T, N)
    dist     = np.linalg.norm(coords_pred - coords_true, axis=-1) # (B, T, N)
    B, _, N  = dist.shape
    per_thresh = {th: [] for th in thresholds_m}
    for b in range(B):
        for n in range(N):
            vt      = gt_vis[b, :, n]
            vh      = pred_vis[b, :, n]
            dd      = dist[b, :, n]
            depth_ok = (d[b, :, n] > 0) & np.isfinite(d[b, :, n]) & vt
            if not depth_ok.any():
                continue
            mean_z  = float(np.mean(d[b, depth_ok, n]))
            for th in thresholds_m:
                alpha = dd < (mean_z * th)
                tp    = np.sum(vt & vh & alpha)
                denom = np.sum(vt) + np.sum(~vt & vh) + np.sum(vt & vh & ~alpha)
                if denom == 0:
                    continue
                per_thresh[th].append(float(tp / denom))
    jaccard_dict = {
        th: float(np.mean(vals)) if vals else float('nan')
        for th, vals in per_thresh.items()
    }
    return float(np.nanmean(list(jaccard_dict.values()))), jaccard_dict
