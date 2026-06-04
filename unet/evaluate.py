import numpy as np
import torch
from sklearn.metrics import f1_score
import matplotlib.pyplot as plt
import seaborn as sns


def _flatten(y_true, y_pred):
    if hasattr(y_true, "detach"):
        y_true = y_true.detach().cpu().numpy()
    if hasattr(y_pred, "detach"):
        y_pred = y_pred.detach().cpu().numpy()

    y_true = np.squeeze(y_true)
    y_pred = np.squeeze(y_pred)

    assert y_true.shape == y_pred.shape, f"{y_true.shape} vs {y_pred.shape}"
    return y_true.reshape(-1), y_pred.reshape(-1)


def normalize_pred(y_pred):
    y_pred = y_pred.detach()

    if y_pred.ndim == 4:
        y_pred = torch.argmax(y_pred, dim=1)
    elif y_pred.ndim == 3:
        if y_pred.shape[0] == 1:
            y_pred = y_pred.squeeze(0)
        elif y_pred.dtype not in (torch.long, torch.int, torch.int64, torch.int32):
            y_pred = torch.argmax(y_pred, dim=0)

    return y_pred


def get_predictions(building_out, damage_out):
    building_prob = torch.sigmoid(building_out)
    building_mask = (building_prob > 0.5).long()

    damage_prob = torch.softmax(damage_out, dim=1)
    damage_pred = torch.argmax(damage_prob, dim=1)

    final_damage = damage_pred * building_mask.squeeze(1)

    return building_mask.squeeze(1), final_damage


def localization_f1(y_true, y_pred):
    y_true_flat, y_pred_flat = _flatten(y_true, y_pred)

    y_true_bin = (y_true_flat > 0).astype(int)
    y_pred_bin = (y_pred_flat > 0).astype(int)

    return f1_score(y_true_bin, y_pred_bin)


def get_iou(pred, target, smooth=1e-6):
    intersection = (pred * target).sum()
    union = (pred + target - pred * target).sum()

    iou = (intersection + smooth) / (union + smooth)
    return iou


def get_dice(pred, target, smooth=1e-6):
    intersection = (pred * target).sum()
    union = pred.sum() + target.sum()

    dice = (2 * intersection + smooth) / (union + smooth)
    return dice


def damage_f1_with_breakdown(y_true, y_pred):
    y_true_flat, y_pred_flat = _flatten(y_true, y_pred)

    mask = y_true_flat > 0
    if mask.sum() == 0:
        return {
            "macro_f1": 0.0,
            "per_class_f1": {c: 0.0 for c in [1, 2, 3, 4]}
        }

    y_true_build = y_true_flat[mask]
    y_pred_build = y_pred_flat[mask]

    labels = [1, 2, 3, 4]

    per_class = f1_score(
        y_true_build,
        y_pred_build,
        labels=labels,
        average=None,
        zero_division=0
    )

    per_class_dict = {cls: score for cls, score in zip(labels, per_class)}

    macro = f1_score(
        y_true_build,
        y_pred_build,
        labels=labels,
        average="macro",
        zero_division=0
    )

    return {
        "macro_f1": macro,
        "per_class_f1": per_class_dict
    }


def classification_metrics(cls_logits, cls_targets, num_classes=5, eps=1e-6):
    preds = cls_logits

    acc = (preds == cls_targets).float().mean().item()

    f1s = []
    for cls in range(1, num_classes):
        pred_c = (preds == cls)
        targ_c = (cls_targets == cls)

        tp = (pred_c & targ_c).sum().item()
        fp = (pred_c & ~targ_c).sum().item()
        fn = (~pred_c & targ_c).sum().item()

        precision = tp / (tp + fp + eps)
        recall = tp / (tp + fn + eps)
        f1 = 2 * precision * recall / (precision + recall + eps)
        f1s.append(f1)

    return acc, sum(f1s) / len(f1s)


def confusion_matrix_5(pred, target, num_classes=5):
    pred = pred.view(-1)
    target = target.view(-1)

    mask = (target >= 0) & (target < num_classes)

    cm = torch.bincount(
        num_classes * target[mask] + pred[mask],
        minlength=num_classes ** 2
    ).reshape(num_classes, num_classes)

    return cm


def iou_from_confusion(cm):
    intersection = torch.diag(cm)
    union = cm.sum(dim=1) + cm.sum(dim=0) - intersection
    iou = intersection / (union + 1e-6)
    return iou


def dice_from_confusion(cm):
    intersection = torch.diag(cm)
    total = cm.sum(dim=1) + cm.sum(dim=0)
    dice = (2 * intersection) / (total + 1e-6)
    return dice


def f1_from_confusion(cm, eps=1e-6):
    tp = torch.diag(cm)
    fp = cm.sum(dim=0) - tp
    fn = cm.sum(dim=1) - tp

    f1 = (2 * tp) / (2 * tp + fp + fn + eps)
    return f1


def acc_from_confusion(cm, eps=1e-6):
    correct = torch.diag(cm).sum()
    total = cm.sum()
    return correct / (total + eps)


