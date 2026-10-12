import torch
import numpy as np

import torch.nn as nn
import torch.nn.functional as F

from einops import rearrange, repeat, einsum
from posetail.posetail.cube import get_camera_scale, project_points_torch, is_point_visible
from posetail.posetail.cube import to_homogeneous, from_homogeneous, signed_log1p, solve_scale_offset

from collections import defaultdict


def coordinate_softmax_loss(logits, target_xy, vis_mask, pixel_size=None):
    """Cross-entropy on per-axis 2D position logits vs target pixels — the primary
    2D objective in upstream TAPNext++ (torch_losses.coordinate_softmax). The
    soft-argmax track-head emits ``2*P`` logits = [P x-bins | P y-bins]; we quantize
    the target pixel (minus the 0.5 bin-centre offset the head adds) to a bin index
    and apply masked CE. ``logits`` (..., 2P); ``target_xy`` (..., 2) pixels (x,y);
    ``vis_mask`` (..., 1). Returns a scalar (unweighted).

    ``pixel_size`` (the clamp bound) DEFAULTS TO P, derived from the logits themselves. It used
    to default to a hardcoded 256 while every caller omitted it and P is really ``image_size``:
    above 256 that silently collapsed every target beyond bin 255, and below 256 the clamp could
    emit an index >= P and crash cross_entropy. Deriving it from the logits makes the two agree
    by construction. Passing it explicitly is still honoured."""
    P = logits.shape[-1] // 2
    if pixel_size is None:
        pixel_size = P
    logits_x, logits_y = logits[..., :P], logits[..., P:]
    finite = torch.isfinite(target_xy).all(dim=-1)
    valid = (vis_mask[..., 0] > 0.5) & finite
    tx = torch.round((torch.where(torch.isfinite(target_xy[..., 0]),
                                  target_xy[..., 0], torch.zeros_like(target_xy[..., 0])) - 0.5)
                     ).clamp(0, pixel_size - 1).long()
    ty = torch.round((torch.where(torch.isfinite(target_xy[..., 1]),
                                  target_xy[..., 1], torch.zeros_like(target_xy[..., 1])) - 0.5)
                     ).clamp(0, pixel_size - 1).long()
    ce_x = F.cross_entropy(logits_x.reshape(-1, P), tx.reshape(-1), reduction='none')
    ce_y = F.cross_entropy(logits_y.reshape(-1, P), ty.reshape(-1), reduction='none')
    ce = (ce_x + ce_y).reshape(valid.shape)
    vf = valid.float()
    return (ce * vf).sum() / (vf.sum() + 1e-6)


def grid_softmax_loss(logits, target_values, lo, hi, vis_mask):
    """Cross-entropy over a fixed bin grid for each coordinate dim — the grid-mode
    analogue of ``coordinate_softmax_loss`` for the 3D (D=3) and depth (D=1) heads.
    The bins are ``linspace(lo, hi, K)``; the continuous target is quantized to its
    nearest bin and supervised with masked CE. ``logits`` (..., D, K);
    ``target_values`` (..., D); ``vis_mask`` (..., 1). Returns a scalar (unweighted)."""
    K = logits.shape[-1]
    finite = torch.isfinite(target_values)
    safe = torch.where(finite, target_values, torch.full_like(target_values, lo))
    idx = torch.round((safe - lo) / (hi - lo) * (K - 1)).clamp(0, K - 1).long()  # (...,D)
    ce = F.cross_entropy(logits.reshape(-1, K), idx.reshape(-1),
                         reduction='none').reshape(idx.shape)                     # (...,D)
    valid = (vis_mask > 0.5) & finite                                            # (...,D) bcast
    vf = valid.float()
    return (ce * vf).sum() / (vf.sum() + 1e-6)


def normalize_by_mean_depth(x, vis, C, eps=1e-6):
    """
    x:    (..., 3) world/cam-frame points or (..., 1) raw depths
    vis:  (..., 1) visibility mask, same leading dims
    C:    broadcastable camera center (or 0.0 if x is already a depth scalar)
    Returns (x_normalized, mean_depth):
      mean_depth = (||x − C|| · vis).sum / vis.sum, pooled over (T, N) per (cam, B)
      x_normalized = (x − C) / mean_depth   (or x / mean_depth for scalar depth)
    """
    if x.shape[-1] == 3:
        d = torch.linalg.norm(x - C, dim=-1, keepdim=True)
        offset = C
    else:
        d = x
        offset = 0.0
    # Excise NaN before the reduction: a single missing keypoint-frame would make
    # NaN * 0 = NaN, contaminating the whole (cam, B) mean_depth via .sum().
    valid = (vis > 0.5) & torch.isfinite(d)
    d_safe = torch.where(valid, d, torch.zeros_like(d))
    vis_f = valid.float()
    mean_depth = d_safe.sum(dim=(-3, -2), keepdim=True) / (vis_f.sum(dim=(-3, -2), keepdim=True) + eps)
    # Keep NaN out of the normalized output too (loss masks these positions anyway).
    x_safe = torch.where(torch.isfinite(x), x, torch.zeros_like(x))
    return (x_safe - offset) / (mean_depth + eps), mean_depth


