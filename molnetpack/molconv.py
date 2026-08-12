"""The MolConv encoder layer.

:class:`MolConv` is E(3)-invariant and aggregates over a supplied neighbour graph — the
covalent bond graph in every released model — with optional chirality awareness.

``MolConv2`` is a deprecated alias of :class:`MolConv`.
"""

from typing import Optional, Tuple

import torch
import torch.nn as nn
import torch.nn.functional as F


class MolConv(nn.Module):
    """E(3)-invariant point-cloud convolution layer.

    The first layer (remove_xyz=True, input contains raw xyz in dims 0–2)
    builds its Gram matrix from relative displacement vectors (xj − xi)
    rather than absolute positions. The dot product <(xj−xi), (xk−xi)>
    encodes the angle ∠jik and is invariant to rotation and reflection;
    combined with (a) centering coordinates on the real-atom centroid and
    (b) a supplied neighbour graph whose padded slots self-point (see the
    CONTRACT in ``forward``), the layer is
    fully E(3)-invariant (rotation + reflection + translation). Because the
    first layer strips xyz from its output, invariance propagates through the
    whole encoder. Subsequent layers (remove_xyz=False) have no xyz and use
    feature-space dot products, invariant by construction.

    chirality=True appends a signed-volume pseudoscalar channel to the first
    layer, making it reflection-SENSITIVE (SE(3), chirality-aware) — for
    chiral tasks such as 3DMolCSP; the default (False) is E(3), reflection-
    invariant, correct for the achiral 3DMolMS tasks (MS/MS, RT, CCS).
    """

    def __init__(self, in_dim: int, out_dim: int, point_num: int, k: int,
                 remove_xyz: bool = False, chirality: bool = False, bond_dim: int = 0):
        super().__init__()
        self.k = k
        self.in_dim = in_dim
        self.out_dim = out_dim
        self.remove_xyz = remove_xyz
        self.chirality = bool(chirality) and remove_xyz
        extra_ch = 1 if self.chirality else 0
        # bond_dim (>0) adds explicit per-edge bond features (type/conj/ring) into the neighbour
        # message block feat_n, so the model sees discrete bond ORDER, not just bond length/angle.
        self.bond_dim = int(bond_dim)

        self.dist_ff = nn.Sequential(
            nn.Conv2d(1, 1, kernel_size=1, bias=False),
            nn.LayerNorm((1, point_num, k)),
            nn.Sigmoid(),
        )

        if remove_xyz:
            fn = in_dim + k - 3 + extra_ch + self.bond_dim
            center_in_dim = in_dim - 3
        else:
            fn = in_dim + k + self.bond_dim
            center_in_dim = in_dim
        self.center_ff = nn.Sequential(
            nn.Conv2d(center_in_dim, fn, kernel_size=1, bias=False),
            nn.LayerNorm((fn, point_num, k)),
            nn.Sigmoid(),
        )
        self.update_ff = nn.Sequential(
            nn.Conv2d(fn, out_dim, kernel_size=1, bias=False),
            nn.LayerNorm((out_dim, point_num, k)),
            nn.Softplus(beta=1.0, threshold=20.0),
        )

    def forward(
        self, x: torch.Tensor, idx_base: torch.Tensor, mask: torch.Tensor,
        neighbor_idx: Optional[torch.Tensor] = None,
        neighbor_mask: Optional[torch.Tensor] = None,
        bond_feat: Optional[torch.Tensor] = None,
    ) -> torch.Tensor:
        # neighbor_idx [B, N, k] is REQUIRED: the atom's neighbours as a fixed, precomputed
        # graph — normally the covalent bond graph, so the relative-displacement Gram encodes
        # true BOND ANGLES and dist true BOND LENGTHS.
        # bond_feat [B, N, k, bond_dim]: explicit per-edge bond descriptor concatenated into feat_n.
        #
        # CONTRACT — unused neighbour slots (atoms with degree < k) MUST be SELF-POINTING, i.e.
        # neighbor_idx[b, i, s] = i, with neighbor_mask[b, i, s] = False. neighbor_mask zeroes their
        # contribution AFTER update_ff, but the Gram / dist / LayerNorm statistics are computed over
        # ALL k slots, so a padded slot pointing at some OTHER atom would perturb the real slots'
        # normalisation. Self-pointing makes the relative displacement exactly zero, which is
        # deterministic and inert. `data_utils.encoding.bond_graph_array` self-pads accordingly.
        dist, gm2, feat_c, feat_n, extra = self._generate_feat(
            x, idx_base, mask, k=self.k, remove_xyz=self.remove_xyz, neighbor_idx=neighbor_idx
        )
        parts = [feat_n, gm2]
        if extra is not None:
            parts.append(extra)                              # + chirality channel
        if self.bond_dim > 0 and bond_feat is not None:
            parts.append(bond_feat.permute(0, 3, 1, 2).contiguous())  # [B, bond_dim, N, k]
        feat_n = torch.cat(parts, dim=1)
        feat_c = self.center_ff(feat_c)
        w = self.dist_ff(dist)

        feat = w * feat_n + feat_c
        feat = self.update_ff(feat)

        # Zero padded bond slots (atoms with degree < k) so they don't contribute.
        if neighbor_mask is not None:
            feat = feat * neighbor_mask.unsqueeze(1).to(feat.dtype)  # [B,1,N,k] over neighbour dim

        # Masked average pooling over neighbours
        mask_expanded = mask.unsqueeze(1).unsqueeze(-1).expand_as(feat)
        feat = feat.masked_fill(~mask_expanded, 0.0)
        valid_counts = mask.sum(dim=1, keepdim=True).clamp(min=0.1)
        feat = feat.sum(dim=3) / valid_counts.unsqueeze(2)  # [batch_size, out_dim, point_num]
        return feat

    def _generate_feat(
        self, x: torch.Tensor, idx_base: torch.Tensor, mask: torch.Tensor,
        k: int, remove_xyz: bool, neighbor_idx: Optional[torch.Tensor] = None
    ) -> Tuple[torch.Tensor, torch.Tensor, torch.Tensor, torch.Tensor, Optional[torch.Tensor]]:
        batch_size, num_dims, num_points = x.size()

        if remove_xyz:
            # Center xyz (dims 0-2) on the real-atom centroid. Distances and the
            # relative-displacement Gram matrix are subtractions of coordinates;
            # when the molecule sits far from the origin these cancel large
            # near-equal values and lose precision under translation. Centering
            # keeps them small and makes translation invariance numerically
            # exact — the centroid shifts with any input translation, so the
            # centered coordinates are identical. Padding atoms are excluded
            # from the centroid via the mask.
            m = mask.view(batch_size, 1, num_points).to(x.dtype)
            centroid = (x[:, :3, :] * m).sum(dim=2, keepdim=True) / m.sum(
                dim=2, keepdim=True
            ).clamp(min=1.0)
            x = torch.cat([x[:, :3, :] - centroid, x[:, 3:, :]], dim=1)

        if neighbor_idx is None:
            raise ValueError(
                "neighbor_idx is required: pass the covalent bond graph from "
                "preprocessing (data_utils.bond_graph_array)."
            )

        # Pairwise squared distances — computed only to GATHER each supplied neighbour's
        # distance below; no neighbour selection happens here. Padded slots self-point
        # (see the forward CONTRACT), so their gathered distance is exactly 0 and stays
        # inert under any translation. For bonded neighbours, `dist` is the bond length
        # (squared) and the Gram below the bond angle.
        inner = -2 * torch.matmul(x.transpose(2, 1), x)
        xx = torch.sum(x ** 2, dim=1, keepdim=True)
        pairwise_distance = -xx - inner - xx.transpose(2, 1)

        idx = neighbor_idx
        dist = -torch.gather(pairwise_distance, 2, idx)

        idx = idx + idx_base
        idx = idx.view(-1)

        x = x.transpose(2, 1).contiguous()  # [batch_size*num_points, num_dims]
        graph_feat = x.view(batch_size * num_points, -1)[idx, :]
        graph_feat = graph_feat.view(batch_size, num_points, k, num_dims)

        x = x.view(batch_size, num_points, 1, num_dims).repeat(1, 1, k, 1)

        if remove_xyz:
            # Gram matrix of relative displacements (xj − xi): <(xj−xi),(xk−xi)>
            # encodes angle ∠jik — invariant to rotation AND reflection (O(3)).
            rel_xyz = graph_feat[:, :, :, :3] - x[:, :, :, :3]  # [B, N, k, 3]
            gm_matrix = torch.matmul(rel_xyz, rel_xyz.permute(0, 1, 3, 2))  # [B, N, k, k]
            gm_matrix = F.normalize(gm_matrix, dim=1)
            sub_feat = gm_matrix[:, :, :, 0].unsqueeze(3)
            sub_gm_matrix = torch.matmul(sub_feat, sub_feat.permute(0, 1, 3, 2))
            sub_gm_matrix = F.normalize(sub_gm_matrix, dim=1)

            chi = None
            if self.chirality:
                # Signed-volume pseudoscalar chi[i,j] = d_j · (d_1 × d_2), where
                # d_1,d_2 are the two nearest *real* neighbour displacements (a
                # local frame). NB index 0 is the atom itself (self-distance 0 is
                # top-k), so d_0 == 0 and is unusable — use indices 1,2 (needs
                # k>=3). Neighbour order is by distance, which is reflection-
                # stable, so the frame is consistent. chi is invariant under
                # proper rotation (det=+1) & translation, but flips sign under
                # reflection (det=-1). Fed LINEARLY (not squared) so the sign
                # survives -> breaks reflection invariance = SE(3), not E(3).
                d1 = rel_xyz[:, :, 1, :]                        # [B, N, 3]
                d2 = rel_xyz[:, :, 2, :]                        # [B, N, 3]
                normal = torch.cross(d1, d2, dim=-1)           # [B, N, 3] = d1 x d2
                num = (rel_xyz * normal.unsqueeze(2)).sum(-1)  # [B, N, k] = d_j . (d1 x d2)
                den = rel_xyz.norm(dim=-1) * normal.norm(dim=-1, keepdim=True) + 1e-6
                chi = (num / den).unsqueeze(1)                 # [B, 1, N, k] in [-1,1]

            # chi is the optional chirality channel (None unless chirality=True).
            return (
                dist.unsqueeze(3).permute(0, 3, 1, 2).contiguous(),
                sub_gm_matrix.permute(0, 3, 1, 2).contiguous(),
                x[:, :, :, 3:].permute(0, 3, 1, 2).contiguous(),
                graph_feat[:, :, :, 3:].permute(0, 3, 1, 2).contiguous(),
                chi,
            )

        # Subsequent layers: input has no xyz.  Features are already
        # invariant (produced by a prior MolConv with remove_xyz=True),
        # so feature-space dot products are rotation-invariant by construction.
        gm_matrix = torch.matmul(graph_feat, graph_feat.permute(0, 1, 3, 2))
        gm_matrix = F.normalize(gm_matrix, dim=1)
        sub_feat = gm_matrix[:, :, :, 0].unsqueeze(3)
        sub_gm_matrix = torch.matmul(sub_feat, sub_feat.permute(0, 1, 3, 2))
        sub_gm_matrix = F.normalize(sub_gm_matrix, dim=1)

        return (
            dist.unsqueeze(3).permute(0, 3, 1, 2).contiguous(),
            sub_gm_matrix.permute(0, 3, 1, 2).contiguous(),
            x.permute(0, 3, 1, 2).contiguous(),
            graph_feat.permute(0, 3, 1, 2).contiguous(),
            None,
        )

    def __repr__(self) -> str:
        return f"{self.__class__.__name__} k = {self.k} ({self.in_dim} -> {self.out_dim})"


# Deprecated alias.
MolConv2 = MolConv
