import os
import sys
import copy
import math
import pprint
from itertools import islice
from functools import partial

import torch
from torch import optim
from torch import nn
from torch.nn import functional as F
from torch import distributed as dist
from torch.utils import data as torch_data
from torch_geometric.data import Data

sys.path.append(os.path.dirname(os.path.dirname(__file__)))
from merc import tasks, util
from merc.models import Merc


separator = ">" * 30
line = "-" * 30


def multigraph_collator(batch, train_graphs):
    probs = torch.tensor([graph.edge_index.shape[1] for graph in train_graphs]).float()
    probs /= probs.sum()
    graph_id = torch.multinomial(probs, 1, replacement=False).item()

    graph = train_graphs[graph_id]
    bs = len(batch)
    edge_mask = torch.randperm(graph.target_edge_index.shape[1])[:bs]

    batch = torch.cat([graph.target_edge_index[:, edge_mask], graph.target_edge_type[edge_mask].unsqueeze(0)]).t()
    return graph, batch

def _unwrap_pred_and_aux(output):
    if isinstance(output, tuple) and len(output) == 2 and isinstance(output[1], dict):
        return output[0], output[1]
    return output, None

# here we assume that train_data and valid_data are tuples of datasets
def train_and_validate(cfg, model, train_data, valid_data, filtered_data=None, batch_per_epoch=None):
    if cfg.train.num_epoch == 0:
        return

    world_size = util.get_world_size()
    rank = util.get_rank()

    # gradient accumulation for effective larger batch sizes
    grad_accum_steps = cfg.train.get("gradient_accumulation_steps", 1)
    logger.warning(f"Using gradient accumulation with {grad_accum_steps} steps")

    # concatenate all target edges from multiple training graphs
    train_triplets = torch.cat([
        torch.cat([g.target_edge_index, g.target_edge_type.unsqueeze(0)]).t()
        for g in train_data
    ])
    sampler = torch_data.DistributedSampler(train_triplets, world_size, rank)
    train_loader = torch_data.DataLoader(train_triplets, cfg.train.batch_size, sampler=sampler,
                                         collate_fn=partial(multigraph_collator, train_graphs=train_data))

    batch_per_epoch = batch_per_epoch or len(train_loader)

    # setup optimizer
    cls = cfg.optimizer.pop("class")
    optimizer = getattr(optim, cls)(model.parameters(), **cfg.optimizer)
    num_params = sum(p.numel() for p in model.parameters())
    logger.warning(line)
    logger.warning(f"Number of parameters: {num_params}")

    # wrap model with DistributedDataParallel for multi-GPU training
    if world_size > 1:
        parallel_model = nn.parallel.DistributedDataParallel(model, device_ids=[device])
    else:
        parallel_model = model

    # periodic evaluation and checkpointing
    step = math.ceil(cfg.train.num_epoch / 10)
    best_result = float("-inf")
    best_epoch = -1

    batch_id = 0
    for i in range(0, cfg.train.num_epoch, step):
        parallel_model.train()
        for epoch in range(i, min(cfg.train.num_epoch, i + step)):
            if util.get_rank() == 0:
                logger.warning(separator)
                logger.warning("Epoch %d begin" % epoch)

            losses = []
            sampler.set_epoch(epoch)

            # initialize gradient accumulation variables
            optimizer.zero_grad()
            accum_loss = 0.0
            accum_steps = 0

            # track attention mechanism statistics over a window
            window_aux_loss = []
            window_att_entropy = []
            window_branch_util = None

            for batch in islice(train_loader, batch_per_epoch):
                # now at each step we sample a new graph and edges from it
                train_graph, batch = batch
                # generate negative samples for each positive triple
                batch = tasks.negative_sampling(train_graph, batch, cfg.task.num_negative,
                                                strict=cfg.task.strict_negative)

                # forward pass through the model
                raw_out = parallel_model(train_graph, batch)
                pred, aux = _unwrap_pred_and_aux(raw_out)

                target = torch.zeros_like(pred)
                target[:, 0] = 1
                bce = F.binary_cross_entropy_with_logits(pred, target, reduction="none")
                neg_weight = torch.ones_like(pred)
                if cfg.task.adversarial_temperature > 0:
                    with torch.no_grad():
                        neg_weight[:, 1:] = F.softmax(pred[:, 1:] / cfg.task.adversarial_temperature, dim=-1)
                else:
                    neg_weight[:, 1:] = 1 / cfg.task.num_negative
                bce = (bce * neg_weight).sum(dim=-1) / neg_weight.sum(dim=-1)
                bce = bce.mean()

                # total loss includes bce and auxiliary losses (e.g., entropy regularization)
                total_loss = bce
                aux_loss_val = None
                if aux is not None and aux.get("aux_loss", None) is not None:
                    total_loss = total_loss + aux["aux_loss"]
                    aux_loss_val = aux["aux_loss"].detach()

                # gradient accumulation
                total_loss = total_loss / grad_accum_steps
                total_loss.backward()
                accum_loss += total_loss.item() * grad_accum_steps
                accum_steps += 1

                # collect attention mechanism statistics for monitoring
                if aux is not None:
                    if aux_loss_val is not None:
                        window_aux_loss.append(float(aux_loss_val))
                    if aux.get("att_entropy", None) is not None:
                        window_att_entropy.append(float(aux["att_entropy"]))
                    if aux.get("att_mean_per_branch", None) is not None:
                        att_branch = aux["att_mean_per_branch"].detach().cpu()
                        if window_branch_util is None:
                            window_branch_util = att_branch.clone()
                        else:
                            window_branch_util += att_branch

                # log training statistics periodically
                if util.get_rank() == 0 and batch_id % cfg.train.log_interval == 0:
                    current_loss = accum_loss / accum_steps
                    logger.warning(separator)
                    logger.warning("binary cross entropy: %g" % current_loss)

                    # log attention entropy (diversity measure)
                    if window_att_entropy:
                        logger.warning("att_entropy (avg over window): %.4f" %
                                       (sum(window_att_entropy) / len(window_att_entropy)))
                    # log auxiliary loss (e.g., entropy regularization)
                    if window_aux_loss:
                        logger.warning("aux_loss (avg over window): %.6f" %
                                       (sum(window_aux_loss) / len(window_aux_loss)))
                    # log branch utilization (how much each branch is used)
                    if window_branch_util is not None:
                        avg_branch = (window_branch_util / max(1, len(window_att_entropy))).numpy()
                        entity_cfg = cfg.model.get("entity_model", {})
                        branch_names = entity_cfg.get("model_list", [])
                        names = [str(branch_names[i]) if i < len(branch_names) else f"b{i}" for i in
                                 range(len(avg_branch))]
                        util_str = ", ".join([f"{name}:{v:.3f}" for name, v in zip(names, avg_branch)])
                        logger.warning("branch utilization (avg att per branch): [%s]" % util_str)

                    # clear window statistics
                    window_aux_loss.clear()
                    window_att_entropy.clear()
                    window_branch_util = None

                # perform optimizer step after accumulating enough gradients
                if accum_steps % grad_accum_steps == 0:
                    optimizer.step()
                    optimizer.zero_grad()
                    losses.append(accum_loss / accum_steps)

                    accum_loss = 0.0
                    accum_steps = 0

                batch_id += 1

            # handle any remaining accumulated gradients
            if accum_steps > 0:
                optimizer.step()
                optimizer.zero_grad()
                losses.append(accum_loss / accum_steps)

            if util.get_rank() == 0:
                avg_loss = sum(losses) / len(losses)
                logger.warning(separator)
                logger.warning("Epoch %d end" % epoch)
                logger.warning(line)
                logger.warning("average binary cross entropy: %g" % avg_loss)

        # save checkpoint at the end of each evaluation period
        epoch = min(cfg.train.num_epoch, i + step)
        if rank == 0:
            logger.warning("Save checkpoint to model_epoch_%d.pth" % epoch)
            state = {
                "model": model.state_dict(),
                "optimizer": optimizer.state_dict()
            }
            torch.save(state, "model_epoch_%d.pth" % epoch)
        util.synchronize()

        # evaluate on validation set
        if rank == 0:
            logger.warning(separator)
            logger.warning("Evaluate on valid")
        result = test(cfg, model, valid_data, filtered_data=filtered_data)

        # track best model based on validation performance
        if result > best_result:
            best_result = result
            best_epoch = epoch

    # load the best checkpoint for final evaluation
    if rank == 0:
        logger.warning("Load checkpoint from model_epoch_%d.pth" % best_epoch)
    state = torch.load("model_epoch_%d.pth" % best_epoch, map_location=device, weights_only=True)
    model.load_state_dict(state["model"])
    util.synchronize()


