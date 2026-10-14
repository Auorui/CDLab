import torch
import torch.nn.functional as F
from torch import nn

class _SegLossBase(nn.Module):
    def __init__(
        self,
        num_classes=2,
        ignore_index=256,
        reduction="mean",
    ):
        super().__init__()

        if num_classes < 2:
            raise ValueError("num_classes must be >= 2")

        if reduction not in ("none", "mean", "sum"):
            raise ValueError(f"Unsupported reduction: {reduction}")

        self.num_classes = num_classes
        self.ignore_index = ignore_index
        self.reduction = reduction

    def _prepare_input_target(self, input, target):
        if input.dim() != 4:
            raise ValueError(
                f"input must be (B,C,H,W), got {input.shape}"
            )

        if input.size(1) != self.num_classes:
            raise ValueError(
                f"input channels={input.size(1)} does not match "
                f"num_classes={self.num_classes}"
            )

        if target.dim() == 4:
            if target.size(1) != 1:
                raise ValueError(
                    f"target must be (B,1,H,W), got {target.shape}"
                )
            target = target[:, 0]

        if target.dim() != 3:
            raise ValueError(
                f"target must be (B,H,W) or (B,1,H,W), "
                f"got {target.shape}"
            )

        target = target.long()

        if input.shape[-2:] != target.shape[-2:]:
            input = F.interpolate(
                input,
                size=target.shape[-2:],
                mode="bilinear",
                align_corners=False,
            )

        if self.ignore_index is None:
            valid_mask = torch.ones_like(
                target,
                dtype=torch.bool,
            )
        else:
            valid_mask = target != self.ignore_index

        invalid = valid_mask & (
            (target < 0) |
            (target >= self.num_classes)
        )

        if invalid.any():
            invalid_values = torch.unique(target[invalid]).tolist()
            raise ValueError(
                f"target contains invalid class ids: {invalid_values}"
            )

        target_safe = target.clone()
        target_safe[~valid_mask] = 0

        return input, target, target_safe, valid_mask

    def _reduce_pixel_loss(self, pixel_loss, valid_mask):
        """
        pixel_loss: (B,H,W)
        valid_mask: (B,H,W)

        reduction='none' 返回每个样本一个损失，形状为 (B)。
        """
        valid_mask = valid_mask.to(dtype=pixel_loss.dtype)

        loss_sum = (
            pixel_loss * valid_mask
        ).flatten(1).sum(dim=1)

        valid_count = valid_mask.flatten(1).sum(dim=1)

        loss_per_sample = loss_sum / valid_count.clamp_min(1.0)

        # 整个样本都是 ignore_index 时，损失置 0
        loss_per_sample = torch.where(
            valid_count > 0,
            loss_per_sample,
            torch.zeros_like(loss_per_sample),
        )

        if self.reduction == "none":
            return loss_per_sample

        if self.reduction == "mean":
            return loss_per_sample.mean()

        return loss_per_sample.sum()

