import numpy as np
import argparse
import os
import time
import random
import logging
import sys
import glob
from torch.utils.tensorboard import SummaryWriter
from tqdm import tqdm
import tracemalloc

import torch
import torch.backends.cudnn as cudnn
from torch.utils.data import DataLoader
from torch.utils.data.sampler import SubsetRandomSampler
import copy

from data.dataset import generate_dataset

from utils.fed_merge import FedAvg, FedUpdate

from utils.cls.train_fedavg import train
from utils.cls.test import test

from utils.cls.selection_methods import query_samples
from utils.utils import cnt_sample_num, statis_acc
import pdb
import warnings
from sklearn.exceptions import UndefinedMetricWarning
import pickle


parser = argparse.ArgumentParser()
parser.add_argument('--fl_method', type=str,  default='FedAvg', help='federated method')
parser.add_argument('--al_method', type=str,  default='Random', help='sampling method')
parser.add_argument('--dataset', type=str,  default='FedISIC', help='dataset')

parser.add_argument('--max_round', type=int,  default=100, help='maximum round number of FL')
parser.add_argument('--al_round', type=int,  default=5, help='maximum round number of AL')

parser.add_argument('--query_model', type=str,  default='global', help='query model')
parser.add_argument('--query_ratio', type=float,  default=0, help='query ratio')
parser.add_argument('--budget', type=int,  default=500, help='query budget')

parser.add_argument('--batch_size', type=int, default=32, help='batch size')
parser.add_argument('--base_lr', type=float,  default=5e-4, help='learning rate')
parser.add_argument('--deterministic', type=bool,  default=False, help='whether use deterministic training')

parser.add_argument('--seed', type=int,  default=0, help='random seed')
parser.add_argument('--display_freq', type=int, default=25, help='display fequency')

parser.add_argument('--kl_weight', type=float, default=0.01, help='edl kl weight')
parser.add_argument('--annealing_step', type=int, default=10, help='annealing_step')
parser.add_argument('--n_neighbor', type=int, default=5, help='number of neighbors')
parser.add_argument('--cosine', type=float, default=0.85, help='cosine')

parser.add_argument('--model_pool_step', type=int, default=2, help='model pool sampling interval S')
parser.add_argument('--model_pool_size', type=int, default=20, help='number of models N in pool')

parser.add_argument('--s_step', type=int, default=1, help='s_step')

parser.add_argument('--cluster_size', type=int, default=10, help='cluster size')

# ---- NEW arg for TMFAL+ ----
parser.add_argument('--kappa', type=int, default=4, help='candidate pool multiplier for two-stage selection in ours2')

args = parser.parse_args()


def worker_init_fn(worker_id):
    random.seed(args.seed + worker_id)