@torch.no_grad()
def test(cfg, model, test_data, filtered_data=None):
    world_size = util.get_world_size()
    rank = util.get_rank()

    # test_data is a tuple of validation/test datasets
    # process sequentially
    all_metrics = []
    for test_graph, filters in zip(test_data, filtered_data):

        test_triplets = torch.cat([test_graph.target_edge_index, test_graph.target_edge_type.unsqueeze(0)]).t()
        sampler = torch_data.DistributedSampler(test_triplets, world_size, rank)
        test_loader = torch_data.DataLoader(test_triplets, cfg.train.batch_size, sampler=sampler)

        model.eval()
        rankings = []
        num_negatives = []
        for batch in test_loader:
            t_batch, h_batch = tasks.all_negative(test_graph, batch)
            t_pred = model(test_graph, t_batch)
            h_pred = model(test_graph, h_batch)

            if filtered_data is None:
                t_mask, h_mask = tasks.strict_negative_mask(test_graph, batch)
            else:
                t_mask, h_mask = tasks.strict_negative_mask(filters, batch)
            pos_h_index, pos_t_index, pos_r_index = batch.t()
            t_ranking = tasks.compute_ranking(t_pred, pos_t_index, t_mask)
            h_ranking = tasks.compute_ranking(h_pred, pos_h_index, h_mask)
            num_t_negative = t_mask.sum(dim=-1)
            num_h_negative = h_mask.sum(dim=-1)

            rankings += [t_ranking, h_ranking]
            num_negatives += [num_t_negative, num_h_negative]

        ranking = torch.cat(rankings)
        num_negative = torch.cat(num_negatives)
        all_size = torch.zeros(world_size, dtype=torch.long, device=device)
        all_size[rank] = len(ranking)
        if world_size > 1:
            dist.all_reduce(all_size, op=dist.ReduceOp.SUM)
        cum_size = all_size.cumsum(0)
        all_ranking = torch.zeros(all_size.sum(), dtype=torch.long, device=device)
        all_ranking[cum_size[rank] - all_size[rank]: cum_size[rank]] = ranking
        all_num_negative = torch.zeros(all_size.sum(), dtype=torch.long, device=device)
        all_num_negative[cum_size[rank] - all_size[rank]: cum_size[rank]] = num_negative
        if world_size > 1:
            dist.all_reduce(all_ranking, op=dist.ReduceOp.SUM)
            dist.all_reduce(all_num_negative, op=dist.ReduceOp.SUM)

        if rank == 0:
            for metric in cfg.task.metric:
                if metric == "mr":
                    score = all_ranking.float().mean()
                elif metric == "mrr":
                    score = (1 / all_ranking.float()).mean()
                elif metric.startswith("hits@"):
                    values = metric[5:].split("_")
                    threshold = int(values[0])
                    if len(values) > 1:
                        num_sample = int(values[1])
                        # unbiased estimation
                        fp_rate = (all_ranking - 1).float() / all_num_negative
                        score = 0
                        for i in range(threshold):
                            # choose i false positive from num_sample - 1 negatives
                            num_comb = math.factorial(num_sample - 1) / \
                                       math.factorial(i) / math.factorial(num_sample - i - 1)
                            score += num_comb * (fp_rate ** i) * ((1 - fp_rate) ** (num_sample - i - 1))
                        score = score.mean()
                    else:
                        score = (all_ranking <= threshold).float().mean()
                logger.warning("%s: %g" % (metric, score))
        mrr = (1 / all_ranking.float()).mean()

        all_metrics.append(mrr)
        if rank == 0:
            logger.warning(separator)

    avg_metric = sum(all_metrics) / len(all_metrics)
    return avg_metric


