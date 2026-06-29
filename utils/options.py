import argparse


def get_args(argv=None):
    parser = argparse.ArgumentParser(description="dm-adapter Args")
    ######################## general settings ########################
    parser.add_argument("--local_rank", default=0, type=int)
    parser.add_argument("--name", default="irra_test", help="experiment name to save")
    parser.add_argument("--output_dir", default="logs")
    parser.add_argument("--run_time", default="",
                        help="timestamp used in run output paths; defaults to current time")
    parser.add_argument("--seed", default=1, type=int,
                        help="base random seed for training, data loading, and prototype initialization")
    parser.add_argument("--log_period", default=100, type=int)
    parser.add_argument("--eval_period", default=1, type=int)
    parser.add_argument("--eval_after_epoch", default=0, type=int,
                        help="skip evaluation until this epoch is completed; 0 preserves immediate evaluation")
    parser.add_argument("--val_dataset", default="test")  # use val set when evaluate, if test use test set
    parser.add_argument("--resume", default=False, action='store_true')
    parser.add_argument("--resume_ckpt_file", default="", help='resume from ...')
    parser.add_argument("--wandb", default=False, action='store_true',
                        help="enable Weights & Biases logging on rank 0")
    parser.add_argument("--wandb_project", default="ITSELF",
                        help="Weights & Biases project name")
    parser.add_argument("--wandb_entity", default="",
                        help="optional Weights & Biases entity")
    parser.add_argument("--wandb_name", default="",
                        help="optional Weights & Biases run name override; defaults to YYYYMMDD_HHMMSS")
    parser.add_argument("--wandb_mode", default="online", choices=["online", "offline", "disabled"],
                        help="Weights & Biases mode; --wandb defaults to online")
    parser.add_argument("--wandb_tags", nargs="*", default=[],
                        help="optional Weights & Biases run tags")

    ######################## model general settings ########################
    parser.add_argument("--pretrain_choice", default='ViT-B/16')  # whether  use pretrained model
    parser.add_argument("--temperature", type=float, default=0.02,
                        help="initial temperature value, if 0, don't use temperature")
    parser.add_argument("--img_aug", default=True, action='store_true')

    ## cross modal transfomer setting
    parser.add_argument("--cmt_depth", type=int, default=4, help="cross modal transformer self attn layers")
    parser.add_argument("--masked_token_rate", type=float, default=0.8, help="masked token rate for mlm task")
    parser.add_argument("--masked_token_unchanged_rate", type=float, default=0.1, help="masked token unchanged rate")
    parser.add_argument("--lr_factor", type=float, default=5.0, help="lr factor for random init self implement module")
    # parser.add_argument("--MLM", default=False, action='store_true',
    #                     help="whether to use Mask Language Modeling dataset")
    parser.add_argument("--MLM", default=True, action='store_true',
                        help="whether to use Mask Language Modeling dataset")

    ######################## loss settings ########################
    parser.add_argument("--loss_names", default='itc',
                        help="which loss to use ['mlm', 'cmpm', 'id', 'itc', 'sdm', 'imkt', 'triplet', 'triplet_enhance', 'triplet_enhance_shuffle']")

    parser.add_argument("--mlm_loss_weight", type=float, default=1.0, help="mlm loss weight")
    parser.add_argument("--id_loss_weight", type=float, default=1.0, help="id loss weight")

    ######################## prototype settings ########################
    parser.add_argument("--prototype", default=False, action='store_true',
                        help="build the plug-and-play prototype branch")
    parser.add_argument("--use_loss_id", default=False, action='store_true',
                        help="add the prototype identity regularizer to the training loss")
    parser.add_argument("--no_pbt", default=False, action='store_true',
                        help="use raw cross-modal prototype banks instead of translated PBT banks")
    parser.add_argument("--prototype_feature", type=str, default="auto", choices=["auto", "global"],
                        help="prototype feature source; auto is the host global retrieval embedding")
    parser.add_argument("--prototype_projector", type=str, default="default",
                        choices=[
                            "default",
                            "identity",
                            "residual_identity",
                            "random_orthogonal",
                            "pca_init",
                            "shared",
                            "shared_pca_init",
                        ],
                        help="prototype projection mode")
    parser.add_argument("--prototype_residual_scale", type=float, default=0.1,
                        help="scale for --prototype_projector residual_identity")
    parser.add_argument("--prototype_per_id", type=int, default=2)
    parser.add_argument("--prototype_dim", type=int, default=512)
    parser.add_argument("--prototype_kmeans_iters", type=int, default=20)
    parser.add_argument("--prototype_warmup_epochs", type=int, default=0)
    parser.add_argument("--prototype_tau", type=float, default=0.05)
    parser.add_argument("--prototype_hard_k", type=int, default=16)
    parser.add_argument("--prototype_id_weight", type=float, default=0.2)
    parser.add_argument("--prototype_momentum", type=float, default=0.2)

    ######################## vison trainsformer settings ########################
    parser.add_argument("--img_size", type=tuple, default=(384, 128))
    parser.add_argument("--stride_size", type=int, default=16)

    ######################## text transformer settings ########################
    parser.add_argument("--text_length", type=int, default=77)
    parser.add_argument("--vocab_size", type=int, default=49408)

    ######################## solver ########################
    parser.add_argument("--optimizer", type=str, default="Adam", help="[SGD, Adam, Adamw]")
    parser.add_argument("--lr", type=float, default=1e-5)
    parser.add_argument("--prototype_lr", type=float, default=None,
                        help="absolute learning rate for prototype_branch; defaults to lr * lr_factor")
    parser.add_argument("--bias_lr_factor", type=float, default=2.)
    parser.add_argument("--momentum", type=float, default=0.9)
    parser.add_argument("--weight_decay", type=float, default=4e-5)
    parser.add_argument("--weight_decay_bias", type=float, default=0.)
    parser.add_argument("--alpha", type=float, default=0.9)
    parser.add_argument("--beta", type=float, default=0.999)

    ######################## scheduler ########################
    parser.add_argument("--num_epoch", type=int, default=60)
    parser.add_argument("--milestones", type=int, nargs='+', default=(20, 50))
    parser.add_argument("--gamma", type=float, default=0.1)
    parser.add_argument("--warmup_factor", type=float, default=0.1)
    parser.add_argument("--warmup_epochs", type=int, default=5)
    parser.add_argument("--warmup_method", type=str, default="linear")
    parser.add_argument("--lrscheduler", type=str, default="cosine")
    parser.add_argument("--target_lr", type=float, default=0)
    parser.add_argument("--power", type=float, default=0.9)

    ######################## dataset ########################
    parser.add_argument("--dataset_name", default="CUHK-PEDES", help="[CUHK-PEDES, ICFG-PEDES, RSTPReid]")
    parser.add_argument("--sampler", default="random", help="choose sampler from [identity, random]")
    parser.add_argument("--num_instance", type=int, default=4)
    parser.add_argument("--root_dir", default="/root/dataset_reid")
    parser.add_argument("--batch_size", type=int, default=64)
    parser.add_argument("--test_batch_size", type=int, default=512)
    parser.add_argument("--num_workers", type=int, default=8)
    parser.add_argument("--test", dest='training', default=True, action='store_false')

    ######################## MOE #############################
    parser.add_argument("--num_experts", type=int, default=6)
    parser.add_argument("--topk", type=int, default=2)
    parser.add_argument("--reduction", type=int, default=8)

    args = parser.parse_args(argv)

    return args