class TotalLoss(nn.Module):

    def __init__(self, gamma = 0.8, pixel_thresh = 12, delta = 6,
                 use_huber_loss = False, vis_loss_weight = 1,
                 vis_loss_3d_weight = 0.0,
                 conf_loss_weight = 1, coords_loss_weight = 1,
                 occluded_coords_loss_weight = 1,
                 feature_loss_weight = 0.5,
                 coords_loss_direct_weight = 0.1,
                 coords_loss_rays_weight = 0.001,
                 coords_loss_triangulate_weight = 0.1,
                 coords_loss_2d_weight = 1,
                 coords_loss_depth_weight = 1,
                 coords_loss_direct_reproj_weight = 0.0,
                 coords_loss_rays_reproj_weight = 0.0,
                 coords_loss_triangulate_reproj_weight = 0.0,
                 conf_2d_loss_weight = 0,
                 per_camera_cube_scale = False,
                 smoothness_loss_3d_weight = 0,
                 smoothness_loss_2d_weight = 0,
                 smoothness_loss_order = 4,
                 smoothness_loss_tolerance = 1.0,
                 coords_3d_loss_scale = 1.0,
                 cube_scale_floor = 0.0,
                 coords_softmax_2d_weight = 0.0,
                 coords_softmax_3d_weight = 0.0,
                 depth_softmax_weight = 0.0):
        super().__init__()

        self.gamma = gamma
        self.pixel_thresh = pixel_thresh
        self.delta = delta

        self.use_huber_loss = use_huber_loss

        # weight for each loss (0 to not use or compute)
        self.vis_loss_weight = vis_loss_weight
        self.vis_loss_3d_weight = vis_loss_3d_weight
        self.conf_loss_weight = conf_loss_weight
        self.coords_loss_weight = coords_loss_weight
        self.occluded_coords_loss_weight = occluded_coords_loss_weight
        self.feature_loss_weight = feature_loss_weight

        self.conf_2d_loss_weight = conf_2d_loss_weight

        self.coords_loss_direct_weight = coords_loss_direct_weight
        self.coords_loss_rays_weight = coords_loss_rays_weight
        self.coords_loss_triangulate_weight = coords_loss_triangulate_weight
        self.coords_loss_2d_weight = coords_loss_2d_weight
        self.coords_loss_depth_weight = coords_loss_depth_weight
        self.coords_loss_direct_reproj_weight = coords_loss_direct_reproj_weight
        self.coords_loss_rays_reproj_weight = coords_loss_rays_reproj_weight
        self.coords_loss_triangulate_reproj_weight = coords_loss_triangulate_reproj_weight
        self.per_camera_cube_scale = per_camera_cube_scale

        self.smoothness_loss_3d_weight = smoothness_loss_3d_weight
        self.smoothness_loss_2d_weight = smoothness_loss_2d_weight
        self.smoothness_loss_order = smoothness_loss_order
        self.smoothness_loss_tolerance = smoothness_loss_tolerance

        # Constant, metric-preserving rescale of the regular (multi-cam) 3D loss
        # branch. The regular branch measures absolute coordinate error / cube_scale
        # (~0.11), which runs ~500x hotter than the per-scene-normalized 2D-query
        # branch and dominates the gradient (corrupting the frozen 2D heads). We
        # cannot normalize per scene/camera in the multi-cam case (it breaks
        # cross-camera metric consistency), so we divide the regular-3D losses by a
        # single global constant to match magnitudes while keeping absolute depth.
        self.coords_3d_loss_scale = coords_3d_loss_scale

        # Floor on per-camera cube_scale before it normalizes the regular-3D loss
        # error (_compute_loss now divides the error by cube_scale *before* the Huber,
        # so a collapsed cube_scale is squared; coords_3d_loss_scale is applied after).
        # A degenerate crop (few near-coplanar points) makes the projection-Jacobian
        # SVD blow up -> cube_scale = 1/sensitivity collapses toward 0 -> the normalized
        # error (and depth/3d loss) spikes. Huber's linear regime caps the per-element
        # gradient, but clamping cube_scale from below removes the spike at the source.
        # Catastrophic spikes are all at cube_scale < ~0.02; the [0.02,0.05) band is
        # already clean. 0.0 disables (legacy behavior).
        self.cube_scale_floor = cube_scale_floor

        # Direct logit-classification objectives (cross-entropy on the position bins),
        # mirroring upstream TAPNext++'s primary 2D loss. The 2D term supervises the
        # pretrained track logits; the 3D/depth terms supervise the grid heads' bins
        # (only fire when the model is in "grid" output_mode -> emits 'grid' / '2d_logits').
        self.coords_softmax_2d_weight = coords_softmax_2d_weight
        self.coords_softmax_3d_weight = coords_softmax_3d_weight
        self.depth_softmax_weight = depth_softmax_weight

        self.bce_loss_vis = BCELossVis(
            gamma = self.gamma,
            weight = self.vis_loss_weight
        )

        # separate-weight BCE for the aggregated 3D visibility (noisy-OR logit
        # over cameras). weight 0 -> returns nan -> dropped from total_loss, so
        # this is inert until a config opts in via vis_loss_3d_weight.
        self.bce_loss_vis_3d = BCELossVis(
            gamma = self.gamma,
            weight = self.vis_loss_3d_weight
        )

        self.bce_loss_conf = BCELossConf(
            gamma = self.gamma, 
            pixel_thresh = self.pixel_thresh, 
            weight = self.conf_loss_weight
        )

        self.mae_loss_coords = WeightedMAELoss(
            gamma = self.gamma, 
            delta = self.delta, 
            use_huber_loss = self.use_huber_loss, 
            weight = self.coords_loss_weight
        )

        self.mae_loss_coords_direct = WeightedMAELoss(
            gamma = self.gamma, 
            delta = self.delta, 
            use_huber_loss = self.use_huber_loss, 
            weight = self.coords_loss_direct_weight
        )

        self.mae_loss_coords_rays = WeightedMAELoss(
            gamma = self.gamma, 
            delta = self.delta, 
            use_huber_loss = self.use_huber_loss, 
            weight = self.coords_loss_rays_weight
        )

        self.mae_loss_coords_triangulate = WeightedMAELoss(
            gamma = self.gamma, 
            delta = self.delta, 
            use_huber_loss = self.use_huber_loss, 
            weight = self.coords_loss_triangulate_weight
        )
        
        self.mae_loss_coords_2d = WeightedMAELoss(
            gamma = self.gamma,
            delta = 16,
            use_huber_loss = True,
            weight = self.coords_loss_2d_weight / 16.0
        )

        # Reprojection of the fused 3D predictions back into each camera, supervised
        # in pixel space against the projected GT. Multi-view consistency constrains
        # depth-of-motion without any SVD/triangulation (no grad spikes). Pixel-space
        # ⇒ mirror mae_loss_coords_2d (delta=16, huber, weight / 16).
        self.mae_loss_direct_reproj = WeightedMAELoss(
            gamma = self.gamma,
            delta = 16,
            use_huber_loss = True,
            weight = self.coords_loss_direct_reproj_weight / 16.0
        )

        self.mae_loss_rays_reproj = WeightedMAELoss(
            gamma = self.gamma,
            delta = 16,
            use_huber_loss = True,
            weight = self.coords_loss_rays_reproj_weight / 16.0
        )

        # Reproject the *triangulated* 3D point into each camera and supervise in pixels.
        # The triangulation's ill-conditioned direction (depth-of-motion for small-baseline /
        # far-from-scene geometry) is exactly the direction reprojection is insensitive to, so
        # the gradient stays bounded regardless of conditioning -- unlike the direct
        # 3d_triangulate loss whose gradient ~ 1/parallax^2. Upweight this instead of
        # 3d_triangulate when triangulation supervision is wanted. Mirror direct_reproj.
        self.mae_loss_triangulate_reproj = WeightedMAELoss(
            gamma = self.gamma,
            delta = 16,
            use_huber_loss = True,
            weight = self.coords_loss_triangulate_reproj_weight / 16.0
        )

        self.mae_loss_coords_depth = WeightedMAELoss(
            gamma = self.gamma, 
            delta = self.delta, 
            use_huber_loss = self.use_huber_loss, 
            weight = self.coords_loss_depth_weight
        )
        
        self.mae_loss_occluded_coords = WeightedMAELoss(
            gamma = self.gamma, 
            delta = self.delta, 
            use_huber_loss = self.use_huber_loss, 
            weight = self.occluded_coords_loss_weight
        )

        # self.mae_loss_occluded_coords_2d = WeightedMAELoss(
        #     gamma = self.gamma, 
        #     delta = 16, 
        #     use_huber_loss = True,
        #     weight = self.occluded_coords_loss_weight * 10 / 16.0
        # )
        
        self.bce_loss_conf_2d = BCELossConf(
            gamma = self.gamma,
            pixel_thresh = self.pixel_thresh,
            weight = self.conf_2d_loss_weight
        )

        self.feature_loss = FeatureLoss(
            weight = self.feature_loss_weight)

        self.smoothness_loss_3d = SmoothnessLoss(
            order = self.smoothness_loss_order,
            weight = self.smoothness_loss_3d_weight,
            tolerance = self.smoothness_loss_tolerance
        )

        self.smoothness_loss_2d = SmoothnessLoss(
            order = self.smoothness_loss_order,
            weight = self.smoothness_loss_2d_weight,
            tolerance = self.smoothness_loss_tolerance
        )

        # loss_names = ['vis_loss', 'conf_loss',
        #               'occluded_coords_loss', 'coords_loss',
        #               '2d_loss', 'depth_loss',
        #               # 'feature_loss','bad_feature_loss',
        #               'total_loss', 'cube_scale']
        # self.loss_history = {loss_name: [] for loss_name in loss_names}
        self.loss_history = defaultdict(list)
        
    def collapse_history(self, prefix = ''): 
        
        loss_summary = {}

        for name, losses in self.loss_history.items():
            loss_summary[f'{prefix}{name}'] = float(np.nanmean(losses))
            
        return loss_summary

    def reset_history(self):
        self.loss_history = {name: [] for name in list(self.loss_history.keys())}

    def _warn_unconsumed_weights(self, model, outputs):
        """Warn once for a nonzero loss weight whose gating output the model never emits.

        Both weights below are live, settable constructor arguments that simply never fire with a
        TrackerEncoder: `coords_pred_iters` survives there only as a commented-out block and
        `feature_planes_levels` is emitted by the OTHER model class (tracker.py) alone. Without
        this a user sets feature_loss_weight=0.5, sees no error, watches the loss go down, and
        concludes the term is doing something.
        """
        if getattr(self, '_warned_unconsumed', False):
            return
        self._warned_unconsumed = True

        model_name = type(model).__name__
        for weight, attr, key in (
            (getattr(self, 'feature_loss_weight', 0), 'feature_loss_weight',
             'feature_planes_levels'),
            (getattr(self, 'gamma', 0) if 'coords_pred_iters' not in outputs else 0,
             'gamma (iteration-decay weights)', 'coords_pred_iters'),
        ):
            if weight and key not in outputs:
                print(f'  [warn] {attr}={weight} is nonzero but {model_name} never emits '
                      f"'{key}', so the term can never fire. It is silently inert.")


    def forward(self, model, outputs, coords_true,
                vis_true, vis_true_cams, cgroup=None, p2d=None, device=None):

        # vis_true / vis_true_cams are BOTH-OR-NEITHER, and the two one-sided cases fail
        # differently -- one loudly, one silently, which is why this is checked here:
        #   vis_true given, vis_true_cams None -> rearrange(None, ...) dies inside einops. LOUD.
        #   vis_true_cams given, vis_true None -> the recompute branch below runs and
        #       UNCONDITIONALLY OVERWRITES vis_true_cams with is_point_visible, i.e. "inside the
        #       frustum", silently discarding a real per-camera occlusion channel. SILENT.
        if (vis_true is None) != (vis_true_cams is None):
            given, missing = (('vis_true', 'vis_true_cams') if vis_true is not None
                              else ('vis_true_cams', 'vis_true'))
            raise ValueError(
                f'vis_true and vis_true_cams are both-or-neither: got {given} but '
                f'{missing}=None. Supplying only vis_true_cams silently DISCARDS it (it is '
                f'recomputed from geometry); supplying only vis_true dies inside einops. Pass '
                f'both, or neither to derive both from the coordinates.')

        B, T, N, R = coords_true.shape
        is_true_2d = (R == 2)

        self._warn_unconsumed_weights(model, outputs)

        coords_pred = outputs['coords_pred']
        vis_pred = outputs['vis_pred']
        conf_pred = outputs['conf_pred']

        if '2d_pred' in outputs:
            coords_pred_2d = outputs['2d_pred']
        else:
            coords_pred_2d = None

        if 'depth_pred' in outputs:
            depth_pred = outputs['depth_pred'][..., None]
        else:
            depth_pred = None

        # Pre-define all loss scalars and scale as nan so the history block at the
        # bottom always has values regardless of which branch ran.
        def _nan():
            return torch.tensor(float('nan'), device=device)
        coords_loss           = _nan()
        occluded_coords_loss  = _nan()
        coords_loss_direct    = _nan()
        coords_loss_rays      = _nan()
        coords_loss_triangulate = _nan()
        coords_loss_direct_reproj = _nan()
        coords_loss_rays_reproj   = _nan()
        coords_loss_triangulate_reproj = _nan()
        vis_loss              = _nan()
        vis_loss_cams         = _nan()
        conf_loss             = _nan()
        conf_loss_2d          = _nan()
        coords_loss_2d        = _nan()
        coords_loss_depth     = _nan()
        coords_softmax_2d     = _nan()
        coords_softmax_3d     = _nan()
        depth_softmax         = _nan()
        smoothness_loss_3d    = _nan()
        smoothness_loss_2d    = _nan()
        feature_loss          = _nan()
        bad_feature_loss      = _nan()
        scale = torch.full((len(cgroup), B), float('nan'), device=device)

        if is_true_2d:
            # True 2D path: coords_true is pixel space (B, T, N, 2).
            # p2d is always set (== rearrange(coords, 't n r -> 1 t n r')).
            coords_true_2d = p2d  # (b, 1, t, n, 2)
            vis_true_cams = get_vis_true(coords_true_2d)  # finite-based; no GT occlusion

            if coords_pred_2d is not None:
                coords_loss_2d = self.mae_loss_coords_2d(
                    coords_pred=coords_pred_2d,
                    coords_true=coords_true_2d,
                    vis_true=vis_true_cams,
                    device=device)
                smoothness_loss_2d = self.smoothness_loss_2d(
                    coords_pred=coords_pred_2d,
                    coords_true=coords_true_2d,
                    vis_true=vis_true_cams,
                    time_dim=2, scale=1.0, device=device)

            if self.coords_softmax_2d_weight > 0 and '2d_logits' in outputs:
                coords_softmax_2d = self.coords_softmax_2d_weight * coordinate_softmax_loss(
                    outputs['2d_logits'], coords_true_2d, vis_true_cams)

        else:
            # 3D path (R==3): original synthetic-2D and pure-3D logic.
            if p2d is not None:
                coords_true_2d = p2d
            else:
                coords_true_2d = project_points_torch(cgroup, coords_true)

            coords_true_cams = repeat(coords_true, 'b t n r -> cams b t n r',
                                      cams=len(cgroup))

            centers_stack = torch.stack([cam['center'] for cam in cgroup])  # (cams,3) or (cams,T,3)
            if centers_stack.ndim == 3:   # moving cams: camera position at each frame
                centers = rearrange(centers_stack, 'cams t r -> cams 1 t 1 r')
            else:
                centers = rearrange(centers_stack, 'cams r -> cams 1 1 1 r')

            depths_true = torch.linalg.norm(coords_true_cams - centers, dim=-1)[..., None]

            if vis_true is None:
                valid_vis = False
                vis_true = get_vis_true(coords_true)

                if any(cam['ext'].ndim == 3 for cam in cgroup):
                    # moving cams: keep time explicit (b,t,n,3) so per-frame ext aligns
                    visible = torch.stack([is_point_visible(cam, coords_true, margin=2)
                                           for cam in cgroup])              # (cams,b,t,n)
                    vis_true_cams = rearrange(visible, 'cams b t n -> cams b t n 1')
                else:
                    qflat = rearrange(coords_true, 'b t n r -> (b t n) r')
                    visible = torch.stack([
                        is_point_visible(cam, qflat, margin=2)
                        for cam in cgroup
                    ])
                    vis_true_cams = rearrange(visible, 'cams (b t n) -> cams b t n 1', b=B, t=T, n=N)

            else:
                valid_vis = True
                vis_true_cams = rearrange(vis_true_cams, 'b t n cams 1 -> cams b t n 1')

            # trajectory point (b, t, n) is observed at frame t; pass those times so a
            # moving camera's cube_scale is sampled per-frame (reshape order matches
            # coords_true.reshape(B, T*N, 3), i.e. flattened (t n) with t outer).
            scale_times = (torch.arange(T, device=coords_true.device)
                           .view(1, T, 1).expand(B, T, N).reshape(B, T * N))
            scale = get_camera_scale(cgroup, coords_true.reshape(B, -1, 3),
                                     times=scale_times)  # (cams, B)
            if not self.per_camera_cube_scale:
                med = scale.median(dim=0).values  # (B,)
                scale = med[None, :].expand_as(scale).contiguous()
            # Clamp degenerate-crop cube_scale collapse (see __init__) so it can't blow up the
            # /scale division in the regular-3D losses. Off when floor==0.
            if self.cube_scale_floor > 0:
                scale = scale.clamp_min(self.cube_scale_floor)

            occluded_true = ~vis_true

            if p2d is None:
                # cube_scale only (world units per pixel). The metric MAE/Huber losses
                # divide the *error* by this BEFORE the robust loss (so the Huber knee
                # acts in pixels and the square leaves no residual cube_scale), then
                # divide by coords_3d_loss_scale AFTER (passed as loss_scale) to match
                # the normalized 2D-query branch's magnitude. The linear smoothness
                # consumer below still takes cube_scale * coords_3d_loss_scale directly.
                scale_cb = rearrange(scale, 'cams b -> cams b 1 1 1')
                scale_b  = scale.median(dim=0).values.reshape(B, 1, 1, 1)
                loss_scale_3d = self.coords_3d_loss_scale
                # Depth (range) ~ cube_scale * f_eff, so the depth error must be
                # normalized by cube_scale * f_eff (-> relative depth error) to be
                # scale-invariant, mirroring the depth-softmax denom (cube_scale *
                # f_eff). Dividing by cube_scale alone leaves an f_eff factor (which
                # spans >100x across datasets) and makes the Huber knee inconsistent.
                # f_eff is None when grid/f_eff_scale is off -> fall back to cube_scale.
                f_eff = outputs.get('grid', {}).get('f_eff', None)
                if f_eff is not None:
                    scale_cb_depth = scale_cb * rearrange(
                        f_eff, 'cams -> cams 1 1 1 1').to(scale_cb.dtype)
                else:
                    scale_cb_depth = scale_cb
            else:
                scale_cb = 1.0
                scale_b  = 1.0
                loss_scale_3d = 1.0
                scale_cb_depth = 1.0

            if p2d is not None:
                coords_true_n, _ = normalize_by_mean_depth(coords_true, vis_true, centers[0])
                coords_true_cams_n, _ = normalize_by_mean_depth(coords_true_cams, vis_true_cams, centers)
                depths_true_n, _ = normalize_by_mean_depth(depths_true, vis_true_cams, 0.0)
            else:
                coords_true_n = coords_true
                coords_true_cams_n = coords_true_cams
                depths_true_n = depths_true

            training_iters = model.training and 'coords_pred_iters' in outputs

            if training_iters:
                coords_pred_iters = outputs['coords_pred_iters']
                vis_pred_iters = outputs['vis_pred_iters']
                conf_pred_iters = outputs['conf_pred_iters']

                coords_true_unrolled, vis_true_unrolled, occluded_true_unrolled = unroll_batch(
                    coords=coords_true,
                    vis=vis_true,
                    stride=model.S,
                    stride_overlap=model.stride_overlap)

            # compute losses
            if valid_vis:
                vis_loss = self.bce_loss_vis_3d(
                    vis_pred=vis_pred_iters if training_iters else vis_pred,
                    vis_true=vis_true_unrolled if training_iters else vis_true,
                    device=device)
                if 'vis_pred_2d' in outputs:
                    vis_loss_cams = self.bce_loss_vis(
                        vis_pred=rearrange(outputs['vis_pred_2d'], 'b t n cams -> b t n cams 1'),
                        vis_true=vis_true_cams,
                        device=device)
                else:
                    vis_loss_cams = torch.tensor(0.0, device=device)
            else:
                vis_loss = torch.tensor(0.0, device=device)
                vis_loss_cams = torch.tensor(0.0, device=device)

            if 'conf_3d' in outputs:
                conf_loss = self.bce_loss_conf(
                    conf_pred=outputs['conf_3d'][..., None],
                    coords_pred=outputs['3d_pred_cams_direct'],
                    coords_true=coords_true_cams,
                    vis_true=vis_true_cams,
                    scale=rearrange(scale, 'cams b -> cams b 1 1'),
                    device=device)
            else:
                conf_loss = self.bce_loss_conf(
                    conf_pred=conf_pred_iters if training_iters else conf_pred,
                    coords_pred=coords_pred_iters if training_iters else coords_pred,
                    coords_true=coords_true_unrolled if training_iters else coords_true,
                    vis_true=vis_true_unrolled if training_iters else vis_true,
                    scale=scale.mean(dim=0).reshape(B, 1, 1),
                    device=device)

            conf_loss_2d = torch.tensor(0.0, device=device)
            if 'conf_pred_2d' in outputs and coords_pred_2d is not None:
                conf_loss_2d = self.bce_loss_conf_2d(
                    conf_pred=outputs['conf_pred_2d'][..., None],
                    coords_pred=coords_pred_2d,
                    coords_true=coords_true_2d,
                    vis_true=vis_true_cams,
                    scale=1.0,
                    device=device)

            if p2d is not None:
                if training_iters:
                    coords_true_unrolled_n = [
                        normalize_by_mean_depth(tgt, vis, centers[0])[0]
                        for tgt, vis in zip(coords_true_unrolled, vis_true_unrolled)
                    ]
                    coords_pred_iters_n = [
                        [normalize_by_mean_depth(pred, vis_true_unrolled[i], centers[0])[0]
                         for pred in stride]
                        for i, stride in enumerate(coords_pred_iters)
                    ]
                    coords_loss = self.mae_loss_coords(
                        coords_pred=coords_pred_iters_n, coords_true=coords_true_unrolled_n,
                        vis_true=vis_true_unrolled, scale=1.0, device=device)
                else:
                    pred_n, _ = normalize_by_mean_depth(coords_pred, vis_true, centers[0])
                    coords_loss = self.mae_loss_coords(
                        coords_pred=pred_n, coords_true=coords_true_n,
                        vis_true=vis_true, scale=1.0, device=device)
            else:
                coords_loss = self.mae_loss_coords(
                    coords_pred=coords_pred_iters if training_iters else coords_pred,
                    coords_true=coords_true_unrolled if training_iters else coords_true,
                    vis_true=vis_true_unrolled if training_iters else vis_true,
                    scale=scale_b,
                    loss_scale=loss_scale_3d,
                    device=device)

            coords_loss_direct = torch.tensor(0.0, device=device)
            coords_loss_rays = torch.tensor(0.0, device=device)
            coords_loss_triangulate = torch.tensor(0.0, device=device)

            if '3d_pred_cams_direct' in outputs:
                if p2d is not None:
                    pred_n, _ = normalize_by_mean_depth(outputs['3d_pred_cams_direct'], vis_true_cams, centers)
                    coords_loss_direct += self.mae_loss_coords_direct(
                        coords_pred=pred_n, coords_true=coords_true_cams_n,
                        vis_true=vis_true_cams, scale=1.0, device=device)
                else:
                    coords_loss_direct += self.mae_loss_coords_direct(
                        coords_pred=outputs['3d_pred_cams_direct'],
                        coords_true=coords_true_cams,
                        vis_true=vis_true_cams,
                        scale=scale_cb,
                        loss_scale=loss_scale_3d,
                        device=device)

            if '3d_pred_direct' in outputs:
                if p2d is not None:
                    pred_n, _ = normalize_by_mean_depth(outputs['3d_pred_direct'], vis_true, centers[0])
                    coords_loss_direct += self.mae_loss_coords_direct(
                        coords_pred=pred_n, coords_true=coords_true_n,
                        vis_true=vis_true, scale=1.0, device=device)
                else:
                    coords_loss_direct += self.mae_loss_coords_direct(
                        coords_pred=outputs['3d_pred_direct'],
                        coords_true=coords_true,
                        vis_true=vis_true,
                        scale=scale_b,
                        loss_scale=loss_scale_3d,
                        device=device)

            if '3d_pred_cams_rays' in outputs:
                if p2d is not None:
                    pred_n, _ = normalize_by_mean_depth(outputs['3d_pred_cams_rays'], vis_true_cams, centers)
                    coords_loss_rays += self.mae_loss_coords_rays(
                        coords_pred=pred_n, coords_true=coords_true_cams_n,
                        vis_true=vis_true_cams, scale=1.0, device=device)
                else:
                    coords_loss_rays += self.mae_loss_coords_rays(
                        coords_pred=outputs['3d_pred_cams_rays'],
                        coords_true=coords_true_cams,
                        vis_true=vis_true_cams,
                        scale=scale_cb,
                        loss_scale=loss_scale_3d,
                        device=device)

            if '3d_pred_rays' in outputs:
                if p2d is not None:
                    pred_n, _ = normalize_by_mean_depth(outputs['3d_pred_rays'], vis_true, centers[0])
                    coords_loss_rays += self.mae_loss_coords_rays(
                        coords_pred=pred_n, coords_true=coords_true_n,
                        vis_true=vis_true, scale=1.0, device=device)
                else:
                    coords_loss_rays += self.mae_loss_coords_rays(
                        coords_pred=outputs['3d_pred_rays'],
                        coords_true=coords_true,
                        vis_true=vis_true,
                        scale=scale_b,
                        loss_scale=loss_scale_3d,
                        device=device)

            if '3d_pred_triangulate' in outputs and outputs['3d_pred_triangulate'] is not None:
                coords_loss_triangulate += self.mae_loss_coords_triangulate(
                    coords_pred=outputs['3d_pred_triangulate'],
                    coords_true=coords_true,
                    vis_true=vis_true,
                    scale=scale_b,
                    loss_scale=loss_scale_3d,
                    device=device)

            # Reprojection losses: project the fused 3D predictions into every camera
            # and supervise the pixel error vs the projected GT. Multi-view geometry
            # constrains depth-of-motion with bounded, parallax-scaled gradients (no
            # SVD/triangulation). Pure-3D multi-cam case only (p2d is None), where
            # coords_true_2d == project_points_torch(cgroup, coords_true) is (cams,b,t,n,2).
            coords_loss_direct_reproj = torch.tensor(0.0, device=device)
            coords_loss_rays_reproj   = torch.tensor(0.0, device=device)
            coords_loss_triangulate_reproj = torch.tensor(0.0, device=device)
            if p2d is None:
                if self.coords_loss_direct_reproj_weight > 0 and '3d_pred_direct' in outputs:
                    reproj = project_points_torch(cgroup, outputs['3d_pred_direct'])
                    coords_loss_direct_reproj = self.mae_loss_direct_reproj(
                        coords_pred=reproj, coords_true=coords_true_2d,
                        vis_true=vis_true_cams, scale=1.0, device=device)
                if self.coords_loss_rays_reproj_weight > 0 and '3d_pred_rays' in outputs:
                    reproj = project_points_torch(cgroup, outputs['3d_pred_rays'])
                    coords_loss_rays_reproj = self.mae_loss_rays_reproj(
                        coords_pred=reproj, coords_true=coords_true_2d,
                        vis_true=vis_true_cams, scale=1.0, device=device)
                if self.coords_loss_triangulate_reproj_weight > 0 and \
                        outputs.get('3d_pred_triangulate') is not None:
                    reproj = project_points_torch(cgroup, outputs['3d_pred_triangulate'])
                    coords_loss_triangulate_reproj = self.mae_loss_triangulate_reproj(
                        coords_pred=reproj, coords_true=coords_true_2d,
                        vis_true=vis_true_cams, scale=1.0, device=device)

            if coords_pred_2d is not None:
                coords_loss_2d = self.mae_loss_coords_2d(
                    coords_pred=coords_pred_2d,
                    coords_true=coords_true_2d,
                    vis_true=vis_true_cams,
                    device=device)
            else:
                coords_loss_2d = torch.tensor(0.0, device=device)

            # ----- direct logit-classification losses (coordinate softmax) -----
            # 2D: supervise the pretrained track logits vs the projected GT pixels.
            if self.coords_softmax_2d_weight > 0 and '2d_logits' in outputs:
                coords_softmax_2d = self.coords_softmax_2d_weight * coordinate_softmax_loss(
                    outputs['2d_logits'], coords_true_2d, vis_true_cams)

            # 3D + depth grid bins: map GT world -> per-camera ray-local / normalized
            # depth (the exact inverse of the forward's decode), quantize to bins, CE.
            if 'grid' in outputs and (self.coords_softmax_3d_weight > 0
                                      or self.depth_softmax_weight > 0):
                g = outputs['grid']
                rays_c = g['rays_c']                                   # (cams,4,4)
                cs = g['cube_scale']                                   # (cams,B)
                feff = g['f_eff']                                      # (cams,) or None
                # GT world -> ray-local (cams,b,t,n,3); divide out the metric scaling
                # the forward multiplies back in (cube_scale [* f_eff]).
                # float64: this einsum forms ~6.5e5 ray-local GT (far rigs) via rays_c's translation, feeding
                # the depth/3d-softmax CE targets; reduced-precision float32 matmul corrupts them. Must match
                # the query_local guard (tracker_encoder) so the gridresid residual cancels exactly.
                gt_h = to_homogeneous(coords_true.to(torch.float64))   # (b,t,n,4)
                p_raylocal = from_homogeneous(
                    einsum(rays_c.to(torch.float64), gt_h,
                           'cams x r, b t n r -> cams b t n x')).to(torch.float32)
                denom = rearrange(cs, 'cams b -> cams b 1 1 1')
                denom_d = rearrange(cs, 'cams b -> cams b 1 1')
                if feff is not None:
                    denom = denom * rearrange(feff, 'cams -> cams 1 1 1 1').to(denom.dtype)
                    denom_d = denom_d * rearrange(feff, 'cams -> cams 1 1 1').to(denom_d.dtype)

                # gridnorm gauge. Use the forward's SOLVED (s_c,t_c)/(scale_d,offset_d) for
                # 3D-input batches; for fake-2D (network sees R==2 but 3D GT is available)
                # ESTIMATE it here from the raw decoded grid @ query frames <-> the known
                # ray-local query (the same fixed-rotation solve, detached). This lets the
                # grid CE run for fake 2D too.
                gn_s_c = gn_t_c = gn_scale_d = gn_offset_d = None
                if g.get('is_gridnorm', False):
                    if g.get('s_c') is not None:
                        gn_s_c, gn_t_c = g['s_c'], g['t_c']
                        gn_scale_d, gn_offset_d = g['scale_d'], g['offset_d']
                    else:
                        ncam = p_raylocal.shape[0]
                        qt = g['query_times']                                    # (b,n)
                        idx3 = repeat(qt, 'b n -> cams b 1 n r', cams=ncam, r=3)  # (cams,b,1,n,3)
                        g_q = torch.gather(g['g_raw'], 2, idx3)[:, :, 0]         # (cams,b,n,3)
                        q_k = torch.gather(p_raylocal, 2, idx3)[:, :, 0]         # (cams,b,n,3)
                        gn_s_c, gn_t_c = solve_scale_offset(g_q, q_k)            # (cams,b),(cams,b,3)
                        idx1 = repeat(qt, 'b n -> cams b 1 n', cams=ncam)        # (cams,b,1,n)
                        dg_q = torch.gather(g['depth_g'], 2, idx1)[:, :, 0]       # (cams,b,n)
                        dk_q = torch.gather(depths_true[..., 0], 2, idx1)[:, :, 0]  # (cams,b,n)
                        gn_scale_d, _off = solve_scale_offset(dg_q[..., None], dk_q[..., None])
                        gn_offset_d = _off[..., 0]                               # (cams,b)

                if self.coords_softmax_3d_weight > 0:
                    if g.get('is_gridnorm', False):
                        # gridnorm: the 3D bins are a gauge-free grid mapped to ray-local
                        # metric by (s_c, t_c) (solved in forward for 3D, estimated above for
                        # fake 2D). CE target = the GT ray-local position in that gauge.
                        s_c = rearrange(gn_s_c, 'cams b -> cams b 1 1 1')
                        t_c = rearrange(gn_t_c, 'cams b r -> cams b 1 1 r')
                        target_3d = (p_raylocal - t_c) / s_c
                    elif g.get('is_resid', False):
                        # gridresid: the 3D bins encode the motion offset from the
                        # per-track query anchor, normalized by cube*image_size
                        # (~pixels; NO f_eff -> ortho-safe). Subtract the (detached)
                        # anchor in ray-local space, then divide.
                        denom_resid = rearrange(cs, 'cams b -> cams b 1 1 1') * g['image_size']
                        target_3d = (p_raylocal - g['anchor_local']) / denom_resid
                    else:
                        target_3d = p_raylocal / denom                # absolute: / cube*f_eff
                    if g.get('learnable_scale', False) and g.get('s3d') is not None:
                        # forward multiplied the (residual) 3D output by the decoded per-track
                        # scale s3d; divide the CE target by it (DETACHED) so CE only shapes the
                        # normalized grid, while the metric regression loss learns s3d.
                        target_3d = target_3d / g['s3d'][..., None].clamp_min(1e-6)
                    lo3d, hi3d = g['g3d_lo'], g['g3d_hi']
                    if g.get('log_warp', False):
                        # quantize in the same signed-log space the warped bin
                        # centres live in (monotonic -> nearest-in-warped == nearest
                        # centre); range becomes [-c_range, c_range].
                        target_3d = signed_log1p(target_3d, g['eps'])
                        lo3d, hi3d = -g['c_range'], g['c_range']
                    coords_softmax_3d = self.coords_softmax_3d_weight * grid_softmax_loss(
                        g['logits_3d'], target_3d, lo3d, hi3d, vis_true_cams)

                if self.depth_softmax_weight > 0:
                    if g.get('is_gridnorm', False):
                        # gridnorm: linear depth gauge -> target = (metric depth - offset_d)/scale_d
                        # (solved in forward for 3D, estimated above for fake 2D), linear bins.
                        scale_d = rearrange(gn_scale_d, 'cams b -> cams b 1 1')
                        offset_d = rearrange(gn_offset_d, 'cams b -> cams b 1 1')
                        target_depth = (depths_true[..., 0] - offset_d) / scale_d
                    else:
                        denom_d_eff = denom_d
                        if g.get('sdep') is not None:
                            # decoded depth scale multiplied the forward depth; fold it into the
                            # normalizer (detached) so the log-depth CE target matches.
                            denom_d_eff = denom_d * g['sdep'].clamp_min(1e-6)
                        target_depth = torch.log(depths_true[..., 0] / denom_d_eff + 1e-6)  # (cams,b,t,n)
                    depth_softmax = self.depth_softmax_weight * grid_softmax_loss(
                        g['logits_depth'][..., None, :], target_depth[..., None],
                        g['gd_lo'], g['gd_hi'], vis_true_cams)

            if depth_pred is not None:
                if p2d is not None:
                    pred_n, _ = normalize_by_mean_depth(depth_pred, vis_true_cams, 0.0)
                    coords_loss_depth = self.mae_loss_coords_depth(
                        coords_pred=pred_n, coords_true=depths_true_n,
                        vis_true=vis_true_cams, scale=1.0, device=device)
                else:
                    coords_loss_depth = self.mae_loss_coords_depth(
                        coords_pred=depth_pred,
                        coords_true=depths_true,
                        vis_true=vis_true_cams,
                        scale=scale_cb_depth,
                        loss_scale=loss_scale_3d,
                        device=device)
            else:
                coords_loss_depth = torch.tensor(0.0, device=device)

            if p2d is not None:
                pred_n_smooth, _ = normalize_by_mean_depth(coords_pred, vis_true, centers[0])
                smoothness_loss_3d = self.smoothness_loss_3d(
                    coords_pred=pred_n_smooth, coords_true=coords_true_n,
                    vis_true=vis_true, time_dim=1, scale=1.0, device=device)
            else:
                # SmoothnessLoss is linear (hinge on |derivative|), so one power of
                # cube_scale is correct; it keeps cube_scale * coords_3d_loss_scale
                # (scale_b is now cube_scale only).
                smoothness_loss_3d = self.smoothness_loss_3d(
                    coords_pred=coords_pred, coords_true=coords_true,
                    vis_true=vis_true, time_dim=1,
                    scale=scale_b * self.coords_3d_loss_scale, device=device)

            if coords_pred_2d is not None:
                smoothness_loss_2d = self.smoothness_loss_2d(
                    coords_pred=coords_pred_2d, coords_true=coords_true_2d,
                    vis_true=vis_true_cams, time_dim=2, scale=1.0, device=device)
            else:
                smoothness_loss_2d = torch.tensor(float('nan'), device=device)

            if valid_vis:
                occluded_coords_loss = self.mae_loss_occluded_coords(
                    coords_pred=coords_pred_iters if training_iters else coords_pred,
                    coords_true=coords_true_unrolled if training_iters else coords_true,
                    vis_true=occluded_true_unrolled if training_iters else occluded_true,
                    scale=scale_b,
                    loss_scale=loss_scale_3d,
                    device=device)
            else:
                occluded_coords_loss = torch.tensor(0.0, device=device)

            if 'feature_planes_levels' in outputs and self.feature_loss_weight > 0:
                feature_loss, bad_feature_loss = self.feature_loss(
                    model=model,
                    coords_true=coords_true,
                    feature_planes_levels=outputs['feature_planes_levels'],
                    cgroup=cgroup,
                    device=device)
            else:
                feature_loss = torch.tensor(0.0, device=device)
                bad_feature_loss = torch.tensor(0.0, device=device)

        named_losses = [
            ('coords_loss', coords_loss), ('occluded_coords_loss', occluded_coords_loss),
            ('coords_loss_direct', coords_loss_direct),
            ('coords_loss_rays', coords_loss_rays),
            ('coords_loss_triangulate', coords_loss_triangulate),
            ('coords_loss_direct_reproj', coords_loss_direct_reproj),
            ('coords_loss_rays_reproj', coords_loss_rays_reproj),
            ('coords_loss_triangulate_reproj', coords_loss_triangulate_reproj),
            # 3D noisy-OR visibility (inert unless vis_loss_3d_weight > 0)
            ('vis_loss', vis_loss),
            ('vis_loss_cams', vis_loss_cams),
            ('conf_loss', conf_loss),
            ('conf_loss_2d', conf_loss_2d),
            ('coords_loss_2d', coords_loss_2d), ('coords_loss_depth', coords_loss_depth),
            ('coords_softmax_2d', coords_softmax_2d),
            ('coords_softmax_3d', coords_softmax_3d),
            ('depth_softmax', depth_softmax),
            ('smoothness_loss_3d', smoothness_loss_3d),
            ('smoothness_loss_2d', smoothness_loss_2d),
            # occluded_coords_loss_2d, # too crazy
            ('feature_loss', feature_loss), ('bad_feature_loss', bad_feature_loss)
        ]

        # A NON-FINITE TERM THAT IS STILL ATTACHED TO THE GRAPH IS A BUG, NOT AN INERT TERM.
        #
        # NaN is this class's deliberate signal for "this term is switched off": every sub-loss
        # returns `_nan()` when its weight is 0, and the filter below exists to drop those. But
        # dropping is not detaching -- `losses[isfinite]` is a masked_select, and its backward
        # hands the dropped element a real 0.0 gradient, which multiplied by the term's own NaN
        # local derivative gives NaN. So a term that goes non-finite by ACCIDENT is silently
        # removed from the forward total and silently destroys the backward one.
        #
        # The two cases are cleanly distinguishable: an intentionally-inert term is a detached
        # leaf built by `_nan()`, while a poisoned one carries a grad_fn. Checking
        # `requires_grad` therefore names the real failure with no false positives on the
        # switched-off terms.
        poisoned = [name for name, loss in named_losses
                    if loss.requires_grad and not torch.isfinite(loss)]
        if poisoned:
            raise ValueError(
                f'sub-loss(es) went non-finite while attached to the autograd graph: '
                f'{poisoned}. These would be dropped from the forward total and would still '
                f'return NaN gradients to every upstream parameter. The usual cause is a '
                f'non-finite TARGET reaching a loss that does not mask its inputs.')

        losses = torch.stack([loss for _, loss in named_losses])
        losses = losses[torch.isfinite(losses)]
        total_loss = losses.sum() / 50.0  # normalize to bring in 0-1 range

        self.loss_history['coords_loss'].append(coords_loss.item())
        self.loss_history['occluded_coords_loss'].append(occluded_coords_loss.item())

        self.loss_history['3d_direct'].append(coords_loss_direct.item())
        self.loss_history['3d_rays'].append(coords_loss_rays.item())
        self.loss_history['3d_triangulate'].append(coords_loss_triangulate.item())
        self.loss_history['3d_direct_reproj'].append(coords_loss_direct_reproj.item())
        self.loss_history['3d_rays_reproj'].append(coords_loss_rays_reproj.item())
        self.loss_history['3d_triangulate_reproj'].append(coords_loss_triangulate_reproj.item())

        self.loss_history['vis_loss'].append(vis_loss.item())
        self.loss_history['vis_2d_loss'].append(vis_loss_cams.item())
        self.loss_history['conf_loss'].append(conf_loss.item())
        self.loss_history['conf_2d_loss'].append(conf_loss_2d.item())
        self.loss_history['total_loss'].append(total_loss.item())

        self.loss_history['2d_loss'].append(coords_loss_2d.item())
        self.loss_history['depth_loss'].append(coords_loss_depth.item())

        self.loss_history['2d_softmax_loss'].append(coords_softmax_2d.item())
        self.loss_history['3d_softmax_loss'].append(coords_softmax_3d.item())
        self.loss_history['depth_softmax_loss'].append(depth_softmax.item())

        self.loss_history['smoothness_3d_loss'].append(smoothness_loss_3d.item())
        self.loss_history['smoothness_2d_loss'].append(smoothness_loss_2d.item())

        self.loss_history['feature_loss'].append(feature_loss.item())
        self.loss_history['bad_feature_loss'].append(bad_feature_loss.item())

        self.loss_history['cube_scale'].append(scale.detach().mean().item())

        return total_loss


