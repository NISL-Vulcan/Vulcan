import torch 
import argparse
import yaml
import time
import multiprocessing as mp
from tabulate import tabulate
from tqdm import tqdm
from torch.utils.data import DataLoader
from torch_geometric.data import Data

from pathlib import Path
from torch.utils.tensorboard import SummaryWriter
from torch.cuda.amp import GradScaler, autocast
from torch.nn.parallel import DistributedDataParallel as DDP
from torch.utils.data import DistributedSampler, RandomSampler
from torch import distributed as dist

from vulcan.framework.models import *
from vulcan.framework.datasets import * 
from vulcan.framework.model import get_model
from vulcan.framework.dataset import get_dataset, get_dataloader
from vulcan.framework.losses import get_loss
from vulcan.framework.schedulers import get_scheduler
from vulcan.framework.optimizers import get_optimizer
from vulcan.framework.utils.utils import fix_seeds, setup_cudnn, cleanup_ddp, setup_ddp
from vulcan.cli.val import evaluate

from collections import OrderedDict


def ordered_load(stream, Loader=yaml.SafeLoader, object_pairs_hook=OrderedDict):
    class OrderedLoader(Loader):
        pass
    def construct_mapping(loader, node):
        loader.flatten_mapping(node)
        return object_pairs_hook(loader.construct_pairs(node))
    OrderedLoader.add_constructor(
        yaml.resolver.BaseResolver.DEFAULT_MAPPING_TAG,
        construct_mapping)
    return yaml.load(stream, OrderedLoader)


def main(cfg, gpu, save_dir: Path):
    """核心训练逻辑，供脚本和其他代码复用。"""
    start = time.time()
    best_Acc = 0.0

    num_workers = mp.cpu_count()
    device = torch.device(cfg['DEVICE'])
    train_cfg, eval_cfg = cfg['TRAIN'], cfg['EVAL']
    dataset_cfg, model_cfg = cfg['DATASET'], cfg['MODEL']
    loss_cfg, optim_cfg, sched_cfg = cfg['LOSS'], cfg['OPTIMIZER'], cfg['SCHEDULER']
    epochs, lr = train_cfg['EPOCHS'], optim_cfg['LR']
    
    trainset = get_dataset(cfg , 'train')
    valset = get_dataset(cfg , 'val')

    model = get_model(model_cfg)
    print(model)
    model = model.to(device)

    if train_cfg['DDP']: 
        sampler = DistributedSampler(trainset, dist.get_world_size(), dist.get_rank(), shuffle=True)
        model = DDP(model, device_ids=[gpu])
    else:
        sampler = RandomSampler(trainset)
    
    trainloader = get_dataloader(dataset_cfg, 'train', trainset, batch_size=train_cfg['BATCH_SIZE'], num_workers=num_workers, sampler=sampler)
    valloader = get_dataloader(dataset_cfg, 'val', valset, batch_size=1, num_workers=1)

    iters_per_epoch = len(trainset) // train_cfg['BATCH_SIZE']
    loss_fn = get_loss(loss_cfg['NAME'])
    print('loss func: '+ str(loss_fn))
    optimizer = get_optimizer(model, optim_cfg['NAME'], lr, optim_cfg['WEIGHT_DECAY'])
    scheduler = get_scheduler(sched_cfg['NAME'], optimizer, epochs * iters_per_epoch, sched_cfg['POWER'], iters_per_epoch * sched_cfg['WARMUP'], sched_cfg['WARMUP_RATIO'])
    scaler = GradScaler(enabled=train_cfg['AMP'])
    writer = SummaryWriter(str(save_dir / 'logs'))

    for epoch in range(epochs):
        model.train()
        if train_cfg['DDP']:
            sampler.set_epoch(epoch)

        train_loss = 0.0
        pbar = tqdm(
            enumerate(trainloader),
            total=iters_per_epoch,
            desc=f"Epoch: [{epoch+1}/{epochs}] Iter: [{0}/{iters_per_epoch}] LR: {lr:.8f} Loss: {train_loss:.8f}",
        )
        for iter, data in pbar:
            (input_x, lbl) = data

            optimizer.zero_grad(set_to_none=True)
            try:
                input_x = input_x.to(device)
            except:
                pass
            lbl = lbl.to(device)

            with autocast(enabled=train_cfg['AMP']):
                logits = model(input_x)
                loss = loss_fn(logits, lbl)

            scaler.scale(loss).backward()
            scaler.step(optimizer)
            scaler.update()
            scheduler.step()
            torch.cuda.synchronize()

            lr = scheduler.get_lr()
            lr = sum(lr) / len(lr)
            train_loss += loss.item()

            pbar.set_description(
                f"Epoch: [{epoch+1}/{epochs}] Iter: [{iter+1}/{iters_per_epoch}] LR: {lr:.8f} Loss: {train_loss / (iter+1):.8f}"
            )
        
        train_loss /= iter + 1
        writer.add_scalar('train/loss', train_loss, epoch)
        torch.cuda.empty_cache()

        if (epoch + 1) % train_cfg['EVAL_INTERVAL'] == 0 or (epoch + 1) == epochs:
            print('eval_interval:')
            acc, f1, rec, prec, roc_auc, pr_auc = evaluate(model, valloader, device)
            writer.add_scalar('val/acc', acc, epoch)
            if acc > best_Acc:
                best_Acc = acc
                torch.save(
                    model.module.state_dict() if train_cfg['DDP'] else model.state_dict(),
                    save_dir / f"{model_cfg['NAME']}_{model_cfg['BACKBONE']}_{dataset_cfg['NAME']}.pth",
                )
            print(f"Current Accuracy: {acc} Best Accuracy: {best_Acc}")

    writer.close()
    pbar.close()
    end = time.gmtime(time.time() - start)
    table = [
        ['Best Acc', f"{best_Acc:.2f}"],
        ['Total Training Time', time.strftime("%H:%M:%S", end)]
    ]
    print(tabulate(table, numalign='right'))


def cli_main():
    """命令行入口：解析参数并运行训练。"""
    parser = argparse.ArgumentParser()
    parser.add_argument(
        '--cfg',
        type=str,
        default='configs/custom.yaml',
        help='Configuration file to use',
    )
    args = parser.parse_args()

    with open(args.cfg) as f:
        ordered_dict = ordered_load(f, yaml.SafeLoader)
        cfg = ordered_dict

    fix_seeds(123456)
    setup_cudnn()
    gpu = setup_ddp()
    save_dir = Path(cfg['SAVE_DIR'])
    save_dir.mkdir(exist_ok=True)
    main(cfg, gpu, save_dir)
    cleanup_ddp()

