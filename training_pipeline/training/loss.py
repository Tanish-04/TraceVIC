"""
training/loss.py
────────────────
Loss functions for both training phases.

  PairwiseRankingLoss        — BCE pairwise loss (Phase 1).
  LabelSmoothingRankingLoss  — Listwise CE + pairwise margin (Phase 2).
"""

import torch
from typing import List
import torch.nn as nn
import torch.nn.functional as F

# Phase 1
class PairwiseRankingLoss(nn.Module):
    """
    Pairwise ranking loss using BCELoss.

    pred_probs  : P(x > y) for each pair (model output)
    target_probs:
        1.0 — x is rootcause,     y is not
        0.0 — x is not rootcause, y is

    build_pairs emits only these two targets; same-class pairs are not
    emitted at all. A 0.5 target is minimised exactly when s_x == s_y, so
    ties would actively train the ranker toward giving every deletion line
    an identical score rather than merely failing to teach.
    """

    def __init__(self):
        super().__init__()
        self.criterion = nn.BCELoss()

    def forward(self, pred_probs: torch.Tensor,
                target_probs: torch.Tensor) -> torch.Tensor:
        return self.criterion(pred_probs, target_probs)



# Phase 2 Focal + Label Smoothing + Margin
class LabelSmoothingRankingLoss(nn.Module):
    """
    Listwise ranking loss combining:
      - Focal loss: down-weights easy cases, focuses on hard ones
      - Label smoothing: regularization to prevent overconfidence
      - Margin loss: pushes GT scores above non-GT scores
    """
    def __init__(
        self,
        temperature: float = 1.0,
        margin:      float = 1.0,
        smoothing:   float = 0.1,
        focal_gamma: float = 2.0,
        focal_alpha: float = 1.0,
        margin_weight:    float = 0.5,
    ):
        super().__init__()
        self.temperature = temperature
        self.margin      = margin
        self.smoothing   = smoothing
        self.focal_gamma = focal_gamma
        self.focal_alpha = focal_alpha
        # Previously hardcoded as 0.5 in forward(); phase2.margin_weight in the
        # config existed but was never read. 0.5 keeps the old default.
        self.margin_weight = margin_weight

    def forward(
        self,
        scores: torch.Tensor,
        ground_truth_positions: List[int],
    ) -> torch.Tensor:


        num_commits = len(scores)
        num_gt      = len(ground_truth_positions)


        # Create GT mask
        gt_mask  = torch.zeros(num_commits, dtype=torch.bool, device=scores.device)
        gt_mask[ground_truth_positions] = True
        neg_mask = ~gt_mask

        # Soft targets with label smoothing
        soft_targets = torch.full_like(
            scores, self.smoothing / max(num_commits - num_gt, 1))
        soft_targets[gt_mask] = (1.0 - self.smoothing) / num_gt

        # Normalize to sum to 1
        soft_targets = soft_targets / soft_targets.sum()

        # Focal loss
        # probs[i] = softmax probability assigned to commit i
        probs     = F.softmax(scores / self.temperature, dim=0)
        log_probs = torch.log(probs + 1e-8)

        # p_gt = probability the model assigns to the GT commit(s)
        # averaged over all GT positions
        p_gt = probs[gt_mask].mean()

        # Focal modulating factor: down-weights easy (high p_gt) examples
        focal_weight = self.focal_alpha * (1.0 - p_gt) ** self.focal_gamma

        # Focal cross-entropy with soft targets
        ce_loss = -torch.sum(soft_targets * log_probs)
        focal_loss = focal_weight * ce_loss

        # Margin loss
        gt_scores  = scores[gt_mask]
        neg_scores = scores[neg_mask]

        if gt_scores.numel() > 0 and neg_scores.numel() > 0:
            diffs     = gt_scores.unsqueeze(1) - neg_scores.unsqueeze(0)
            violation = F.relu(self.margin - diffs)          # [G, C-G]

            margin_loss = violation.mean()
        else:
            margin_loss = torch.tensor(0.0, device=scores.device)

        return focal_loss + self.margin_weight * margin_loss