class _OverlapLossBase(_SegLossBase):
    def __init__(
        self,
        num_classes=2,
        smooth=1e-5,
        ignore_index=256,
        reduction="mean",
        include_background=False,
    ):
        super().__init__(
            num_classes=num_classes,
            ignore_index=ignore_index,
            reduction=reduction,
        )

        self.smooth = smooth
        self.include_background = include_background

    def _prepare_overlap(self, input, target):
        input, _, target_safe, valid_mask = \
            self._prepare_input_target(input, target)

        prob = F.softmax(input, dim=1)

        target_one_hot = F.one_hot(
            target_safe,
            num_classes=self.num_classes,
        ).permute(0, 3, 1, 2).to(dtype=input.dtype)

        mask = valid_mask.unsqueeze(1).to(dtype=input.dtype)

        prob = prob * mask
        target_one_hot = target_one_hot * mask

        if self.num_classes == 2:
            if self.include_background:
                class_ids = [0, 1]
            else:
                # 二分类默认只计算前景
                class_ids = [1]
        else:
            if self.include_background:
                class_ids = list(range(self.num_classes))
            else:
                class_ids = list(range(1, self.num_classes))

        prob = prob[:, class_ids]
        target_one_hot = target_one_hot[:, class_ids]

        intersection = (
            prob * target_one_hot
        ).sum(dim=(2, 3))

        prob_sum = prob.sum(dim=(2, 3))
        target_sum = target_one_hot.sum(dim=(2, 3))

        valid_pixels = valid_mask.sum(dim=(1, 2))

        class_valid = (
            (valid_pixels > 0).unsqueeze(1)
            & ((prob_sum + target_sum) > 0)
        )

        return (
            intersection,
            prob_sum,
            target_sum,
            class_valid,
        )

    def _reduce_class_loss(self, class_loss, class_valid):
        class_loss = (
            class_loss
            * class_valid.to(dtype=class_loss.dtype)
        )

        valid_class_count = \
            class_valid.sum(dim=1).clamp_min(1)

        loss = (
            class_loss.sum(dim=1)
            / valid_class_count
        )

        loss = torch.where(
            class_valid.any(dim=1),
            loss,
            torch.zeros_like(loss),
        )

        if self.reduction == "none":
            return loss

        if self.reduction == "mean":
            return loss.mean()

        return loss.sum()

class CrossEntropyLoss(_SegLossBase):
    def __init__(
        self,
        num_classes=2,
        weight=None,
        reduction="mean",
        ignore_index=256,
    ):
        super().__init__(
            num_classes=num_classes,
            ignore_index=ignore_index,
            reduction=reduction,
        )

        if weight is not None:
            weight = torch.as_tensor(
                weight,
                dtype=torch.float32,
            )
            if weight.numel() != num_classes:
                raise ValueError(
                    "weight length must equal num_classes"
                )
            self.register_buffer("weight", weight)
        else:
            self.weight = None

    def forward(self, input, target):
        input, target, _, valid_mask = \
            self._prepare_input_target(input, target)

        if self.ignore_index is None:
            pixel_loss = F.cross_entropy(
                input,
                target,
                weight=self.weight,
                reduction="none",
            )
        else:
            pixel_loss = F.cross_entropy(
                input,
                target,
                weight=self.weight,
                ignore_index=self.ignore_index,
                reduction="none",
            )

        return self._reduce_pixel_loss(
            pixel_loss,
            valid_mask,
        )

class FocalLoss(_SegLossBase):
    def __init__(
        self,
        num_classes=2,
        alpha=0.25,
        gamma=2.0,
        reduction="mean",
        ignore_index=256,
    ):
        super().__init__(
            num_classes=num_classes,
            ignore_index=ignore_index,
            reduction=reduction,
        )

        if gamma < 0:
            raise ValueError("gamma must be >= 0")

        self.alpha = alpha
        self.gamma = gamma

    def _get_alpha_factor(
        self,
        target_safe,
        valid_mask,
        dtype,
    ):
        if self.alpha is None:
            return torch.ones_like(
                target_safe,
                dtype=dtype,
            )

        if isinstance(self.alpha, (int, float)):
            alpha = float(self.alpha)

            if not 0.0 <= alpha <= 1.0:
                raise ValueError(
                    "scalar alpha must be in [0, 1]"
                )

            if self.num_classes == 2:
                # 二分类：前景 alpha，背景 1-alpha
                alpha_factor = torch.where(
                    target_safe == 1,
                    torch.full_like(
                        target_safe,
                        alpha,
                        dtype=dtype,
                    ),
                    torch.full_like(
                        target_safe,
                        1.0 - alpha,
                        dtype=dtype,
                    ),
                )
            else:
                # 多分类：背景 1-alpha，所有前景 alpha
                alpha_factor = torch.where(
                    target_safe == 0,
                    torch.full_like(
                        target_safe,
                        1.0 - alpha,
                        dtype=dtype,
                    ),
                    torch.full_like(
                        target_safe,
                        alpha,
                        dtype=dtype,
                    ),
                )

        else:
            alpha_vector = torch.as_tensor(
                self.alpha,
                dtype=dtype,
                device=target_safe.device,
            )

            if alpha_vector.numel() != self.num_classes:
                raise ValueError(
                    "alpha length must equal num_classes"
                )

            alpha_factor = alpha_vector[target_safe]

        return alpha_factor * valid_mask.to(dtype=dtype)

    def forward(self, input, target):
        input, target, target_safe, valid_mask = \
            self._prepare_input_target(input, target)

        if self.ignore_index is None:
            ce_loss = F.cross_entropy(
                input,
                target,
                reduction="none",
            )
        else:
            ce_loss = F.cross_entropy(
                input,
                target,
                ignore_index=self.ignore_index,
                reduction="none",
            )

        pt = torch.exp(-ce_loss)

        alpha_factor = self._get_alpha_factor(
            target_safe=target_safe,
            valid_mask=valid_mask,
            dtype=ce_loss.dtype,
        )

        focal_loss = (
            alpha_factor
            * (1.0 - pt).pow(self.gamma)
            * ce_loss
        )

        return self._reduce_pixel_loss(
            focal_loss,
            valid_mask,
        )