if __name__ == '__main__':
    # log
    localtime = time.localtime(time.time())
    ticks = '{:>02d}{:>02d}{:>02d}{:>02d}{:>02d}'.format(
        localtime.tm_mon, localtime.tm_mday, localtime.tm_hour, localtime.tm_min, localtime.tm_sec)

    snapshot_path = "logs/{}/{}/{}_{}_{}_{}/".format(
        args.dataset.lower(), args.query_model,
        args.dataset, args.fl_method, args.al_method, ticks)
    if not os.path.exists(snapshot_path):
        os.makedirs(snapshot_path)
    if not os.path.exists(snapshot_path + '/model'):
        os.makedirs(snapshot_path + '/model')

    warnings.filterwarnings("ignore", message="y_pred contains classes not in y_true")
    logging.basicConfig(filename=snapshot_path + "/log.txt", level=logging.INFO,
                        format='[%(asctime)s.%(msecs)03d] %(message)s', datefmt='%H:%M:%S')
    logging.getLogger().addHandler(logging.StreamHandler(sys.stdout))
    logging.info(str(args))
    
    with open(os.path.join(snapshot_path, 'global_test_result.txt'), 'a') as f:
        print(args, file=f)

    # init
    dataset = args.dataset
    assert dataset in ['FedISIC', 'FedCamelyon']
    fl_method = args.fl_method
    assert fl_method in ['FedAvg']

    if dataset == 'FedISIC':
        num_classes = 8
        client_num = 4
        SUBSET = 10000
        from model.efficientnet import EfficientNetB0 as Model
    elif dataset == 'FedCamelyon':
        num_classes = 2
        client_num = 5
        SUBSET = 10000
        from model.efficientnet import DENSENET121 as Model

    train_slice_num = np.zeros(client_num, dtype=int)
    batch_size = args.batch_size
    base_lr = args.base_lr
    max_round = args.max_round
    display_freq = args.display_freq

    # al
    al_method = args.al_method
    # ---- updated assert to include ours2 and novel ----
    assert al_method in ['Random', 'FEAL', 'ours', 'ours2', 'novel']
    al_round = args.al_round
    query_model = args.query_model
    assert query_model in ['global', 'local', 'both']
    query_ratio = args.query_ratio
    query_num = np.zeros(client_num, dtype=int)
    if query_ratio == 0:
        budget = args.budget

    # random seed
    if args.deterministic:
        cudnn.benchmark = False
        cudnn.deterministic = True
        random.seed(args.seed)
        np.random.seed(args.seed)
        torch.manual_seed(args.seed)
        torch.cuda.manual_seed(args.seed)

    # local dataloader, model, optimizer
    local_models = []

    local_train_data = []
    local_unlabeled_data = []

    local_labeled_sets = []
    local_unlabeled_sets = []

    local_train_loaders = []
    local_test_loaders = []

    al_best_accs = []

    for client_idx in range(client_num):
        # data
        data_train, data_unlabeled, data_test = generate_dataset(
            dataset=dataset, fl_method=fl_method, client_idx=client_idx, args=args)

        local_train_data.append(data_train)
        local_unlabeled_data.append(data_unlabeled)

        # init
        train_slice_num[client_idx] = len(data_train)
        if query_ratio == 0:
            if budget <= np.ceil(0.85 * train_slice_num[client_idx]):
                query_num[client_idx] = budget
            else:
                query_num[client_idx] = np.ceil(0.85 * train_slice_num[client_idx])
        else:
            query_num[client_idx] = np.floor(len(data_train) * query_ratio)

        # initial set
        indices = list(range(train_slice_num[client_idx]))
        random.shuffle(indices)
        labeled_set = indices[:query_num[client_idx]]
        unlabeled_set = indices[query_num[client_idx]:]
        local_labeled_sets.append(labeled_set)
        local_unlabeled_sets.append(unlabeled_set)

        # dataloader
        train_loader = DataLoader(
            dataset=data_train, batch_size=batch_size,
            sampler=SubsetRandomSampler(labeled_set),
            num_workers=4, pin_memory=True)
        test_loader = DataLoader(
            dataset=data_test, batch_size=batch_size,
            shuffle=False, num_workers=4, pin_memory=True)

        local_train_loaders.append(train_loader)
        local_test_loaders.append(test_loader)

        # model
        model = Model(num_classes=num_classes).cuda()
        local_models.append(model)

    writer = SummaryWriter(snapshot_path + '/log')
    logging.info(args)

    # active learning
    print('total slice: {}'.format(train_slice_num))
    for al_round_idx in tqdm(range(al_round), ncols=100):

        al_best_acc = 0

        logging.info('\nAL round {}'.format(al_round_idx + 1))

        # global model
        global_model = Model(num_classes=num_classes).cuda()

        local_optimizers = []
        local_schedulers = []
        for client_idx in range(client_num):
            if dataset in ['FedISIC']:
                optimizer = torch.optim.Adam(
                    local_models[client_idx].parameters(), lr=args.base_lr, weight_decay=5e-4)
                scheduler = torch.optim.lr_scheduler.MultiStepLR(optimizer, milestones=[50], gamma=0.1)
            elif dataset in ['FedCamelyon']:
                optimizer = torch.optim.Adam(
                    local_models[client_idx].parameters(), lr=args.base_lr, weight_decay=1e-5)
                scheduler = torch.optim.lr_scheduler.MultiStepLR(optimizer, milestones=[50], gamma=0.1)
            local_optimizers.append(optimizer)
            local_schedulers.append(scheduler)

        train_num = [len(item) for item in local_labeled_sets]
        with open(os.path.join(snapshot_path, 'global_test_result.txt'), 'a') as f:
            print('train num: {}'.format(train_num), file=f)

        num_per_class = [cnt_sample_num(local_train_loaders[client_idx], num_classes)
                         for client_idx in range(client_num)]
        FedUpdate(global_model, local_models)   # init

        model_pools = []
        local_model_pools = {}
        for client_idx in range(client_num):
            local_model_pools[client_idx] = []

        # For adaptive temporal pooling
        client_min_loss = {c: float('inf') for c in range(client_num)}

        # federated learning in an AL round
        for round_idx in range(max_round):
            round_losses = []
            for client_idx in range(client_num):
                avg_loss = train(round_idx=round_idx,
                      client_idx=client_idx,
                      model=local_models[client_idx],
                      dataloader=local_train_loaders[client_idx],
                      optimizer=local_optimizers[client_idx],
                      num_per_class=num_per_class[client_idx],
                      args=args)
                local_schedulers[client_idx].step()
                round_losses.append(avg_loss)

            client_weight = np.array(train_num, dtype=float)
            client_weight = client_weight / client_weight.sum()
            logging.info(client_weight)

            # Adaptive Temporal Pooling
            if args.al_method == 'novel':
                # Dynamically select based on loss trajectory
                added_any = False
                for client_idx in range(client_num):
                    if round_losses[client_idx] < client_min_loss[client_idx]:
                        client_min_loss[client_idx] = round_losses[client_idx]
                        local_model_pools[client_idx].append(copy.deepcopy(local_models[client_idx].state_dict()))
                        added_any = True
                
                # Update global model before checking if we add it
                FedAvg(global_model, local_models, client_weight)
                
                if added_any:
                    model_pools.append(copy.deepcopy(global_model.state_dict()))
            else:
                if (round_idx + 1) % args.model_pool_step == 0:
                    for client_idx in range(client_num):
                        local_model_pools[client_idx].append(
                            copy.deepcopy(local_models[client_idx].state_dict()))

                FedAvg(global_model, local_models, client_weight)

                if (round_idx + 1) % args.model_pool_step == 0:
                    model_pools.append(copy.deepcopy(global_model.state_dict()))

            if (round_idx + 1) % 1 == 0:
                with open(os.path.join(snapshot_path, 'global_test_result.txt'), 'a') as f:
                    print('AL round {}, FL round {}'.format(al_round_idx + 1, round_idx + 1), file=f)

                avg_acc = 0
                for client_idx in range(client_num):
                    metric = test(dataset=dataset, model=global_model,
                                  dataloader=local_test_loaders[client_idx],
                                  client_idx=client_idx)
                    with open(os.path.join(snapshot_path, 'global_test_result.txt'), 'a') as f:
                        if dataset in ['FedISIC', 'FedCamelyon']:
                            print('client {}. Balanced acc:\t{}'.format(client_idx, metric), file=f)
                    avg_acc += metric
                print('\n')
                avg_acc /= client_num

                if avg_acc > al_best_acc:
                    al_best_acc = avg_acc

            if round_idx == max_round - 1:
                al_best_accs.append(al_best_acc)
                logging.info(al_best_accs)
                with open(os.path.join(snapshot_path, 'global_test_result.txt'), 'a') as f:
                    print('Best Acc:\t{}'.format(al_best_acc), file=f)

            if round_idx == max_round - 1 and al_round_idx < al_round - 1:

                # query samples
                for client_idx in range(client_num):

                    # save local models
                    save_model_path = os.path.join(
                        snapshot_path + '/model/AL{}_FL{}_client{}.pth'.format(
                            al_round_idx + 1, round_idx + 1, client_idx))
                    torch.save(local_models[client_idx].state_dict(), save_model_path)

                    if len(local_labeled_sets[client_idx]) >= np.ceil(0.85 * train_slice_num[client_idx]):
                        continue
                    if len(local_labeled_sets[client_idx]) + query_num[client_idx] > \
                            np.ceil(0.85 * train_slice_num[client_idx]):
                        query_num[client_idx] = (
                            np.ceil(0.85 * train_slice_num[client_idx]) -
                            len(local_labeled_sets[client_idx])
                        ).astype('int')

                    if len(local_unlabeled_sets[client_idx]) <= query_num[client_idx]:
                        subset = local_unlabeled_sets[client_idx][:SUBSET]
                        rank_arg = list(range(len(local_unlabeled_sets[client_idx])))
                    else:
                        random.shuffle(local_unlabeled_sets[client_idx])
                        subset = local_unlabeled_sets[client_idx][:SUBSET]

                        if query_model == 'both':
                            target_model_pools = (model_pools[:args.model_pool_size] +
                                                  local_model_pools[client_idx][:args.model_pool_size])
                        elif query_model == 'global':
                            target_model_pools = model_pools[:args.model_pool_size]
                        elif query_model == 'local':
                            target_model_pools = local_model_pools[client_idx][:args.model_pool_size]

                        rank_arg = query_samples(
                            al_method=al_method,
                            global_model=global_model,
                            local_model=local_models[client_idx],
                            data_unlabeled=local_unlabeled_data[client_idx],
                            # ---- NEW: pass labeled dataset ----
                            data_labeled=local_unlabeled_data[client_idx],
                            unlabeled_set=subset,
                            labeled_set=local_labeled_sets[client_idx],
                            query_num=query_num[client_idx],
                            num_per_class=num_per_class[client_idx],
                            client_idx=client_idx,
                            round_idx=al_round_idx,
                            args=args,
                            model_pools=target_model_pools,
                            cluster_size=args.cluster_size,
                            s_step=args.s_step,
                            # ---- NEW args ----
                            num_classes=num_classes,
                            kappa=args.kappa,
                        )

                    query_set = list(torch.tensor(subset)[rank_arg][-query_num[client_idx]:].numpy())
                    local_labeled_sets[client_idx] += query_set
                    listd = list(torch.tensor(subset)[rank_arg][:-query_num[client_idx]].numpy())
                    local_unlabeled_sets[client_idx] = listd + local_unlabeled_sets[client_idx][SUBSET:]

                    # update local_train_loaders
                    local_train_loaders[client_idx] = DataLoader(
                        dataset=local_train_data[client_idx],
                        batch_size=batch_size,
                        sampler=SubsetRandomSampler(local_labeled_sets[client_idx]),
                        num_workers=4, pin_memory=True)

            FedUpdate(global_model, local_models)   # distribute

        save_model_path = os.path.join(
            snapshot_path + '/model/AL{}_FL{}_global.pth'.format(al_round_idx + 1, round_idx + 1))
        torch.save(global_model.state_dict(), save_model_path)

    print(al_best_accs)
    writer.close()