def xview2_score_single(y_true, y_pred, w_loc=0.3, w_dmg=0.7):
    loc = localization_f1(y_true, y_pred)
    dmg_dict = damage_f1_with_breakdown(y_true, y_pred)

    final = w_loc * loc + w_dmg * dmg_dict["macro_f1"]

    return {
        "localization_f1": loc,
        "damage_f1": dmg_dict["macro_f1"],
        "damage_per_class": dmg_dict["per_class_f1"],
        "final_score": final
    }


def xview2_score_dataset(y_true_list, y_pred_list, w_loc=0.3, w_dmg=0.7):
    tp = fp = fn = 0
    acc_comp = 0
    f1_comp = 0

    num_classes = 4
    conf = np.zeros((num_classes, num_classes), dtype=np.int64)

    for yt, yp in zip(y_true_list, y_pred_list):
        yt = np.squeeze(yt)
        yp = np.squeeze(yp)

        acc_temp, f1_temp = classification_metrics(yt, yp)
        acc_comp += acc_temp
        f1_comp += f1_temp

        yt_bin = yt > 0
        yp_bin = yp > 0

        tp += np.sum(yt_bin & yp_bin)
        fp += np.sum(~yt_bin & yp_bin)
        fn += np.sum(yt_bin & ~yp_bin)

        mask = yt_bin
        if np.any(mask):
            yt_build = yt[mask] - 1
            yp_build = yp[mask] - 1

            valid = (yp_build >= 0) & (yp_build < num_classes)
            yt_build = yt_build[valid]
            yp_build = yp_build[valid]

            idx = yt_build * num_classes + yp_build
            bincount = np.bincount(idx, minlength=num_classes ** 2)
            conf += bincount.reshape(num_classes, num_classes)

    loc_f1 = (2 * tp) / (2 * tp + fp + fn + 1e-8)

    per_class_f1 = {}
    for c in range(num_classes):
        TP = conf[c, c]
        FP = conf[:, c].sum() - TP
        FN = conf[c, :].sum() - TP

        denom = (2 * TP + FP + FN)
        f1 = (2 * TP / denom) if denom > 0 else 0.0

        per_class_f1[c + 1] = f1

    dmg_macro = np.mean(list(per_class_f1.values()))

    final = w_loc * loc_f1 + w_dmg * dmg_macro

    return {
        "localization_f1": loc_f1,
        "damage_f1": dmg_macro,
        "damage_per_class": per_class_f1,
        "final_score": final
    }


class XView2Evaluator:
    def __init__(self, num_classes=4, device="cuda"):
        self.num_classes = num_classes
        self.device = device

        self.tp = torch.tensor(0.0, device=device)
        self.tn = torch.tensor(0.0, device=device)
        self.fp = torch.tensor(0.0, device=device)
        self.fn = torch.tensor(0.0, device=device)

        self.conf = torch.zeros((num_classes, num_classes), device=device)

        self.full_cm = torch.zeros((num_classes + 1, num_classes + 1), device=device)

        self.acc_total = 0
        self.f1_total = 0
        self.dice_total = 0
        self.iou_total = 0
        self.count = 0

    @torch.no_grad()
    def update(self, y_true, y_pred):
        y_true = y_true.squeeze().to(self.device)

        y_pred = normalize_pred(y_pred)
        y_pred = y_pred.squeeze().to(self.device)

        acc_temp, f1_temp = classification_metrics(y_true, y_pred)
        self.acc_total += acc_temp
        self.f1_total += f1_temp

        dice_temp = get_dice(y_pred, y_true)
        iou_temp = get_iou(y_pred, y_true)
        self.dice_total += dice_temp
        self.iou_total += iou_temp

        self.count += 1

        self.full_cm += confusion_matrix_5(y_pred, y_true)

        yt_bin = y_true > 0
        yp_bin = y_pred > 0

        self.tp += torch.sum(yt_bin & yp_bin)
        self.tn += torch.sum(~yt_bin & ~yp_bin)
        self.fp += torch.sum(~yt_bin & yp_bin)
        self.fn += torch.sum(yt_bin & ~yp_bin)

        mask = y_true > 0

        if mask.sum() > 0:
            yt_build = y_true[mask].to(torch.long) - 1
            yp_build = y_pred[mask].to(torch.long) - 1

            valid = (yp_build >= 0) & (yp_build < self.num_classes)
            yt_build = yt_build[valid]
            yp_build = yp_build[valid]

            if yt_build.numel() > 0:
                idx = yt_build * self.num_classes + yp_build
                idx = idx.to(torch.long)

                bincount = torch.bincount(
                    idx,
                    minlength=self.num_classes ** 2
                )

                self.conf += bincount.view(self.num_classes, self.num_classes)

    def compute(self, w_loc=0.3, w_dmg=0.7):
        eps = 1e-8

        loc_f1 = (2 * self.tp) / (2 * self.tp + self.fp + self.fn + eps)

        per_class_f1 = []

        for c in range(self.num_classes):
            TP = self.conf[c, c]
            FP = self.conf[:, c].sum() - TP
            FN = self.conf[c, :].sum() - TP

            denom = (2 * TP + FP + FN)
            f1 = torch.where(denom > 0, 2 * TP / denom, torch.tensor(0.0, device=self.device))

            per_class_f1.append(f1)

        per_class_f1 = torch.stack(per_class_f1)
        dmg_macro = per_class_f1.mean()

        final = w_loc * loc_f1 + w_dmg * dmg_macro

        return {
            "localization_f1": loc_f1.item(),
            "damage_f1": dmg_macro.item(),
            "damage_per_class": {
                i + 1: per_class_f1[i].item() for i in range(self.num_classes)
            },
            "final_score": final.item(),
            "damage_cm": self.conf.cpu().tolist(),
            "building_cm": torch.tensor([
                [self.tn, self.fp],
                [self.fn, self.tp]
            ], device=self.device).cpu().tolist(),
            "full_f1s": f1_from_confusion(self.full_cm).cpu().tolist(),
            "damage_f1s": f1_from_confusion(self.conf).cpu().tolist(),
            "full_acc": float(acc_from_confusion(self.full_cm).cpu()),
            "damage_acc": float(acc_from_confusion(self.conf).cpu()),
            "full_dice": dice_from_confusion(self.full_cm).cpu().tolist(),
            "building_dice": dice_from_confusion(torch.tensor([
                [self.tn, self.fp],
                [self.fn, self.tp]
            ], device=self.device)).tolist(),
            "full_iou": iou_from_confusion(self.full_cm).cpu().tolist(),
            "building_iou": iou_from_confusion(torch.tensor([
                [self.tn, self.fp],
                [self.fn, self.tp]
            ], device=self.device)).tolist(),
            "full_cm": self.full_cm.cpu().tolist(),
        }