class BCELossVis(nn.Module): 
    
    def __init__(self, gamma = 0.8, weight = 1):
        super().__init__()

        self.gamma = gamma 
        self.weight = weight

    def _compute_loss(self, vis_pred, vis_true):

        # A NON-FINITE TARGET MEANS "NOT ASSESSED", and it must be masked at the INPUT.
        #
        # Letting a NaN reach binary_cross_entropy_with_logits poisons the backward pass even
        # though TotalLoss drops the non-finite sub-loss from its forward sum (:854): that filter
        # is a masked_select, whose backward hands the dropped element a real 0.0 gradient, and
        # BCEWithLogitsBackward then computes 0.0 * (sigmoid(x) - NaN) = NaN. The result is a
        # healthy-looking loss curve while every upstream parameter receives NaN -- measured as
        # 36 of 40 training steps skipped on a non-finite gradient, with the printed loss falling
        # normally the whole time.
        #
        # Same hazard the coordinate losses already guard (see WeightedMAELoss._compute_loss and
        # BCELossConf._compute_loss), and the same substitute-then-mask idiom: the target is
        # replaced at invalid positions so NaN never enters a differentiable op, and the
        # reduction divides by the number of assessed entries rather than by all of them.
        #
        # This is what lets a three-state visibility annotation (visible / occluded / not
        # assessed) be expressed to the loss. Without it, callers must collapse "not assessed"
        # into "not visible" and train the visibility head on targets it was never given.
        valid = torch.isfinite(vis_true)
        if not valid.any():
            return torch.tensor(float('nan'), device = vis_pred.device)

        target = torch.where(valid, vis_true, torch.zeros_like(vis_true)).float()
        loss = F.binary_cross_entropy_with_logits(
            vis_pred,
            target,
            reduction = 'none')

        return (loss * valid).sum() / valid.sum()

    def forward(self, vis_pred, vis_true, device = None):

        # don't compute if the weight is 0
        if self.weight == 0: 
            return torch.tensor(float('nan'), device = device)

        if isinstance(vis_pred, torch.Tensor): 
            total_loss = self._compute_loss(vis_pred, vis_true)
            return self.weight * total_loss 

        n_strides = len(vis_pred)
        n_iters = len(vis_pred[0])

        losses = torch.ones((n_strides, n_iters), device = device)
        weights = self.gamma ** torch.arange(n_iters, device = device).flip(0)

        for i in range(n_strides):
            for j in range(n_iters):
                losses[i, j] = self._compute_loss(vis_pred[i][j], vis_true[i])

        total_loss = self.weight * torch.nanmean(weights * torch.nanmean(losses, axis = 0), axis = 0)

        return total_loss