if __name__ == "__main__":
    args, vars = util.parse_args()
    cfg = util.load_config(args.config, context=vars)
    working_dir = util.create_working_directory(cfg)

    torch.manual_seed(args.seed + util.get_rank())

    logger = util.get_root_logger()
    if util.get_rank() == 0:
        logger.warning("Random seed: %d" % args.seed)
        logger.warning("Config file: %s" % args.config)
        logger.warning(pprint.pformat(cfg))

    task_name = cfg.task["name"]
    dataset = util.build_dataset(cfg)
    device = util.get_device(cfg)

    train_data, valid_data, test_data = dataset._data[0], dataset._data[1], dataset._data[2]

    if "fast_test" in cfg.train:
        num_val_edges = cfg.train.fast_test
        if util.get_rank() == 0:
            logger.warning(f"Fast evaluation on {num_val_edges} samples in validation")
        short_valid = [copy.deepcopy(vd) for vd in valid_data]
        for graph in short_valid:
            mask = torch.randperm(graph.target_edge_index.shape[1])[:num_val_edges]
            graph.target_edge_index = graph.target_edge_index[:, mask]
            graph.target_edge_type = graph.target_edge_type[mask]

        short_valid = [sv.to(device) for sv in short_valid]

    train_data = [td.to(device) for td in train_data]
    valid_data = [vd.to(device) for vd in valid_data]
    test_data = [tst.to(device) for tst in test_data]

    model = Merc(
        rel_model_cfg=cfg.model.relation_model,
        entity_model_cfg=cfg.model.entity_model,
        entropy_reg_weight=cfg.model.entity_model.get("entropy_reg_weight", 0.003),
        attn_dropout=cfg.model.entity_model.get("attn_dropout", 0.1)
    )

    if "checkpoint" in cfg:
        state = torch.load(cfg.checkpoint, map_location="cpu", weights_only=True)
        model.load_state_dict(state["model"])

    model = model.to(device)

    assert task_name == "MultiGraphPretraining", "Only the MultiGraphPretraining task is allowed for this script"

    # for transductive setting, use the whole graph for filtered ranking
    filtered_data = [
        Data(
            edge_index=torch.cat([trg.target_edge_index, valg.target_edge_index, testg.target_edge_index], dim=1),
            edge_type=torch.cat([trg.target_edge_type, valg.target_edge_type, testg.target_edge_type, ]),
            num_nodes=trg.num_nodes).to(device)
        for trg, valg, testg in zip(train_data, valid_data, test_data)
    ]

    train_and_validate(cfg, model, train_data, valid_data if "fast_test" not in cfg.train else short_valid,
                       filtered_data=filtered_data, batch_per_epoch=cfg.train.batch_per_epoch)
    if util.get_rank() == 0:
        logger.warning(separator)
        logger.warning("Evaluate on valid")
    test(cfg, model, valid_data, filtered_data=filtered_data)
    if util.get_rank() == 0:
        logger.warning(separator)
        logger.warning("Evaluate on test")
    test(cfg, model, test_data, filtered_data=filtered_data)