def normalize_confusion_matrix(conf, row_wise=True):
    conf = np.array(conf)

    if row_wise:
        row_sums = conf.sum(axis=1)
        norm_conf = conf / (row_sums + 1e-8)
    else:
        col_sums = conf.sum(axis=0)
        norm_conf = conf / (col_sums + 1e-8)

    return norm_conf


def plot_confusion(conf, row_wise=True, labels=None):
    conf = np.array(conf)
    conf = conf / conf.sum()

    plt.figure(figsize=(6, 5))
    if labels:
        sns.heatmap(conf, annot=True, fmt=".3f",
                    xticklabels=labels,
                    yticklabels=labels)
    else:
        sns.heatmap(conf, annot=True, fmt=".3f")
    plt.xlabel("Predicted")
    plt.ylabel("True")
    plt.title("Normalized Confusion Matrix")
    plt.show()


def run_evaluation(model, dataset, device="cuda"):
    model.eval()

    evaluator = XView2Evaluator(device=device)

    if isinstance(dataset, torch.utils.data.DataLoader):
        with torch.no_grad():
            for batch in dataset:
                images = batch["image"].to(device, non_blocking=True)
                y_true = batch["post_mask"].to(device)

                building_out, damage_out = model(images)
                _, d_pred = get_predictions(building_out, damage_out)

                evaluator.update(y_true, d_pred)
    else:
        with torch.no_grad():
            for i in range(len(dataset)):
                sample = dataset[i]
                image = sample["image"].unsqueeze(0).to(device, non_blocking=True)
                y_true = sample["post_mask"].to(device)

                building_out, damage_out = model(image)
                _, d_pred = get_predictions(building_out, damage_out)

                evaluator.update(y_true, d_pred)

    results = evaluator.compute()

    print("\n===== XVIEW2 EVALUATION RESULTS =====")
    print(f"Localization F1: {results['localization_f1']:.4f}")
    print(f"Damage F1:       {results['damage_f1']:.4f}")
    print(f"Final Score:     {results['final_score']:.4f}")

    print("\nPer-class Damage F1:")
    for k, v in results["damage_per_class"].items():
        print(f"  Class {k}: {v:.4f}")

    print("\nBuilding Confusion Matrix:")
    print(results["building_cm"])
    print("\nDamage Confusion Matrix (raw):")
    print(results["damage_cm"])

    print("\nFull Results:")
    print(results)

    return results


def evaluate_checkpoint(weight_path, dataset, device="cuda"):
    from program import UNetDualHead

    model = UNetDualHead(in_channels=6).to(device)
    model.load_state_dict(torch.load(weight_path, map_location=device, weights_only=True))

    return run_evaluation(model, dataset, device=device)


if __name__ == "__main__":
    from data_load import get_dataloaders
    import glob, os

    ckpts = sorted(glob.glob('sbatch_output/model_weights--*.pth'))
    if ckpts:
        latest = ckpts[-1]
        print(f'Evaluating {latest}')
        _, _, test_loader = get_dataloaders('content/data/xview2_jpeg', batch_size=12)
        evaluate_checkpoint(latest, test_loader)
    else:
        print('No checkpoint found in sbatch_output/')