class BCELossConf(nn.Module): 

    def __init__(self, gamma = 0.8, pixel_thresh = 12, weight = 1): 
        super().__init__()

        self.gamma = gamma 
        self.pixel_thresh = pixel_thresh
        self.weight = weight

    def _compute_loss(self, conf_pred, coords_pred, coords_true, vis_true, scale=1):

        # NaN-safe: zero the diff at invalid (occluded / non-finite GT) positions so
        # NaN targets don't poison gradients (see WeightedMAELoss._compute_loss).
        valid = (vis_true > 0.5) & torch.isfinite(coords_true[..., 0:1])
        coords_true_safe = torch.where(valid, coords_true, coords_pred.detach())

        dist = torch.sum((coords_pred - coords_true_safe) ** 2, dim = -1) ** 0.5
        mask = (dist <= self.pixel_thresh * scale).float().unsqueeze(dim = -1)

        loss = F.binary_cross_entropy_with_logits(
            conf_pred,
            mask,
            reduction = 'none')

        valid_f = valid.float()
        loss = (loss * valid_f).sum() / (valid_f.sum() + 1e-6)

        return loss

    def forward(self, conf_pred, coords_pred, coords_true, vis_true, scale=1, device = None): 

        # don't compute if the weight is 0
        if self.weight == 0: 
            return torch.tensor(float('nan'), device = device)
 
        if isinstance(coords_pred, torch.Tensor): 
            total_loss = self._compute_loss(conf_pred, coords_pred, coords_true, vis_true, scale)
            return self.weight * total_loss 

        n_strides = len(conf_pred)
        n_iters = len(conf_pred[0])

        losses = torch.ones((n_strides, n_iters), device = device)
        weights = self.gamma ** torch.arange(n_iters, device = device).flip(0)

        for i in range(n_strides): 
            for j in range(n_iters):
                losses[i, j] = self._compute_loss(
                    conf_pred[i][j], 
                    coords_pred[i][j], 
                    coords_true[i], 
                    vis_true[i],
                    scale)

        total_loss = self.weight * torch.nanmean(weights * torch.nanmean(losses, axis = 0), axis = 0)

        return total_loss 

