import logging
import time
import torch
import torch.distributed as dist
import torch.nn.functional as F
from torch.utils.data import DataLoader
from utils.meter import AverageMeter
from utils.metrics import Evaluator
from utils.comm import get_rank, synchronize
from utils.train_diagnostics import compute_train_diagnostics
from utils.wandb_utils import wandb_log, wandb_upload_best_checkpoints
from torch.utils.tensorboard import SummaryWriter
from prettytable import PrettyTable
import numpy as np
import copy
from datasets.bases import ImageTextDataset
from datasets.build import build_transforms, collate, make_data_loader_generator, seed_worker


def _unwrap_model(model):
    return model.module if hasattr(model, "module") else model


def _prototype_requested(args):
    return (
        getattr(args, "prototype", False)
        or getattr(args, "use_loss_id", False)
    )


def _prototype_ready(model):
    model = _unwrap_model(model)
    branch = getattr(model, "prototype_branch", None)
    return branch is not None and branch.is_ready()


def _set_epoch_on_loader(loader, epoch):
    sampler = getattr(loader, "sampler", None)
    if sampler is not None and hasattr(sampler, "set_epoch"):
        sampler.set_epoch(epoch)

    batch_sampler = getattr(loader, "batch_sampler", None)
    inner_sampler = getattr(batch_sampler, "sampler", None)
    if inner_sampler is not None and hasattr(inner_sampler, "set_epoch"):
        inner_sampler.set_epoch(epoch)


@torch.no_grad()
def _sync_prototype_memory(model):
    if not (dist.is_available() and dist.is_initialized()):
        return
    model = _unwrap_model(model)
    branch = getattr(model, "prototype_branch", None)
    memory = getattr(branch, "memory", None) if branch is not None else None
    if memory is None or not getattr(memory, "is_ready", lambda: False)():
        return

    world_size = dist.get_world_size()
    for name in ("image_prototypes", "text_prototypes", "text_to_image", "image_to_text"):
        buffer = getattr(memory, name, None)
        if torch.is_tensor(buffer):
            dist.all_reduce(buffer, op=dist.ReduceOp.SUM)
            buffer.div_(world_size)
            buffer.copy_(F.normalize(buffer, p=2, dim=1))


def _build_prototype_init_loader(train_loader, args):
    train_set = getattr(train_loader, "dataset", None)
    source_dataset = getattr(train_set, "dataset", None)
    if train_set is None or source_dataset is None:
        return None

    prototype_set = ImageTextDataset(
        source_dataset,
        transform=build_transforms(img_size=args.img_size, aug=False, is_train=False),
        text_length=getattr(train_set, "text_length", args.text_length),
        truncate=getattr(train_set, "truncate", True),
    )

    return DataLoader(
        prototype_set,
        batch_size=getattr(args, "test_batch_size", args.batch_size),
        shuffle=False,
        num_workers=args.num_workers,
        collate_fn=collate,
        worker_init_fn=seed_worker,
        generator=make_data_loader_generator(args, offset=5000),
    )


@torch.no_grad()
def _project_prototype_feature_bank(branch, image_features, text_features, batch_size):
    image_projected, text_projected = [], []
    batch_size = max(int(batch_size), 1)
    for start in range(0, image_features.shape[0], batch_size):
        end = start + batch_size
        image_batch, text_batch = branch.project_for_memory(
            image_features[start:end],
            text_features[start:end],
        )
        image_projected.append(image_batch.cpu())
        text_projected.append(text_batch.cpu())
    return torch.cat(image_projected, dim=0), torch.cat(text_projected, dim=0)


def _validate_prototype_init_features(image_features, text_features, pids, expected_len, num_classes):
    if image_features.shape[0] != text_features.shape[0] or image_features.shape[0] != pids.numel():
        raise ValueError(
            "prototype initialization feature count mismatch: "
            f"image={image_features.shape[0]}, text={text_features.shape[0]}, pids={pids.numel()}"
        )
    if expected_len is not None and image_features.shape[0] != expected_len:
        raise ValueError(
            f"prototype initialization scanned {image_features.shape[0]} samples, expected {expected_len}"
        )
    if pids.numel() == 0:
        raise ValueError("prototype initialization saw no samples")
    if pids.min().item() < 0 or pids.max().item() >= num_classes:
        raise ValueError(
            f"prototype pids must be in [0, {num_classes - 1}], "
            f"got min={pids.min().item()} max={pids.max().item()}"
        )
    unique = torch.unique(pids.cpu().long(), sorted=True)
    expected = torch.arange(num_classes, dtype=torch.long)
    if unique.numel() != expected.numel() or not torch.equal(unique, expected):
        missing = sorted(set(expected.tolist()) - set(unique.tolist()))
        raise ValueError(
            "prototype initialization did not cover every train identity; "
            f"missing {len(missing)} identities, first missing={missing[:10]}"
        )