class DiceLoss(_OverlapLossBase):
    def forward(self, input, target):
        intersection, prob_sum, target_sum, class_valid = \
            self._prepare_overlap(input, target)

        denominator = prob_sum + target_sum

        dice = (
            2.0 * intersection + self.smooth
        ) / (
            denominator + self.smooth
        )

        return self._reduce_class_loss(
            1.0 - dice,
            class_valid,
        )


class JaccardLoss(_OverlapLossBase):
    def forward(self, input, target):
        intersection, prob_sum, target_sum, class_valid = \
            self._prepare_overlap(input, target)

        # Jaccard 的并集要减掉 intersection
        union = prob_sum + target_sum - intersection

        jaccard = (
            intersection + self.smooth
        ) / (
            union + self.smooth
        )

        return self._reduce_class_loss(
            1.0 - jaccard,
            class_valid,
        )

class TanimotoLoss(_OverlapLossBase):
    def __init__(
        self,
        num_classes=2,
        smooth=1e-5,
        ignore_index=256,
        reduction="mean",
        include_background=False,
        use_complement=True,
    ):
        super().__init__(
            num_classes=num_classes,
            smooth=smooth,
            ignore_index=ignore_index,
            reduction=reduction,
            include_background=include_background,
        )

        self.use_complement = use_complement

    def forward(self, input, target):
        input, _, target_safe, valid_mask = \
            self._prepare_input_target(input, target)

        prob = F.softmax(input, dim=1)

        target_one_hot = F.one_hot(
            target_safe,
            num_classes=self.num_classes,
        ).permute(0, 3, 1, 2).to(dtype=input.dtype)

        mask = valid_mask.unsqueeze(1).to(dtype=input.dtype)

        if self.num_classes == 2:
            if self.include_background:
                class_ids = [0, 1]
            else:
                # 二分类默认只计算前景
                class_ids = [1]
        else:
            if self.include_background:
                class_ids = list(range(self.num_classes))
            else:
                # 多分类默认忽略背景
                class_ids = list(range(1, self.num_classes))

        prob = prob[:, class_ids]
        target_one_hot = target_one_hot[:, class_ids]

        # 注意：这里不要提前 prob = prob * mask
        # 每个统计项单独乘 mask，避免 ignore 区域进入 complement 分支
        intersection = (
            prob * target_one_hot * mask
        ).sum(dim=(2, 3))

        p2 = (
            prob * prob * mask
        ).sum(dim=(2, 3))

        t2 = (
            target_one_hot
            * target_one_hot
            * mask
        ).sum(dim=(2, 3))

        tanimoto = (
            intersection + self.smooth
        ) / (
            p2 + t2 - intersection + self.smooth
        )

        if self.use_complement:
            prob_complement = 1.0 - prob
            target_complement = 1.0 - target_one_hot

            intersection_c = (
                prob_complement
                * target_complement
                * mask
            ).sum(dim=(2, 3))

            p2_c = (
                prob_complement
                * prob_complement
                * mask
            ).sum(dim=(2, 3))

            t2_c = (
                target_complement
                * target_complement
                * mask
            ).sum(dim=(2, 3))

            tanimoto_c = (
                intersection_c + self.smooth
            ) / (
                p2_c + t2_c - intersection_c + self.smooth
            )

            tanimoto_score = 0.5 * (
                tanimoto + tanimoto_c
            )
        else:
            tanimoto_score = tanimoto

        loss = 1.0 - tanimoto_score

        # 类别有效性判断
        valid_pixels = valid_mask.sum(dim=(1, 2))

        prob_sum = (
            prob * mask
        ).sum(dim=(2, 3))

        target_sum = (
            target_one_hot * mask
        ).sum(dim=(2, 3))

        class_valid = (
            (valid_pixels > 0).unsqueeze(1)
            & ((prob_sum + target_sum) > 0)
        )

        return self._reduce_class_loss(
            loss,
            class_valid,
        )