class WeightedMAELoss(nn.Module):

    def __init__(self, gamma = 0.8, delta = 6, use_huber_loss = False, weight = 1):
        super().__init__()

        self.gamma = gamma
        self.delta = delta
        self.use_huber_loss = use_huber_loss
        self.weight = weight

    def huber_loss(self, diff):

        mask = torch.abs(diff) <= self.delta
        
        loss_masked = 0.5 * ((diff * mask) ** 2) 
        loss_unmasked = ~mask * self.delta * (torch.abs(diff * ~mask) - 0.5 * self.delta)

        total_loss = loss_masked + loss_unmasked

        return total_loss
    
    def _compute_loss(self, coords_pred, coords_true, vis_true, scale=1.0, loss_scale=1.0):

        # validity = visible AND finite GT. vis alone is insufficient: it can be 1
        # at NaN coords, and NaN targets poison the backward pass even when masked
        # by multiplication (0 * NaN = NaN). torch.where zeroes the diff at invalid
        # positions so NaN never enters a differentiable op (cf. SmoothnessLoss).
        valid = (vis_true > 0.5) & torch.isfinite(coords_true[..., 0:1])
        coords_true_safe = torch.where(valid, coords_true, coords_pred.detach())

        # Normalize the error by `scale` BEFORE the robust loss, then divide by the
        # magnitude knob `loss_scale` AFTER. In 3D mode scale == cube_scale (world
        # units per pixel), so the error enters the Huber in pixels and `delta` is a
        # pixel threshold. This is what makes the metric losses scale-invariant: the
        # Huber square now acts on the pixel error, so no power of cube_scale leaks
        # through (the old `huber(world_err) / (cube_scale * k)` was effectively
        # 0.5 * cube_scale * pixel_err^2 / k -- one un-cancelled cube_scale, so the
        # loss vanished for small-cube datasets like tuthill-fly). For L1
        # (use_huber_loss=False) dividing before vs after is identical; only the
        # Huber path changes. loss_scale is applied linearly so it cannot
        # reintroduce a scale dependence.
        diff = (coords_pred - coords_true_safe) / scale

        if self.use_huber_loss:
            loss = self.huber_loss(diff)
        else:
            loss = torch.abs(diff)

        valid_f = valid.float()
        loss = (loss / loss_scale * valid_f).sum() / (valid_f.sum() * coords_pred.shape[-1] + 1e-6)

        return loss

    def forward(self, coords_pred, coords_true, vis_true, scale=1.0, loss_scale=1.0, device=None):

        # don't compute if the weight is 0
        if self.weight == 0:
            return torch.tensor(float('nan'), device = device)

        if isinstance(coords_pred, torch.Tensor):
            total_loss = self._compute_loss(coords_pred, coords_true, vis_true, scale, loss_scale)
            return self.weight * total_loss

        n_strides = len(coords_pred)
        n_iters = len(coords_pred[0])

        losses = torch.ones((n_strides, n_iters), device = device)
        weights = self.gamma ** torch.arange(n_iters, device = device).flip(0)

        for i in range(n_strides):
            for j in range(n_iters):
                losses[i, j] = self._compute_loss(coords_pred[i][j], coords_true[i], vis_true[i], scale, loss_scale)

        total_loss = self.weight * torch.nanmean(weights * torch.nanmean(losses, axis = 0), axis = 0)

        return total_loss