@torch.no_grad()
def maybe_initialize_prototypes(model, train_loader, args, device, logger):
    model_without_ddp = _unwrap_model(model)
    branch = getattr(model_without_ddp, "prototype_branch", None)
    if branch is None or branch.is_ready():
        return

    logger.info("Initializing PBT prototypes from full train embeddings")
    was_training = model_without_ddp.training
    prototype_loader = _build_prototype_init_loader(train_loader, args)
    if prototype_loader is not None:
        logger.info("Using a dedicated no-augmentation loader for prototype initialization")
    else:
        logger.warning("Falling back to the training loader for prototype initialization")
        prototype_loader = train_loader

    image_features, text_features, pids = [], [], []
    try:
        model_without_ddp.eval()
        for batch in prototype_loader:
            batch = {k: v.to(device) for k, v in batch.items()}
            image_feat, text_feat = model_without_ddp.extract_prototype_features(batch)
            image_features.append(image_feat.cpu())
            text_features.append(text_feat.cpu())
            pids.append(batch['pids'].cpu())
    finally:
        model_without_ddp.train(was_training)

    image_features = torch.cat(image_features, dim=0)
    text_features = torch.cat(text_features, dim=0)
    pids = torch.cat(pids, dim=0)
    dataset = getattr(prototype_loader, "dataset", None)
    expected_len = len(dataset) if dataset is not None else None
    _validate_prototype_init_features(
        image_features,
        text_features,
        pids,
        expected_len,
        branch.memory.num_classes,
    )

    if hasattr(branch, "needs_pca_init") and branch.needs_pca_init():
        logger.info("Initializing prototype projector from raw train embeddings")
        branch.initialize_projector_from_features(image_features, text_features)

    image_features, text_features = _project_prototype_feature_bank(
        branch,
        image_features,
        text_features,
        getattr(args, "test_batch_size", getattr(args, "batch_size", 512)),
    )
    branch.initialize_projected(image_features, text_features, pids)
    _sync_prototype_memory(model)
    logger.info("Prototype banks initialized with %d samples", pids.numel())
    synchronize()


def _loss_components(ret):
    return {
        key: value
        for key, value in ret.items()
        if "loss" in key and torch.is_tensor(value)
    }


def _has_prototype_branch(model):
    model = _unwrap_model(model)
    return getattr(model, "prototype_branch", None) is not None


def _grad_norm_by_loss(losses, model):
    params = [p for p in _unwrap_model(model).parameters() if p.requires_grad]
    norms = {}
    if not params:
        return norms

    for name, loss in losses.items():
        if not loss.requires_grad:
            norms[f"{name}_grad_norm"] = 0.0
            continue
        grads = torch.autograd.grad(loss, params, retain_graph=True, allow_unused=True)
        grad_sq_sum = loss.new_zeros(())
        has_grad = False
        for grad in grads:
            if grad is None:
                continue
            has_grad = True
            grad_sq_sum = grad_sq_sum + grad.detach().float().pow(2).sum()
        norms[f"{name}_grad_norm"] = grad_sq_sum.sqrt().item() if has_grad else 0.0
    return norms


def _update_meter(meters, key, value, batch_size):
    if key not in meters:
        meters[key] = AverageMeter()
    if torch.is_tensor(value):
        value = value.detach().item()
    meters[key].update(value, batch_size)


def _best_val_wandb_metrics(best_metrics):
    metrics = {}
    for key in ("R1", "R5", "R10", "mAP", "mINP", "rSum"):
        if key in best_metrics:
            metrics[f"val/best_row/{key}"] = best_metrics[key]
    if best_metrics.get("task"):
        metrics["val/best_row_task"] = best_metrics["task"]
    return metrics