class CombinedLoss(nn.Module):
    def __init__(self, loss_type=None, loss_weight=None, aux_loss_weights=None,
                 num_classes=2, smooth=1e-5, focal_alpha=0.25, focal_gamma=2.0,
                 ignore_index=256, reduction='mean', include_background=False):
        super(CombinedLoss, self).__init__()
        if loss_type is None:
            loss_type = ['ce', 'dice', 'focal', 'iou']
        if loss_weight is None:
            loss_weight = [1.0] * len(loss_type)
        self.loss_type = loss_type
        self.loss_weight = loss_weight
        self.reduction = reduction
        self.aux_loss_weights = aux_loss_weights

        assert len(self.loss_type) == len(self.loss_weight), \
            "The lengths of loss_type and loss_weight must be consistent."

        self.loss_map = nn.ModuleDict({
            "ce": CrossEntropyLoss(
                num_classes=num_classes,
                ignore_index=ignore_index,
                reduction=reduction,
            ),
            "dice": DiceLoss(
                num_classes=num_classes,
                smooth=smooth,
                ignore_index=ignore_index,
                reduction=reduction,
                include_background=include_background,
            ),
            "focal": FocalLoss(
                num_classes=num_classes,
                alpha=focal_alpha,
                gamma=focal_gamma,
                ignore_index=ignore_index,
                reduction=reduction,
            ),
            "iou": JaccardLoss(
                num_classes=num_classes,
                smooth=smooth,
                ignore_index=ignore_index,
                reduction=reduction,
                include_background=include_background,
            ),
            "tanimoto": TanimotoLoss(
                num_classes=num_classes,
                smooth=smooth,
                ignore_index=ignore_index,
                reduction=reduction,
                include_background=False,
                use_complement=True,
            ),
        })

    def _compute_single_loss(self, input, target):
        total_loss = 0.0

        for loss_name, weight in zip(self.loss_type, self.loss_weight):
            if loss_name not in self.loss_map:
                raise ValueError(f"Unsupported loss type: {loss_name}")
            total_loss = total_loss + weight * self.loss_map[loss_name](input, target)

        return total_loss

    def forward(self, input, target):
        """
        Args:
            input: 可以是单个tensor (B, C, H, W) 或多个tensor的列表/元组
            target: (B, H, W) or (B, 1, H, W) labels
        Returns:
            loss: scalar
        """
        if isinstance(input, (list, tuple)):
            losses = [self._compute_single_loss(inp, target) for inp in input]
            if self.aux_loss_weights and len(self.aux_loss_weights) == len(losses):
                total_loss = sum(w * l for w, l in zip(self.aux_loss_weights, losses))
            else:
                total_loss = sum(losses)
            return total_loss
        else:
            return self._compute_single_loss(input, target)