class SmoothnessLoss(nn.Module):
    """One-sided hinge on the k-th temporal derivative magnitude.

    Penalizes pred only when |∂^k pred| > tolerance * |∂^k true|.
    Zero loss when pred is at or below the GT's wiggle bound.
    """

    def __init__(self, order=4, weight=1, tolerance=1.0, eps=1e-6):
        super().__init__()
        self.order = order
        self.weight = weight
        self.tolerance = tolerance
        self.eps = eps

    def forward(self, coords_pred, coords_true, vis_true, time_dim, scale=1.0, device=None):
        if self.weight == 0:
            return torch.tensor(float('nan'), device=device)

        T = coords_true.shape[time_dim]
        # Degrade to a lower-order difference on short windows rather than raising: `narrow`
        # below takes length T-k and dies on a negative length, so order=4 (the default) used to
        # kill any window shorter than 5 frames. A k-th difference needs k+1 samples.
        if T < 2:
            return torch.tensor(0.0, device=device)
        k = min(self.order, T - 1)

        # Build per-position validity: visible AND finite GT coord.
        # NaN in vis_true → (NaN > 0.5) is False → excluded automatically.
        vis_bool = (vis_true > 0.5)
        true_finite = torch.isfinite(coords_true[..., 0:1])
        valid = vis_bool & true_finite

        # Stencil-AND mask: all k+1 frames in the derivative window must be valid.
        mask = valid.narrow(time_dim, 0, T - k)
        for i in range(1, k + 1):
            mask = mask & valid.narrow(time_dim, i, T - k)

        d_pred = torch.diff(coords_pred, n=k, dim=time_dim)
        d_true = torch.diff(coords_true, n=k, dim=time_dim)  # may contain NaN

        # Excise NaN from d_true at one well-defined spot. torch.where short-circuits
        # the masked branch, so NaN * 0 = NaN is avoided (unlike d_true * mask).
        d_true_safe = torch.where(mask, d_true, torch.zeros_like(d_true))

        excess = (d_pred.abs() - self.tolerance * d_true_safe.abs()).clamp_min(0)

        R = coords_pred.shape[-1]
        loss = (excess / scale * mask.float()).sum() / (mask.sum() * R + self.eps)

        return self.weight * loss