def _train_wandb_metrics(meters, loss_components, optimizer, epoch, current_steps):
    metrics = {
        "train/epoch": epoch,
        "train/iteration": current_steps,
        "train/total_loss": meters["loss"].avg,
        "train/weighted_loss": meters["loss"].avg,
        "train/lr": optimizer.param_groups[0]["lr"],
    }
    lrs = [group["lr"] for group in optimizer.param_groups]
    metrics["train/lr_min"] = min(lrs)
    metrics["train/lr_max"] = max(lrs)

    for loss_key in loss_components.keys():
        if loss_key in meters and meters[loss_key].count > 0:
            metrics[f"train/weighted_loss/{loss_key}"] = meters[loss_key].avg

    for key, meter in meters.items():
        if key.endswith("_grad_norm") and meter.count > 0:
            loss_name = key[: -len("_grad_norm")]
            metrics[f"train/loss_grad_norm/{loss_name}"] = meter.avg

    for key in ("img_acc", "txt_acc", "mlm_acc"):
        if key in meters and meters[key].count > 0:
            metrics[f"train/{key}"] = meters[key].avg

    dashboard_keys = [
        "host_margin_mean",
        "host_margin_p10",
        "hard_pos_margin_mean",
        "negative_intrusion_rate",
        "mean_first_positive_rank",
        "host_intra_i2i_sim_mean",
        "host_intra_t2t_sim_mean",
        "host_intra_xmod_sim_mean",
        "host_paired_xmod_sim_mean",
        "host_inter_i2i_nearest_sim_mean",
        "host_inter_t2t_nearest_sim_mean",
        "host_inter_xmod_nearest_sim_mean",
        "host_i2i_identity_margin_mean",
        "host_t2t_identity_margin_mean",
        "host_xmod_identity_margin_mean",
        "host_topk_neg_attr_sim_mean",
        "host_topk_neg_identity_centroid_sim_mean",
        "host_topk_neg_identity_centroid_distance_mean",
        "host_topk_attr_id_decoupling",
        "host_same_id_alignment_gap",
        "host_identity_centroid_nearest_sim_mean",
        "host_identity_centroid_margin_mean",
        "proto_margin_img_mean",
        "proto_margin_txt_mean",
        "negative_proto_margin_rate",
        "dead_slot_rate",
        "effective_slots_per_id",
        "effective_prototypes",
        "soft_assignment_entropy",
        "soft_assignment_peak",
        "slot_redundancy",
        "assignment_flip_rate",
        "hard_negative_overlap",
        "proto_to_host_margin_corr",
    ]
    for key in dashboard_keys:
        if key in meters and meters[key].count > 0:
            metrics[f"train/{key}"] = meters[key].avg
    return metrics


def _train_console_metrics(loss_components):
    keys = ["loss"]
    for loss_key in loss_components.keys():
        keys.append(loss_key)
        keys.append(f"{loss_key}_grad_norm")
    return keys


def _should_run_initial_eval(start_epoch, eval_after_epoch):
    return (start_epoch - 1) >= eval_after_epoch


def _should_run_epoch_eval(epoch, eval_period, eval_after_epoch):
    return epoch >= eval_after_epoch and epoch % eval_period == 0