class FeatureLoss(nn.Module):

    def __init__(self, weight):
        super().__init__()

        self.weight = weight

    def forward(self, model, coords_true, feature_planes_levels, cgroup, device = None): 

        # don't compute if the weight is 0
        if self.weight == 0: 
            feature_loss = torch.tensor(float('nan'), device = device)
            bad_feature_loss = torch.tensor(float('nan'), device = device)
            return feature_loss, bad_feature_loss

        feature_loss = model.get_feature_loss(
            feature_planes_levels = feature_planes_levels, 
            coords_full = coords_true, 
            camera_group = cgroup)
        
        b, s, n, r = coords_true.shape
        coords_flat = rearrange(coords_true, 'b s n r -> (b s n) r')
        ixs_perm = torch.randperm(coords_flat.shape[0])
        coords_shuffle = rearrange(coords_flat[ixs_perm], '(b s n) r -> b s n r',
            b = b, s = s, n = n)

        bad_feature_loss = model.get_feature_loss(
            feature_planes_levels = feature_planes_levels, 
            coords_full = coords_shuffle, 
            camera_group = cgroup)
        bad_feature_loss  = 1 - bad_feature_loss
        
        feature_loss *= self.weight
        bad_feature_loss *= self.weight
    
        return feature_loss, bad_feature_loss


def get_vis_true(coords):

    # vis = ~torch.isnan(torch.einsum('bsnr->bsn', coords))
    # vis = rearrange(vis, 'b s n -> b s n 1')

    vis = torch.isfinite(coords[..., 0])[..., None]

    return vis 


def unroll_batch(coords, vis, stride = 8, stride_overlap = 4): 

    T = coords.shape[1]
    stride_remainder = stride - stride_overlap
    n_windows = T // (stride_remainder)
    
    coords_unrolled = []
    vis_unrolled = []
    occluded_unrolled = []

    for i in range(n_windows): 

        ix = stride_remainder * i
        coords_subset = coords[:, ix:ix + stride, ...]
        vis_subset = vis[:, ix:ix + stride, ...]

        coords_unrolled.append(coords_subset)
        vis_unrolled.append(vis_subset)
        occluded_unrolled.append(~vis_subset)

    return coords_unrolled, vis_unrolled, occluded_unrolled