def do_train(start_epoch, args, model, train_loader, evaluator, optimizer,
             scheduler, checkpointer):
    log_period = args.log_period
    eval_period = args.eval_period
    device = "cuda"
    num_epoch = args.num_epoch
    arguments = {}
    arguments["num_epoch"] = num_epoch
    arguments["iteration"] = 0
    arguments["epoch"] = start_epoch - 1

    logger = logging.getLogger("dm-adapter.train")
    logger.info('start training')

    meters = {
        "loss": AverageMeter(),
        "sdm_loss": AverageMeter(),
        "itc_loss": AverageMeter(),
        "id_loss": AverageMeter(),
        "mlm_loss": AverageMeter(),
        "imkt_loss": AverageMeter(),
        "triplet_loss": AverageMeter(),
        "triplet_enhance_loss": AverageMeter(),
        "triplet_enhance_shuffle_loss": AverageMeter(),
        "aux_loss": AverageMeter(),
        "proto_id_loss": AverageMeter(),
        "img_acc": AverageMeter(),
        "txt_acc": AverageMeter(),
        "mlm_acc": AverageMeter()
    }

    tb_writer = SummaryWriter(log_dir=args.output_dir)

    best_top1 = 0.0
    eval_after_epoch = max(int(getattr(args, "eval_after_epoch", 0)), 0)
    if _should_run_initial_eval(start_epoch, eval_after_epoch):
        eval_model = model.module.eval() if getattr(args, "distributed", False) else model.eval()
        initial_eval = evaluator.eval(eval_model, return_metrics=(get_rank() == 0))
        if get_rank() == 0 and isinstance(initial_eval, tuple):
            initial_top1, _, initial_best_metrics = initial_eval
            wandb_metrics = {
                "val/epoch": start_epoch - 1,
                "val/top1": initial_top1,
            }
            wandb_metrics.update(_best_val_wandb_metrics(initial_best_metrics))
            wandb_log(wandb_metrics, step=0)

    train_diag_state = {"assignments": {}}
    current_steps = 0

    # train
    for epoch in range(start_epoch, num_epoch + 1):
        start_time = time.time()
        for meter in meters.values():
            meter.reset()
        _set_epoch_on_loader(train_loader, epoch)
        if _prototype_requested(args):
            if epoch > getattr(args, "prototype_warmup_epochs", 0) and not _prototype_ready(model):
                maybe_initialize_prototypes(model, train_loader, args, device, logger)
        model.train()

        for n_iter, batch in enumerate(train_loader):
            current_steps += 1
            batch = {k: v.to(device) for k, v in batch.items()}

            ret = model(batch)

            loss_components = _loss_components(ret)
            total_loss = sum(loss_components.values())

            batch_size = batch['images'].shape[0]
            meters['loss'].update(total_loss.item(), batch_size)
            for loss_key, loss_value in loss_components.items():
                _update_meter(meters, loss_key, loss_value, batch_size)

            for metric_key in ('img_acc', 'txt_acc', 'mlm_acc'):
                if metric_key in ret:
                    _update_meter(meters, metric_key, ret[metric_key], batch_size)

            if (n_iter + 1) % log_period == 0:
                grad_norms = _grad_norm_by_loss(loss_components, model)
                for grad_key, grad_norm in grad_norms.items():
                    _update_meter(meters, grad_key, grad_norm, batch_size)
                train_diag_metrics = compute_train_diagnostics(model, ret, args, train_diag_state)
                for diag_key, diag_value in train_diag_metrics.items():
                    _update_meter(meters, diag_key, diag_value, batch_size)

            optimizer.zero_grad()
            total_loss.backward()
            optimizer.step()
            _sync_prototype_memory(model)
            synchronize()

            if (n_iter + 1) % log_period == 0:
                info_str = f"Epoch[{epoch}] Iteration[{n_iter + 1}/{len(train_loader)}]"
                # log loss and acc info
                for k in _train_console_metrics(loss_components):
                    v = meters.get(k)
                    if v is not None and v.count > 0:
                        info_str += f", {k}: {v.avg:.4f}"
                info_str += f", Base Lr: {args.lr:.2e}"
                logger.info(info_str)
                if get_rank() == 0:
                    wandb_log(_train_wandb_metrics(meters, loss_components, optimizer, epoch, current_steps),
                              step=current_steps)

        tb_writer.add_scalar('lr', scheduler.get_lr()[0], epoch)
        tb_writer.add_scalar('temperature', ret['temperature'], epoch)
        for k, v in meters.items():
            if v.count > 0:
                tb_writer.add_scalar(k, v.avg, epoch)

        scheduler.step()
        if get_rank() == 0:
            end_time = time.time()
            time_per_batch = (end_time - start_time) / (n_iter + 1)
            logger.info(
                "Epoch {} done. Time per batch: {:.3f}[s] Speed: {:.1f}[samples/s]"
                .format(epoch, time_per_batch,
                        batch_size / time_per_batch))
        if _should_run_epoch_eval(epoch, eval_period, eval_after_epoch):
            if get_rank() == 0:
                logger.info("Validation Results - Epoch: {}".format(epoch))
                if args.distributed:
                    top1, _, best_val_metrics = evaluator.eval(model.module.eval(), return_metrics=True)
                else:
                    top1, _, best_val_metrics = evaluator.eval(model.eval(), return_metrics=True)

                wandb_metrics = {
                    "val/epoch": epoch,
                    "val/top1": top1,
                    "val/best_top1": max(best_top1, top1),
                }
                wandb_metrics.update(_best_val_wandb_metrics(best_val_metrics))
                wandb_log(wandb_metrics, step=current_steps)
                torch.cuda.empty_cache()
                if best_top1 < top1:
                    best_top1 = top1
                    arguments["epoch"] = epoch
                    checkpointer.save("best", **arguments)
                    if _has_prototype_branch(model):
                        if hasattr(checkpointer, "save_prototype_branch"):
                            checkpointer.save_prototype_branch("best_prototype_branch", **arguments)
                        if hasattr(checkpointer, "save_prototype_bank"):
                            checkpointer.save_prototype_bank("best_prototype_bank", **arguments)
    if get_rank() == 0:
        logger.info(f"best R1: {best_top1} at epoch {arguments['epoch']}")
        wandb_upload_best_checkpoints(
            args.output_dir,
            logger=logger,
            metadata={
                "best_top1": float(best_top1),
                "best_epoch": int(arguments["epoch"]),
            },
        )



def do_inference(model, test_img_loader, test_txt_loader):
    logger = logging.getLogger("dm-adapter.test")
    logger.info("Enter inferencing")

    evaluator = Evaluator(test_img_loader, test_txt_loader)
    top1 = evaluator.eval(model.eval())
