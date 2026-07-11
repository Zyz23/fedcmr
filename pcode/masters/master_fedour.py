# # -*- coding: utf-8 -*-
# import os
# import copy

# import numpy as np
# import torch
# import torch.distributed as dist
# from pcode.utils.module_state import ModuleState
# import pcode.master_utils as master_utils
# import pcode.create_coordinator as create_coordinator
# import pcode.create_dataset as create_dataset
# import pcode.create_metrics as create_metrics
# import pcode.create_model as create_model
# import pcode.utils.checkpoint as checkpoint
# from pcode.utils.tensor_buffer import TensorBuffer
# import pcode.utils.cross_entropy as cross_entropy
# from pcode.utils.early_stopping import EarlyStoppingTracker


# class MasterFedOur(object):
#     def __init__(self, conf):
#         self.conf = conf

#         # some initializations.
#         self.client_ids = list(range(1, 1 + conf.n_clients)) #总的客户端id列表 
#         self.world_ids = list(range(1, 1 + conf.n_participated))  # 总的参与客户端id列表 

#         # create model as well as their corresponding state_dicts.
#         # 创建服务器模型 不需要arch
#         # _, self.master_model = create_model.define_model( # 获取模型
#         #     conf, to_consistent_model=False
#         # )
#         # 所有客户端的模型架构  
#         self.used_client_archs =[ 
#                 create_model.determine_arch(conf, client_id, use_complex_arch=True)
#                 for client_id in range(1, 1 + conf.n_clients)
#             ]
        
        
       
        
#         self.conf.used_client_archs = self.used_client_archs
#         # 打印日志 客户端使用的模型架构 和服务器已经为客户端创建模型架构
#         conf.logger.log(f"The client will use archs={self.used_client_archs}.")
#         conf.logger.log("Master created model templates for client models.")

#         #创建客户端模型字典 便于异构聚合 包含了模型参数
#         # self.client_models = dict( # 获取客户端模型信息
#         #     create_model.define_model(conf, to_consistent_model=False, arch=arch)
#         #     for arch in self.used_client_archs
#         # )
#         # 使用客户端ID作为字典的键
#         self.client_models = {
#             client_id: create_model.define_model(conf, to_consistent_model=False, client_id=client_id, arch=arch)
#             for client_id, arch in zip(range(1, 1 + conf.n_clients), self.used_client_archs)
#         }
# # 创建服务器模型 选取第一个客户端的全秩模型作为基准
#         first_model_name, first_model_instance = self.client_models[1]
#         self.master_model = copy.deepcopy(first_model_instance)
#         print()
#         self.master_model.recover_model() # 初始模型都是分解的 先恢复全职模型


        


#         # 确定每一个客户的具体使用的什么模型 只有名称 没有返回模型参数

#         self.clientid2arch = dict( # 获取所有客户端的模型名称
#             (
#                 client_id,
#                 create_model.determine_arch(
#                     conf, client_id=client_id, use_complex_arch=True
#                 ),
#             )
#             for client_id in range(1, 1 + conf.n_clients)
#         )
#         self.conf.clientid2arch = self.clientid2arch

#         conf.logger.log(
#             f"Master initialize the clientid2arch mapping relations: {self.clientid2arch}."
#         )

#         # create dataset (as well as the potential data_partitioner) for training.
#         dist.barrier()
#         self.dataset = create_dataset.define_dataset(conf, data=conf.data, agg_data_ratio=conf.agg_data_ratio)
#         _, self.data_partitioner = create_dataset.define_data_loader(
#             self.conf,
#             dataset=self.dataset["train"],
#             localdata_id=0,  # random id here.
#             is_train=True,
#             data_partitioner=None,
#         ) # 虽然划分了数据但是全丢了，只保留数据划分器



#         conf.logger.log(f"Master initialized the local training data with workers.")

#         # create val loader.
#         # right now we just ignore the case of partitioned_by_user.
#         if self.dataset["val"] is not None:
#             assert not conf.partitioned_by_user
#             self.val_loader, _ = create_dataset.define_data_loader(
#                 conf, self.dataset["val"], is_train=False
#             )
#             conf.logger.log(f"Master initialized val data.")
#         else:
#             self.val_loader = None

#         # create test loaders.
#         # localdata_id start from 0 to the # of clients - 1. client_id starts from 1 to the # of clients.
#         if conf.partitioned_by_user:
#             self.test_loaders = []
#             for localdata_id in self.client_ids:
#                 test_loader, _ = create_dataset.define_data_loader(
#                     conf,
#                     self.dataset["test"],
#                     localdata_id=localdata_id - 1,
#                     is_train=False,
#                     shuffle=False,
#                 )
#                 self.test_loaders.append(copy.deepcopy(test_loader))
#         else:
#             test_loader, _ = create_dataset.define_data_loader(
#                 conf, self.dataset["test"], is_train=False
#             )
#             self.test_loaders = [test_loader] # 这里的test_loader和上面的val_loader都是总的，也就是说未平分给客户端的

#         # define the criterion and metrics.
#         self.criterion = cross_entropy.CrossEntropyLoss(reduction="mean")   # 模型的损失函数，这里传入mean表示计算的损失会求平均
#         self.metrics = create_metrics.Metrics(self.master_model, task="classification")  # 模型的评估，计算准确率之类
#         conf.logger.log(f"Master initialized model/dataset/criterion/metrics.")

#         self.coordinator = create_coordinator.Coordinator(conf, self.metrics)   # 记录最佳性能
#         if not self.conf.train_fast:
#             self.local_coordinator = [create_coordinator.Coordinator(conf, self.metrics) for _ in
#                                       range(self.conf.n_clients)]

#         conf.logger.log(f"Master initialized the coordinator.\n")

#         # define early_stopping_tracker.
#         self.early_stopping_tracker = EarlyStoppingTracker(
#             patience=conf.early_stopping_rounds
#         )   # 早停装置，为0时关掉早停功能

#         # save arguments to disk.
#         conf.is_finished = False    # 用于控制全局训练是否已经结束
#         checkpoint.save_arguments(conf) # 将超参数保存在json文件中

#     def run(self):

        
#         for comm_round in range(1, 1 + self.conf.n_comm_rounds):
#             self.conf.graph.comm_round = comm_round
#             self.conf.logger.log(
#                 f"Master starting one round of federated learning: (comm_round={comm_round})."
#             )

#             # get random n_local_epochs.
#             list_of_local_n_epochs = get_n_local_epoch(
#                 conf=self.conf, n_participated=self.conf.n_participated
#             )   # 生成参与数长的列表，每个值为每个客户端的训练轮数
#             self.list_of_local_n_epochs = list_of_local_n_epochs

#             # random select clients from a pool.对应真实的id号
#             selected_client_ids = self._random_select_clients() # 随机选择客户端

#             # detect early stopping.
#             self._check_early_stopping() # 检查是否满足早停，可能未开启早停

#             # init the activation tensor and broadcast to all clients (either start or stop).
#             self.activate_selected_clients(
#                 selected_client_ids, self.conf.graph.comm_round, list_of_local_n_epochs
#             )

#             # will decide to send the model or stop the training.
#             if not self.conf.is_finished:
#                 self.send_extra_info_to_selected_clients(selected_client_ids)

#                 # broadcast the model to activated clients.
#                 self._send_model_to_selected_clients(selected_client_ids)

#             else:
#                 dist.barrier()
#                 self.conf.logger.log(
#                     f"Master finished the federated learning by early-stopping: (current comm_rounds={comm_round}, total_comm_rounds={self.conf.n_comm_rounds})"
#                 )
#                 return

#             self.receive_extra_info_from_selected_clients(selected_client_ids)

#             # wait to receive the local models.
#             flatten_local_models = self._receive_models_from_selected_clients(
#                 selected_client_ids
#             ) # 接受模型参数

#             # aggregate the local models and evaluate on the validation dataset.
#             self._aggregate_model_and_evaluate(flatten_local_models, selected_client_ids)   # 聚合模型，评估和存档

#             # evaluate the aggregated model.
#             self.conf.logger.log(f"Master finished one round of federated learning.\n")

#         # formally stop the training (the master has finished all communication rounds).
#         dist.barrier()
#         self._finishing()

#     def receive_extra_info_from_selected_clients(self, selected_client_ids):
#         pass


#     def _random_select_clients(self):
#         selected_client_ids = self.conf.random_state.choice(
#             self.client_ids, self.conf.n_participated, replace=False
#         ).tolist()  # 随机选择客户端
#         selected_client_ids.sort()
#         self.conf.logger.log(
#             f"Master selected {self.conf.n_participated} from {self.conf.n_clients} clients: {selected_client_ids}."
#         )
#         return selected_client_ids

#     def activate_selected_clients(
#             self, selected_client_ids, comm_round, list_of_local_n_epochs, to_send_history=False
#     ):
#         # Activate the selected clients:
#         # the first row indicates the client id,
#         # the second row indicates the current_comm_round,
#         # the third row indicates the expected local_n_epochs
#         selected_client_ids = np.array(selected_client_ids)
#         msg_len = 3 # 消息行数

#         activation_msg = torch.zeros((msg_len, len(selected_client_ids)))
#         activation_msg[0, :] = torch.Tensor(selected_client_ids) # 第一行装客户端id
#         activation_msg[1, :] = comm_round                       # 第二行装联邦轮次
#         activation_msg[2, :] = torch.Tensor(list_of_local_n_epochs)     # 第三行装每个客户端训练轮数

#         dist.broadcast(tensor=activation_msg, src=0)
#         self.conf.logger.log(f"Master activated the selected clients.")
#         dist.barrier()

#     def _send_model_to_selected_clients(self, selected_client_ids):
#         # the master_model can be large; the client_models can be small and different.
#         self.conf.logger.log(f"Master send the models to workers.")

#         """
#         流程：
#         1. 获取 Master 参数 (Full Rank)。
#         2. 遍历每个被选中的 Client。
#         3. 将 Master 参数加载到 Client 模型中 (此时 Client 模型必须是 Recover 状态才能匹配 Key)。
#         4. 根据 Client 配置的 Rank 对模型进行 Decompose。
#         5. 打包发送。
#         """

# # 更新服务器端存储的客户端模型参数（J基于 全局模型参数填充）
#         rank_list = self.conf.rank_list # 获取所有模型的秩
#         master_model_state_dict= self.master_model.state_dict()#获取 Master 参数



#         for worker_rank, selected_client_id in enumerate(selected_client_ids, start=1):
#             _,client_model = self.client_models[selected_client_id] # 1 取出该客户端的模型对象
#             client_model.to('cuda:7')
#             if hasattr(client_model, "recover_model"):
#                 client_model.recover_model() # 2 恢复全秩
#             client_model.to('cuda:7')

#             client_model.load_state_dict(master_model_state_dict) # 3. 加载全局参数

#             arch = self.clientid2arch[selected_client_id] # 获取当前循环模型名称

#             current_rank_ratio = rank_list[selected_client_id - 1] #根据该客户端的 Rank 进行分解
#             if hasattr(client_model, "decom_model"):
#                 client_model.decom_model(current_rank_ratio)
#             client_model.to('cpu')

#             # client_model_state_dict = self.client_models[arch].state_dict()
#             # 改为 由id获取字典的元组 
            
#             client_model_state_dict = client_model.state_dict()


#             flatten_model = TensorBuffer(list(client_model_state_dict.values())) # 打包模型参数
#             dist.send(tensor=flatten_model.buffer, dst=worker_rank) # 发送参数到对应模型
#             self.conf.logger.log(
#                 f"\tMaster send the current model={arch} to process_id={worker_rank}."
#             )

#         dist.barrier()

#     def send_extra_info_to_selected_clients(self, selected_client_ids):
#         pass

#     def _receive_models_from_selected_clients(self, selected_client_ids):
#         self.conf.logger.log(f"Master waits to receive the local models.")
#         dist.barrier()

#         # init the placeholders to recv the local models from workers.
#         flatten_local_models = dict()
#         for selected_client_id in selected_client_ids: # 为接受数据准备容器，这也可以解释为什么要在服务器创建模型
#             arch = self.clientid2arch[selected_client_id]
#             # client_tb = TensorBuffer(
#             #     list(self.client_models[arch].state_dict().values())
#             # )
#             # 改为
#             _, client_model = self.client_models[selected_client_id]
            
#             current_rank_ratio = self.conf.rank_list[selected_client_id - 1]
#             if hasattr(client_model, "decom_model"):
#                 client_model.decom_model(current_rank_ratio)
#             client_tb = TensorBuffer(list(client_model.state_dict().values()))
            
#             client_tb.buffer = torch.zeros_like(client_tb.buffer)
#             flatten_local_models[selected_client_id] = client_tb

#         # async to receive model from clients.
#         reqs = []
#         for client_id, world_id in zip(selected_client_ids, self.world_ids):
#             req = dist.irecv(
#                 tensor=flatten_local_models[client_id].buffer, src=world_id
#             )   # 这里并不会阻塞，相当于告诉客户端数据放在哪里
#             reqs.append(req)

#         for req in reqs:
#             req.wait()  # 这里会阻塞等待数据

#         dist.barrier()
#         self.conf.logger.log(f"Master received all local models.")
#         return flatten_local_models

#     def _fedavg(self, flatten_local_models, weights=None):
#         n_selected_clients = len(flatten_local_models)

#         if weights == None:
#             weights = [
#                 torch.FloatTensor([1.0 / n_selected_clients]) for _ in range(n_selected_clients)
#             ]
#         # 存储所有客户端恢复后的全秩 StateDict
#         recovered_state_dicts = []

#         # NOTE: the arch for different local models needs to be the same as the master model.
#         # retrieve the local models.
#         local_models = {}
#         for client_idx, flatten_local_model in flatten_local_models.items():
#             _arch = self.clientid2arch[client_idx]
#             # _model = copy.deepcopy(self.client_models[_arch])
#              # _model = copy.deepcopy(_model)
#             _, client_model = self.client_models[client_idx] # 1. 获取模型实例
           
#             # 2. [确保状态] 必须处于分解状态才能 unpack buffer
#             current_rank_ratio = self.conf.rank_list[client_idx - 1]
#             if hasattr(client_model, "decom_model"):
#                 client_model.decom_model(current_rank_ratio)
            
#             # 3. Unpack 数据 (将 Buffer 填入模型的 U, V 参数中)
#             current_state_dict = client_model.state_dict()
#             flatten_local_model.unpack(current_state_dict.values())
#             client_model.load_state_dict(current_state_dict)

#             # 4. [关键] 恢复全秩 (Recover)
#             if hasattr(client_model, "recover_model"):
#                 client_model.recover_model()
#             # 5. 保存恢复后的全秩参数用于后续平均
#             recovered_state_dicts.append(copy.deepcopy(client_model.state_dict()))
#         # 6. 开始聚合 (FedAvg)
#         # 取第一个模型作为累加基底
#         avg_model_state = copy.deepcopy(recovered_state_dicts[0])
#             # 将参数转换为 Tensor 进行加权
#         for key in avg_model_state.keys():
#             # 初始化为第一个模型的加权值
#             if "num_batches_tracked" in key:
#                  # BatchNorm 的计数参数通常取 sum 或者 max，这里简化处理保持第一个
#                  avg_model_state[key] = avg_model_state[key]
#             else:
#                 avg_model_state[key] = avg_model_state[key] * weights[0]
                
#                 # 累加后续模型
#                 for i in range(1, n_selected_clients):
#                      avg_model_state[key] += recovered_state_dicts[i][key] * weights[i]
        
#         # 返回聚合后的参数字典 (此时是全秩的)
#         return avg_model_state

#             # _model_state_dict = self.client_models[_arch].state_dict()
#             # _, client_model = self.client_models[client_idx]
#             # _model_state_dict = copy.deepcopy(client_model.state_dict())

#             # flatten_local_model.unpack(_model_state_dict.values())
#             # _model.load_state_dict(_model_state_dict)
#             # local_models[client_idx] = _model

#         # uniformly average the local models.
#         # assume we use the runtime stat from the last model.
#         # _model = copy.deepcopy(_model)
#         # local_states = [
#         #     ModuleState(copy.deepcopy(local_model.state_dict()))
#         #     for _, local_model in local_models.items()
#         # ]
#         # model_state = local_states[0] * weights[0]
#         # for idx in range(1, len(local_states)):
#         #     model_state += local_states[idx] * weights[idx]
#         # model_state.copy_to_module(_model)
#         # return _model

#     def _avg_over_archs(self, flatten_local_models):
#         # get unique arch from this comm. round.
#         archs = set(
#             [
#                 self.clientid2arch[client_idx]
#                 for client_idx in flatten_local_models.keys()
#             ]
#         )

#         # average for each arch.
#         archs_fedavg_models = {}
#         for arch in archs:
#             # extract local_models from flatten_local_models.
#             _flatten_local_models = {}
#             for client_idx, flatten_local_model in flatten_local_models.items():
#                 if self.clientid2arch[client_idx] == arch:
#                     _flatten_local_models[client_idx] = flatten_local_model

#             # average corresponding local models.
#             self.conf.logger.log(
#                 f"Master uniformly average over {len(_flatten_local_models)} received models ({arch})."
#             )

#             fedavg_model = self._fedavg(flatten_local_models) # 平均算法
#             archs_fedavg_models[arch] = fedavg_model
#         return archs_fedavg_models

#     def aggregate(self, flatten_local_models):
#         # uniformly average local models with the same architecture.
#         fedavg_models = self._avg_over_archs(flatten_local_models)
#         return fedavg_models

#     def _aggregate_model_and_evaluate(self, flatten_local_models, selected_client_ids):
#         # aggregate the local models.
#         # client_models = self.aggregate(
#         #     flatten_local_models
#         # ) # 计算平均后的模型

#         # 1. 调用修改后的 _fedavg 获取全秩的聚合参数
#         aggregated_state_dict = self._fedavg(flatten_local_models)

#         self.master_model.load_state_dict(
#             aggregated_state_dict
#         ) # 更新全局模型
#         # for arch, _client_model in client_models.items():
#         #     self.client_models[arch].load_state_dict(_client_model.state_dict())
        
#         # for arch, _client_model in client_models.items():
#         #     for client_id, (model_name, model_instance) in self.client_models.items():
#         #          if self.clientid2arch[client_id] == arch:
#         #             model_instance.load_state_dict(_client_model.state_dict())
#         # evaluate the aggregated model on the test data.
#         master_utils.do_validation( # 最终评估
#             self.conf,
#             self.coordinator,
#             self.master_model,
#             self.criterion,
#             self.metrics,
#             self.test_loaders,
#             label=f"aggregated_test_loader_0",
#         )

#         if not self.conf.train_fast:  # test all the selected_clients
#             for client_idx, flatten_local_model in flatten_local_models.items():
#                 _arch = self.clientid2arch[client_idx]
#                 _model_state_dict = copy.deepcopy(self.client_models[_arch].state_dict())
#                 flatten_local_model.unpack(_model_state_dict.values())
#                 _, test_model = create_model.define_model(self.conf, to_consistent_model=False, arch=_arch)
#                 test_model.load_state_dict(_model_state_dict)

#                 master_utils.do_validation(
#                     conf=self.conf,
#                     coordinator=self.local_coordinator[client_idx - 1],
#                     model=test_model,
#                     criterion=self.criterion,
#                     metrics=self.metrics,
#                     data_loaders=self.test_loaders,
#                     label=f"aggregated_test_loader_{client_idx}",
#                 )
#             self.additional_validation()


#         torch.cuda.empty_cache()
#     def additional_validation(self):
#         pass

#     def _check_early_stopping(self):
#         meet_flag = False

#         # consider both of target_perf and early_stopping
#         if self.conf.target_perf is not None:   # 是否设置目标性能
#             assert 100 >= self.conf.target_perf > 0

#             # meet the target perf.
#             if (
#                     self.coordinator.key_metric.cur_perf is not None
#                     and self.coordinator.key_metric.cur_perf > self.conf.target_perf
#             ):
#                 self.conf.logger.log("Master early stopping: meet target perf.")
#                 self.conf.meet_target = True
#                 meet_flag = True
#             # or has no progress and early stop it.
#             elif self.early_stopping_tracker(self.coordinator.key_metric.cur_perf):
#                 self.conf.logger.log(
#                     "Master early stopping: not meet target perf but has no patience."
#                 )
#                 meet_flag = True
#         # only consider the early stopping.
#         else:
#             if self.early_stopping_tracker(self.coordinator.key_metric.cur_perf):
#                 meet_flag = True

#         if meet_flag:
#             # we perform the early-stopping check:
#             # (1) before the local training and (2) after the update of the comm_round.
#             _comm_round = self.conf.graph.comm_round - 1
#             self.conf.graph.comm_round = -1
#             self._finishing(_comm_round)

#     def _finishing(self, _comm_round=None):
#         self.conf.logger.save_json()
#         self.conf.logger.log(f"Master finished the federated learning.")
#         self.conf.is_finished = True
#         self.conf.finished_comm = _comm_round
#         checkpoint.save_arguments(self.conf)
#         os.system(f"echo {self.conf.checkpoint_root} >> {self.conf.job_id}")


# def get_n_local_epoch(conf, n_participated):
#     if conf.min_local_epochs is None:
#         return [conf.local_n_epochs] * n_participated
#     else:
#         # here we only consider to (uniformly) randomly sample the local epochs.
#         assert conf.min_local_epochs > 1.0
#         random_local_n_epochs = conf.random_state.uniform(
#             low=conf.min_local_epochs, high=conf.local_n_epochs, size=n_participated
#         )
#         return random_local_n_epochs



# -*- coding: utf-8 -*-
import os
import copy

import numpy as np
import torch.nn.functional as F
import torch
import torch.distributed as dist
from pcode.utils.module_state import ModuleState
import pcode.master_utils as master_utils
import pcode.create_coordinator as create_coordinator
import pcode.create_dataset as create_dataset
import pcode.create_metrics as create_metrics
import pcode.create_model as create_model
import pcode.utils.checkpoint as checkpoint
from pcode.utils.tensor_buffer import TensorBuffer
import pcode.utils.cross_entropy as cross_entropy
from pcode.utils.early_stopping import EarlyStoppingTracker
import torch.nn.utils as torch_utils
from pcode.models.resnet import MetaBasicBlock
from torch import nn
import clip
import matplotlib.pyplot as plt
import seaborn as sns
from sklearn.manifold import TSNE
import pcode.create_dataset as create_dataset # 确保引入了这个，用于加载 batch

class MasterFedOur(object):
    def __init__(self, conf):
        self.conf = conf
        # some initializations.
        self.client_ids = list(range(1, 1 + conf.n_clients))
        self.world_ids = list(range(1, 1 + conf.n_participated))

        assert conf.meta == True

        # create model as well as their corresponding state_dicts.
        # 获取未分解的模型
        # _, self.master_model = create_model.define_model( # 获取全局模型
        #     conf, to_consistent_model=False
        # )
        # 恢复全局模型

        self.text_model, _ = self.load_clip_text_model()
        self.anchor_raw, self.anchor = self.generate_text_anchors()
        self.output_dim = self.anchor[0].shape[-1] 
        conf.output_dim = self.output_dim
        self.conf = conf

        self.used_client_archs =[create_model.determine_arch(conf, client_id, use_complex_arch=True) for client_id in range(1, 1 + conf.n_clients)]  # 所有客户端模型架构名称
        
        
        self.conf.used_client_archs = self.used_client_archs

        conf.logger.log(f"The client will use archs={self.used_client_archs}.")
        conf.logger.log("Master created model templates for client models.")

        self.client_models = [ # 获取客户端模型
            create_model.define_model(conf, to_consistent_model=False, client_id=i, arch=arch)
            for i,arch in enumerate(self.used_client_archs)
        ]

        # 拷贝构建全局模型

        self.master_model = copy.deepcopy(self.client_models[0][1])
        if "resnet" in self.conf.arch:
            for m in self.master_model.modules():
                    if isinstance(m, MetaBasicBlock):
                        m.recover()
        elif "cnn" in self.conf.arch:
            self.master_model.recover_model()

        final_anchors = self.anchor[-1].clone().detach() # 取最后一层的文本锚点   
        if hasattr(self.master_model, 'set_text_anchors'):
            model_device = next(self.master_model.parameters()).device
            self.master_model.set_text_anchors(final_anchors.to(model_device))
            
        for idx in range(len(self.client_models)):
            model = self.client_models[idx][1]
            if hasattr(model, 'set_text_anchors'):
                model_device = next(model.parameters()).device
                model.set_text_anchors(final_anchors.to(model_device)) 

        # self.decom_recover_loss()
        self.clientid2arch = list( # 获取所有客户端的模型名称
            (
                client_id,
                create_model.determine_arch(
                    conf, client_id=client_id, use_complex_arch=True
                ),
            )
            for client_id in range(0, conf.n_clients)
        )
        self.conf.clientid2arch = self.clientid2arch

        conf.logger.log(
            f"Master initialize the clientid2arch mapping relations: {self.clientid2arch}."
        )

        # create dataset (as well as the potential data_partitioner) for training.
        dist.barrier()
        self.dataset = create_dataset.define_dataset(conf, data=conf.data, agg_data_ratio=conf.agg_data_ratio)
        _, self.data_partitioner = create_dataset.define_data_loader(
            self.conf,
            dataset=self.dataset["train"],
            localdata_id=0,  # random id here.
            is_train=True,
            data_partitioner=None,
        ) # 虽然划分了数据但是全丢了，只保留数据划分器



        conf.logger.log(f"Master initialized the local training data with workers.")

        # create val loader.
        # right now we just ignore the case of partitioned_by_user.
        if self.dataset["val"] is not None:
            assert not conf.partitioned_by_user
            self.val_loader, _ = create_dataset.define_data_loader(
                conf, self.dataset["val"], is_train=False
            )
            conf.logger.log(f"Master initialized val data.")
        else:
            self.val_loader = None

        # create test loaders.
        # localdata_id start from 0 to the # of clients - 1. client_id starts from 1 to the # of clients.
        if conf.partitioned_by_user:
            self.test_loaders = []
            for localdata_id in self.client_ids:
                test_loader, _ = create_dataset.define_data_loader(
                    conf,
                    self.dataset["test"],
                    localdata_id=localdata_id - 1,
                    is_train=False,
                    shuffle=False,
                )
                self.test_loaders.append(copy.deepcopy(test_loader))
        else:
            test_loader, _ = create_dataset.define_data_loader(
                conf, self.dataset["test"], is_train=False
            )
            self.test_loaders = [test_loader] # 这里的test_loader和上面的val_loader都是总的，也就是说未平分给客户端的

        # define the criterion and metrics.
        self.criterion = cross_entropy.CrossEntropyLoss(reduction="mean")   # 模型的损失函数，这里传入mean表示计算的损失会求平均
        self.metrics = create_metrics.Metrics(self.master_model, task="classification")  # 模型的评估，计算准确率之类
        conf.logger.log(f"Master initialized model/dataset/criterion/metrics.")

        self.coordinator = create_coordinator.Coordinator(conf, self.metrics)   # 记录最佳性能
        if not self.conf.train_fast:
            self.local_coordinator = [create_coordinator.Coordinator(conf, self.metrics) for _ in
                                      range(self.conf.n_clients)]

        conf.logger.log(f"Master initialized the coordinator.\n")

        # define early_stopping_tracker.
        self.early_stopping_tracker = EarlyStoppingTracker(
            patience=conf.early_stopping_rounds
        )   # 早停装置，为0时关掉早停功能

        # save arguments to disk.
        conf.is_finished = False    # 用于控制全局训练是否已经结束
        checkpoint.save_arguments(conf) # 将超参数保存在json文件中



    def load_clip_text_model(self, model_name="ViT-B/32", save_dir="./model_state/"):
        """
        仅加载 CLIP 的文本提取部分。
        
        1. 自动检查本地/下载 (逻辑不变)。
        2. 使用 jit=False 加载，以便我们可以修改模型结构。
        3. 删除 visual 部分以节省显存。
        """
        
        device = "cuda" if torch.cuda.is_available() else "cpu"
        
        if not os.path.exists(save_dir):
            os.makedirs(save_dir)

        print(f"Loading CLIP Text Backbone: {model_name}...")
        
        # [关键修改 1] jit=False: 允许我们将模型作为普通的 PyTorch nn.Module 加载，
        # 这样我们才能执行 del model.visual 操作。
        # model 的 preprocess (针对图像) 我们直接忽略，用不到。
        model, _ = clip.load(model_name, device=device, download_root=save_dir, jit=False)
        output_dim = model.text_projection.shape[1]
        # [关键修改 2] 删除视觉编码器部分
        # 这会释放掉 ViT 或 ResNet 部分占用的显存
        if hasattr(model, 'visual'):
            # 1. 先保存当前的数据类型 (通常是 float16 或 float32)
            # 注意：如果 visual 已经被删了，这里会报错，所以要小心
            try:
                stored_dtype = model.visual.conv1.weight.dtype
            except:
                stored_dtype = torch.float16 # 默认备选
                
            # 2. 删除真正的视觉编码器 (释放显存)
            del model.visual
            if device == "cuda":
                torch.cuda.empty_cache()
                
            # 3. [核心] 塞入一个假的 visual，只为了让 model.dtype 属性不报错
            model.visual = DummyVisual(stored_dtype)
                
        print("Text-only model loaded. Visual encoder removed.")
        
        # 将模型设为评估模式 (对于文本部分这通常不影响，但好习惯)
        model.eval()
        model.to("cuda")

        return model, device

    def generate_text_anchors(self):
        """
        根据数据集名称生成文本锚点 (Text Anchors)。
        支持 CIFAR 和动态加载的 Tiny-ImageNet。
        """
        device = next(self.text_model.parameters()).device
        dataset_name = self.conf.data.lower() # 确保大小写匹配
        
        # === 1. 获取类别名称列表 ===
        classes = []
        
        if "tiny" in dataset_name:
            # ---------------------------------------------------------
            # 针对 Tiny-ImageNet 动态计算锚点 (防错位核心逻辑)
            # ---------------------------------------------------------
            # 假设 conf.data_dir 是 './data'，conf.data 是 'imagenet_tiny'
            tiny_root = os.path.join(self.conf.data_dir, self.conf.data) 
            words_path = os.path.join(tiny_root, "words.txt")
            train_dir = os.path.join(tiny_root, "train")
            
            if not os.path.exists(words_path) or not os.path.exists(train_dir):
                raise FileNotFoundError(f"找不到 Tiny-ImageNet 的 words.txt 或 train 目录，请检查路径: {tiny_root}")
                
            # A. 解析 words.txt 映射字典 (只取逗号前的核心名词，提升 CLIP 识别率)
            # 例如: "n01443537 \t goldfish, Carassius auratus" -> {"n01443537": "goldfish"}
            wnid_to_word = {}
            with open(words_path, 'r', encoding='utf-8') as f:
                for line in f.readlines():
                    parts = line.strip().split('\t')
                    if len(parts) == 2:
                        wnid_to_word[parts[0]] = parts[1].split(',')[0].strip()
                        
            # B. 严格按照字母排序读取 train 目录下的文件夹名 (底层对齐 ImageFolder 的 0-199 索引)
            wnids = sorted([d for d in os.listdir(train_dir) if os.path.isdir(os.path.join(train_dir, d))])
            
            # C. 映射出最终的 200 个英文标签
            classes = [wnid_to_word.get(wnid, "object") for wnid in wnids]
            print(f"✅ 成功提取 Tiny-ImageNet 类别，共 {len(classes)} 类。前5类为: {classes[:5]}")
            
        elif dataset_name == "cifar10":
            classes = ["airplane", "automobile", "bird", "cat", "deer", "dog", "frog", "horse", "ship", "truck"]
        elif dataset_name == "cifar100":
            classes = [
                'apple', 'aquarium fish', 'baby', 'bear', 'beaver', 'bed', 'bee', 'beetle', 
                'bicycle', 'bottle', 'bowl', 'boy', 'bridge', 'bus', 'butterfly', 'camel', 
                'can', 'castle', 'caterpillar', 'cattle', 'chair', 'chimpanzee', 'clock', 
                'cloud', 'cockroach', 'couch', 'crab', 'crocodile', 'cup', 'dinosaur', 
                'dolphin', 'elephant', 'flatfish', 'forest', 'fox', 'girl', 'hamster', 
                'house', 'kangaroo', 'keyboard', 'lamp', 'lawn_mower', 'leopard', 'lion', 
                'lizard', 'lobster', 'man', 'maple_tree', 'motorcycle', 'mountain', 'mouse', 
                'mushroom', 'oak_tree', 'orange', 'orchid', 'otter', 'palm_tree', 'pear', 
                'pickup_truck', 'pine_tree', 'plain', 'plate', 'poppy', 'porcupine', 
                'possum', 'rabbit', 'raccoon', 'ray', 'road', 'rocket', 'rose', 
                'sea', 'seal', 'shark', 'shrew', 'skunk', 'skyscraper', 'snail', 'snake', 
                'spider', 'squirrel', 'streetcar', 'sunflower', 'sweet_pepper', 'table', 
                'tank', 'telephone', 'television', 'tiger', 'tractor', 'train', 'trout', 
                'tulip', 'turtle', 'wardrobe', 'whale', 'willow_tree', 'wolf', 'woman', 'worm'
            ]
        else:
            raise ValueError(f"Dataset '{dataset_name}' 不在支持的锚点生成列表中。")


        # === 2. 构造提示词 (Prompt Template) ===
        # CLIP 官方推荐模板
        prompts = [f"a photo of a {c}" for c in classes]
        
        # === 3. Tokenize ===
        text_inputs = clip.tokenize(prompts).to(device)
        
        # === 4. 提取 CLIP 文本特征并截取多层锚点 ===
        self.text_model.eval()
        with torch.no_grad():
            x = self.text_model.token_embedding(text_inputs).type(self.text_model.dtype)
            x = x + self.text_model.positional_embedding.type(self.text_model.dtype)
            x = x.permute(1, 0, 2)  # NLD -> LND
            
            layers = self.text_model.transformer.resblocks
            total_layers = len(layers)
            
            # 定义要截取的层索引
            indices = [
                int(total_layers * 1 / 4) - 1,
                int(total_layers * 2 / 4) - 1,
                int(total_layers * 3 / 4) - 1,
                total_layers - 1
            ]
            raw_anchors_list = []
            anchors_list = []
            
            for i, layer in enumerate(layers):
                x = layer(x)
                
                if i in indices:
                    x_temp = x.permute(1, 0, 2)
                    # 提取 [EOS] token
                    sent_emb = x_temp[torch.arange(x_temp.shape[0]), text_inputs.argmax(dim=-1)]
                    
                    if i == total_layers - 1:
                        sent_emb = self.text_model.ln_final(sent_emb).type(self.text_model.dtype)
                        sent_emb = sent_emb @ self.text_model.text_projection
                    
                    
                    # 保留原始文本表征
                    raw_anchor= sent_emb.float()
                    # L2 归一化 (核心步骤)
                    norm_anchor = F.normalize(raw_anchor, p=2, dim=-1)

                    raw_anchors_list.append(raw_anchor)
                    anchors_list.append(norm_anchor) 

            return raw_anchors_list, anchors_list # 返回 4 个层级的锚点 Tensor 列表
        # """
        # 根据数据集名称生成文本锚点 (Text Anchors)。
        
        # 流程:
        # 1. 获取类别名称列表 (classes).
        # 2. 构造 Prompts (templates).
        # 3. Tokenize -> Text Encoder -> Normalize.
        # """
        
        # # 1. 获取当前设备
        # # 假设 self.text_model 已经在正确的 device 上 (比如 cpu 或 cuda)
        # device = next(self.text_model.parameters()).device
        
        # # 2. 定义数据集与其对应的类别列表
        # # 这里列出了 CIFAR-10 和 CIFAR-100 的标准类别
        # data_classes_registry = {
        #     "cifar10": [
        #         "airplane", "automobile", "bird", "cat", "deer",
        #         "dog", "frog", "horse", "ship", "truck"
        #     ],
        #     "cifar100": [
        #         'apple', 'aquarium fish', 'baby', 'bear', 'beaver', 'bed', 'bee', 'beetle', 
        #         'bicycle', 'bottle', 'bowl', 'boy', 'bridge', 'bus', 'butterfly', 'camel', 
        #         'can', 'castle', 'caterpillar', 'cattle', 'chair', 'chimpanzee', 'clock', 
        #         'cloud', 'cockroach', 'couch', 'crab', 'crocodile', 'cup', 'dinosaur', 
        #         'dolphin', 'elephant', 'flatfish', 'forest', 'fox', 'girl', 'hamster', 
        #         'house', 'kangaroo', 'keyboard', 'lamp', 'lawn_mower', 'leopard', 'lion', 
        #         'lizard', 'lobster', 'man', 'maple_tree', 'motorcycle', 'mountain', 'mouse', 
        #         'mushroom', 'oak_tree', 'orange', 'orchid', 'otter', 'palm_tree', 'pear', 
        #         'pickup_truck', 'pine_tree', 'plain', 'plate', 'poppy', 'porcupine', 
        #         'possum', 'rabbit', 'raccoon', 'ray', 'road', 'rocket', 'rose', 
        #         'sea', 'seal', 'shark', 'shrew', 'skunk', 'skyscraper', 'snail', 'snake', 
        #         'spider', 'squirrel', 'streetcar', 'sunflower', 'sweet_pepper', 'table', 
        #         'tank', 'telephone', 'television', 'tiger', 'tractor', 'train', 'trout', 
        #         'tulip', 'turtle', 'wardrobe', 'whale', 'willow_tree', 'wolf', 'woman', 'worm'
        #     ],
        #     # 你可以在这里添加 tinyimagenet 或其他数据集
        # }

        # dataset_name = self.conf.data.lower() # 确保大小写匹配
        
        # if dataset_name not in data_classes_registry:
        #     raise ValueError(f"Dataset '{dataset_name}' not found in registry. Please add class names to generate_text_anchors.")
        
        # classes = data_classes_registry[dataset_name]
        
        # # 3. 构造提示词 (Prompt Template)
        # # CLIP 官方推荐使用 "a photo of a {label}"
        # prompts = [f"a photo of a {c}" for c in classes]
        

        # # 4. Tokenize
        # # clip.tokenize 会自动截断或填充到 77 token 长度
        # text_inputs = clip.tokenize(prompts).to(device)
        
        # # 5. 提取特征 (Inference)
        # # 确保不计算梯度，确保模型处于 eval 模式
        # self.text_model.eval()
        # with torch.no_grad():
        #     # encode_text 是 CLIP 模型提取文本特征的标准方法
        #     x = self.text_model.token_embedding(text_inputs).type(self.text_model.dtype)
        #     x = x + self.text_model.positional_embedding.type(self.text_model.dtype)
        #     x = x.permute(1, 0, 2)  # NLD -> LND
            
        #     # 2. 获取 Transformer 的层数
        #     # ViT-B/32 的 layers=12
        #     layers = self.text_model.transformer.resblocks
        #     total_layers = len(layers)
            
        #     # 3. 定义我们要截取的节点 (均匀分布)
        #     # 例如 12层 -> [2, 5, 8, 11] (索引从0开始)
        #     # 这里的逻辑是：ResNet Stage1 对齐 Layer3，Stage4 对齐 Layer12
        #     indices = [
        #         int(total_layers * 1 / 4) - 1,
        #         int(total_layers * 2 / 4) - 1,
        #         int(total_layers * 3 / 4) - 1,
        #         total_layers - 1
        #     ]
            
        #     anchors_list = []
            
        #     # 4. 前向传播并截取
        #     for i, layer in enumerate(layers):
        #         x = layer(x)
                
        #         if i in indices:
        #             # 取出 [EOS] token 的特征 (就像 CLIP 标准做法一样)
        #             # x 形状: [L, Batch, Dim] -> permute -> [Batch, L, Dim]
        #             x_temp = x.permute(1, 0, 2)
                    
        #             # text_inputs.argmax(dim=-1) 找到 EOS 的位置
        #             # 提取特征
        #             sent_emb = x_temp[torch.arange(x_temp.shape[0]), text_inputs.argmax(dim=-1)]
                    
        #             # [关键]
        #             # 只有最后一层 (i == total_layers - 1) 需要通过 text_projection 映射到联合空间
        #             # 前面的层保持原样，或者也通过 LayerNorm
        #             if i == total_layers - 1:
        #                 sent_emb = self.text_model.ln_final(sent_emb).type(self.text_model.dtype)
        #                 sent_emb = sent_emb @ self.text_model.text_projection
        #             else:
        #                 # 中间层通常不需要 ln_final，或者你可以选择加上
        #                 pass 

        #             # 归一化 (一定要做!)
        #             sent_emb = sent_emb / sent_emb.norm(dim=-1, keepdim=True)
        #             anchors_list.append(sent_emb.float()) # 转回 float32

        #     return anchors_list # 返回包含 4 个 Tensor 的列表



    def run(self):

        # 断点恢复
        # ==========================================
        # [新增 1] 确定起始轮次并尝试加载断点
        # ==========================================
        start_round = 1
        # 假设将点保存在 checkpoint 目录下
        experiment_dir = os.path.dirname(self.conf.checkpoint_root)
        checkpoint_path = os.path.join(experiment_dir, "master_checkpoint.pt")
        # checkpoint_path = os.path.join(self.conf.checkpoint_root, "master_checkpoint.pt")
        
        if os.path.exists(checkpoint_path):
            self.conf.logger.log(f"发现断点文件 {checkpoint_path}，尝试恢复训练...")
            try:
                ckpt = torch.load(checkpoint_path, map_location='cpu')
                start_round = ckpt['comm_round'] + 1
                self.master_model.load_state_dict(ckpt['master_model_state'])
                self.conf.logger.log(f"成功恢复！将从第 {start_round} 轮继续训练。")
                # ==========================================
                # [新增修复 1]：在下发给 Worker 炸毁前，先评估一次当前的真实实力
                # ==========================================
                self.conf.logger.log(">>> [断点检查] 正在评估恢复的初始全局模型...")
                master_utils.do_validation(
                    self.conf,
                    self.coordinator,
                    self.master_model,
                    self.criterion,
                    self.metrics,
                    self.test_loaders,
                    label="Resume_Validation",
                )
                # ==========================================
            except Exception as e:
                self.conf.logger.log(f"加载断点失败: {e}，将从头开始训练。")
        # ==========================================

        for comm_round in range(start_round, 1 + self.conf.n_comm_rounds):
            self.conf.graph.comm_round = comm_round
            self.conf.logger.log(
                f"Master starting one round of federated learning: (comm_round={comm_round})."
            )

            # get random n_local_epochs.
            list_of_local_n_epochs = get_n_local_epoch(
                conf=self.conf, n_participated=self.conf.n_participated
            )   # 生成参与数长的列表，每个值为每个客户端的训练轮数
            self.list_of_local_n_epochs = list_of_local_n_epochs

            # random select clients from a pool.
            selected_client_ids = self._random_select_clients() # 随机选择客户端

            # detect early stopping.
            self._check_early_stopping() # 检查是否满足早停，可能未开启早停

            # init the activation tensor and broadcast to all clients (either start or stop).
            self.activate_selected_clients(
                selected_client_ids, self.conf.graph.comm_round, list_of_local_n_epochs
            )

            # will decide to send the model or stop the training.
            if not self.conf.is_finished:
                self.send_extra_info_to_selected_clients(selected_client_ids)

                # broadcast the model to activated clients.
                
                self._send_model_to_selected_clients(selected_client_ids)

            else:
                dist.barrier()
                self.conf.logger.log(
                    f"Master finished the federated learning by early-stopping: (current comm_rounds={comm_round}, total_comm_rounds={self.conf.n_comm_rounds})"
                )
                return

            self.receive_extra_info_from_selected_clients(selected_client_ids)

            # wait to receive the local models.
            flatten_local_models = self._receive_models_from_selected_clients(
                selected_client_ids
            ) # 接受模型参数

            # aggregate the local models and evaluate on the validation dataset.
            self._aggregate_model_and_evaluate(flatten_local_models, selected_client_ids)   # 聚合模型，评估和存档

            # evaluate the aggregated model.
            self.conf.logger.log(f"Master finished one round of federated learning.\n")

            # ==========================================
            # [新增 ] 每轮结束时保存全局模型状态和轮次
            # ==========================================
            save_dict = {
                'comm_round': comm_round,
                'master_model_state': self.master_model.state_dict()
            }
            # 为了防止保存中断导致文件损坏，可以先存为临时文件再替换
            temp_path = checkpoint_path + ".tmp"
            torch.save(save_dict, temp_path)
            os.replace(temp_path, checkpoint_path) 
            self.conf.logger.log(f"断点已自动保存至第 {comm_round} 轮。")
            # ==========================================

        # formally stop the training (the master has finished all communication rounds).

            if comm_round == self.conf.n_comm_rounds:
                # if comm_round == 5:
                self.visualize_global_features()
        dist.barrier()
        self._finishing()

    
    def visualize_global_features(self):
        """
        在最后一轮提取全局模型在测试集上的特征，并使用 t-SNE 绘制特征分布散点图。
        【双图输出版】：
        图1：仅包含视觉特征的分布（颜色较深，清晰可见）。
        图2：视觉特征（背景） + 类中心 + 文本锚点 + 对齐连线。
        """
        self.conf.logger.log("Extracting ALL features and text anchors for t-SNE visualization...")
        
        # ================= 保留：加载表现最好的模型 =================
        if hasattr(self, 'best_model_state_dict'):
            self.master_model.load_state_dict(self.best_model_state_dict)
            self.conf.logger.log(f"Loaded the BEST model (accuracy: {self.best_perf:.4f}) for t-SNE visualization.")
        else:
            self.conf.logger.log("Best model not found, using the final round model.")
        # ============================================================
        
        # 1. 准备模型
        self.master_model.eval()
        if self.conf.graph.on_cuda:
            self.master_model = self.master_model.cuda()

        all_features = []
        all_targets = []

        # 2. 遍历测试集提取视觉特征
        with torch.no_grad():
            for data_loader in self.test_loaders:
                for _input, _target in data_loader:
                    data_batch = create_dataset.load_data_batch(
                        self.conf, _input, _target, is_training=False
                    )
                    
                    feature, output = self.master_model(data_batch["input"])
                    all_features.append(feature.cpu().numpy())
                    all_targets.append(data_batch["target"].cpu().numpy())

        # 拼接所有 Batch 的视觉特征
        all_features = np.concatenate(all_features, axis=0)
        all_targets = np.concatenate(all_targets, axis=0)
        
        # 取出最后一层的文本锚点
        text_anchors = self.anchor[-1].detach().cpu().numpy()
        num_classes = text_anchors.shape[0]

        # ============================================================
        # 核心视觉修复：消除 Modality Gap，强行对齐模态中心
        # ============================================================
        # 1. 减去各自的均值，将两个模态平移到二维坐标系的绝对中心
        text_anchors = text_anchors - np.mean(text_anchors, axis=0)
        all_features = all_features - np.mean(all_features, axis=0)
        
        # 2. 重新进行 L2 归一化，确保它们乖乖贴合在同一个单位超球面上
        text_anchors = text_anchors / (np.linalg.norm(text_anchors, axis=1, keepdims=True) + 1e-8)
        all_features = all_features / (np.linalg.norm(all_features, axis=1, keepdims=True) + 1e-8)
        # ============================================================

        # ============================================================
        # 3. 计算视觉特征的类中心 (Class Centroids) 
        # ============================================================
        centroids = []
        for i in range(num_classes):
            class_features = all_features[all_targets == i]
            class_mean = np.mean(class_features, axis=0)
            # 必须进行 L2 归一化，使其与文本锚点在同一超球面上
            class_mean = class_mean / (np.linalg.norm(class_mean) + 1e-8)
            centroids.append(class_mean)
        centroids = np.stack(centroids, axis=0)

        # ============================================================
        # 4. 直接使用全部测试集图像
        # ============================================================
        sampled_features = all_features
        sampled_targets = all_targets

        self.conf.logger.log(f"Running t-SNE on ALL {sampled_features.shape[0]} images, {num_classes} centroids, and {num_classes} anchors... (This might take a few minutes)")

        # ============================================================
        # 5. 拼接特征并降维：[全部背景图像, 图像类中心, 文本锚点]
        # ============================================================
        combined_features = np.concatenate([sampled_features, centroids, text_anchors], axis=0)
        
        # 对于上万个点的数据量，perplexity 设为 50 比较合适
        perplexity = 50
        tsne = TSNE(n_components=2, perplexity=perplexity, random_state=42, metric='cosine', init='random', learning_rate='auto')
        combined_2d = tsne.fit_transform(combined_features)

        # 分离降维后的坐标
        num_sampled = sampled_features.shape[0]
        features_2d = combined_2d[:num_sampled, :]
        centroids_2d = combined_2d[num_sampled : num_sampled + num_classes, :]
        anchors_2d = combined_2d[num_sampled + num_classes :, :]

        palette = sns.color_palette("tab10", num_classes) if num_classes <= 10 else sns.color_palette("husl", num_classes)

        # ============================================================
        # 绘图 1：纯视觉特征分布图 (调高透明度与点大小，确保清晰)
        # ============================================================
        plt.figure(figsize=(12, 10)) 
        
        sns.scatterplot(
            x=features_2d[:, 0], 
            y=features_2d[:, 1],
            hue=sampled_targets,
            palette=palette,
            legend="full", 
            alpha=0.5,   # 调高透明度，让点清晰可见
            s=15,        # 增大点的尺寸
            edgecolor=None,
            zorder=1
        )
        
        plt.title(f"t-SNE: Visual Features Only (Round {self.conf.graph.comm_round})", fontsize=16, fontweight='bold')
        plt.xlabel("t-SNE Dimension 1", fontsize=12)
        plt.ylabel("t-SNE Dimension 2", fontsize=12)
        
        # 优化图例
        plt.legend(bbox_to_anchor=(1.02, 1), loc='upper left', borderaxespad=0., fontsize=12)
        plt.tight_layout()
        
        # 保存图 1
        save_path_1 = os.path.join(self.conf.checkpoint_root, "global_model_tsne_features_only.png")
        plt.savefig(save_path_1, dpi=300, bbox_inches='tight') 
        plt.close()
        self.conf.logger.log(f"Features-only visualization saved to {save_path_1}")


        # ============================================================
        # 绘图 2：跨模态对齐图 (背景图像变淡 + 类中心 + 文本锚点 + 连线)
        # ============================================================
        plt.figure(figsize=(12, 10)) 
        
        # a. 绘制全部背景图像特征 (透明度较低，作为星云背景)
        sns.scatterplot(
            x=features_2d[:, 0], 
            y=features_2d[:, 1],
            hue=sampled_targets,
            palette=palette,
            legend=False, 
            alpha=0.15,  # 较低透明度，不喧宾夺主
            s=10,        # 较小的点
            edgecolor=None,
            zorder=1     
        )
        
        # b. 绘制图像的类中心 (实心大圆，带白边)
        for i in range(num_classes):
            plt.scatter(
                x=centroids_2d[i, 0], y=centroids_2d[i, 1],
                color=palette[i], marker='o', s=250,
                edgecolor='white', linewidth=2, zorder=5,
                label=f'Image Centroids' if i == 0 else ""
            )
            
        # c. 绘制文本锚点 (大五角星，带黑边)
        for i in range(num_classes):
            plt.scatter(
                x=anchors_2d[i, 0], y=anchors_2d[i, 1],
                color=palette[i], marker='*', s=500,
                edgecolor='black', linewidth=1.5, zorder=10,
                label='Text Anchors' if i == 0 else ""
            )
            
        # d. 画虚线连接：图像中心 --> 文本锚点
        for i in range(num_classes):
            plt.plot(
                [centroids_2d[i, 0], anchors_2d[i, 0]], 
                [centroids_2d[i, 1], anchors_2d[i, 1]], 
                color=palette[i], linestyle='--', linewidth=1.5, zorder=4, alpha=0.8
            )
        
        plt.title(f"t-SNE: Visual-Text Feature Alignment (Round {self.conf.graph.comm_round})", fontsize=16, fontweight='bold')
        plt.xlabel("t-SNE Dimension 1", fontsize=12)
        plt.ylabel("t-SNE Dimension 2", fontsize=12)
        
        # 优化图例 (去重合并)
        handles, labels = plt.gca().get_legend_handles_labels()
        by_label = dict(zip(labels, handles))
        plt.legend(by_label.values(), by_label.keys(), bbox_to_anchor=(1.02, 1), loc='upper left', borderaxespad=0., fontsize=12)
        
        plt.tight_layout()
        
        # 保存图 2
        save_path_2 = os.path.join(self.conf.checkpoint_root, "global_model_tsne_alignment.png")
        plt.savefig(save_path_2, dpi=300, bbox_inches='tight') 
        plt.close()
        self.conf.logger.log(f"Alignment visualization saved to {save_path_2}")
        
        if self.conf.graph.on_cuda:
            self.master_model = self.master_model.cpu()

    def receive_extra_info_from_selected_clients(self, selected_client_ids):
        pass


    def _random_select_clients(self):
        selected_client_ids = self.conf.random_state.choice(
            self.client_ids, self.conf.n_participated, replace=False
        ).tolist()  # 随机选择客户端
        selected_client_ids.sort()
        ids = [selected_client_id-1 for selected_client_id in selected_client_ids]
        selected_client_ids = ids
        self.conf.logger.log(
            f"Master selected {self.conf.n_participated} from {self.conf.n_clients} clients: {selected_client_ids}."
        )
        return selected_client_ids

    def activate_selected_clients(
            self, selected_client_ids, comm_round, list_of_local_n_epochs, to_send_history=False
    ):
        # Activate the selected clients:
        # the first row indicates the client id,
        # the second row indicates the current_comm_round,
        # the third row indicates the expected local_n_epochs
        selected_client_ids = np.array(selected_client_ids)
        msg_len = 3 # 消息行数

        activation_msg = torch.zeros((msg_len, len(selected_client_ids)))
        activation_msg[0, :] = torch.Tensor(selected_client_ids) # 第一行装客户端id
        activation_msg[1, :] = comm_round                       # 第二行装联邦轮次
        activation_msg[2, :] = torch.Tensor(list_of_local_n_epochs)     # 第三行装每个客户端训练轮数

        dist.broadcast(tensor=activation_msg, src=0)
        self.conf.logger.log(f"Master activated the selected clients.")
        dist.barrier()

    

    def _send_model_to_selected_clients(self, selected_client_ids):
        # the master_model can be large; the client_models can be small and different.
        self.conf.logger.log(f"Master send the models to workers.")

        
        self.updata_selected_clients_models(selected_client_ids)

        for worker_rank, selected_client_id in enumerate(selected_client_ids, start=1):
            arch = self.clientid2arch[selected_client_id] # 获取当前循环模型名称
            client_model_state_dict = self.client_models[selected_client_id][1].state_dict()

            flatten_model = TensorBuffer(list(client_model_state_dict.values())) # 打包模型参数
            dist.send(tensor=flatten_model.buffer, dst=worker_rank) # 发送参数到对应模型
            self.conf.logger.log(
                f"\tMaster send the current model={arch} to process_id={worker_rank}."
            )
        self.conf.logger.log(
        f"[MASTER SEND] worker_rank={worker_rank}, "
        f"client_id={selected_client_id}, "
        f"rank={self.conf.rank_list[selected_client_id]}, "
        f"numel={flatten_model.buffer.numel()}, "
        f"bytes={flatten_model.buffer.numel() * flatten_model.buffer.element_size()}"
        )

        dist.barrier()

    def send_extra_info_to_selected_clients(self, selected_client_ids):
        pass

    def _receive_models_from_selected_clients(self, selected_client_ids):
        self.conf.logger.log(f"Master waits to receive the local models.")
        dist.barrier()

        # init the placeholders to recv the local models from workers.
        flatten_local_models = dict()
        for selected_client_id in selected_client_ids: # 为接受数据准备容器，这也可以解释为什么要在服务器创建模型
            arch = self.clientid2arch[selected_client_id]
            client_tb = TensorBuffer(
                list(self.client_models[selected_client_id][1].state_dict().values())
            )
            client_tb.buffer = torch.zeros_like(client_tb.buffer)
            flatten_local_models[selected_client_id] = client_tb

        # async to receive model from clients.
        reqs = []
        for client_id, world_id in zip(selected_client_ids, self.world_ids):
            req = dist.irecv(
                tensor=flatten_local_models[client_id].buffer, src=world_id
            )   # 这里并不会阻塞，相当于告诉客户端数据放在哪里
            reqs.append(req)

        for req in reqs:
            req.wait()  # 这里会阻塞等待数据

        dist.barrier()
        self.conf.logger.log(f"Master received all local models.")
        return flatten_local_models

    def _fedavg(self, flatten_local_models, weights=None):
        n_selected_clients = len(flatten_local_models)

        if weights == None:
            weights = [
                torch.FloatTensor([1.0 / n_selected_clients]) for _ in range(n_selected_clients)
            ]

        # NOTE: the arch for different local models needs to be the same as the master model.
        # retrieve the local models.
        local_models = {}
        for client_idx, flatten_local_model in flatten_local_models.items():
            _arch = self.clientid2arch[client_idx]
            _model = copy.deepcopy(self.client_models[_arch])
            _model_state_dict = self.client_models[_arch].state_dict()
            flatten_local_model.unpack(_model_state_dict.values())
            _model.load_state_dict(_model_state_dict)
            local_models[client_idx] = _model

        # uniformly average the local models.
        # assume we use the runtime stat from the last model.
        _model = copy.deepcopy(_model)
        local_states = [
            ModuleState(copy.deepcopy(local_model.state_dict()))
            for _, local_model in local_models.items()
        ]
        model_state = local_states[0] * weights[0]
        for idx in range(1, len(local_states)):
            model_state += local_states[idx] * weights[idx]
        model_state.copy_to_module(_model)
        return _model

    def _avg_over_archs(self, flatten_local_models):
        # get unique arch from this comm. round.
        archs = set(
            [
                self.clientid2arch[client_idx]
                for client_idx in flatten_local_models.keys()
            ]
        )

        # average for each arch.
        archs_fedavg_models = {}
        for arch in archs:
            # extract local_models from flatten_local_models.
            _flatten_local_models = {}
            for client_idx, flatten_local_model in flatten_local_models.items():
                if self.clientid2arch[client_idx] == arch:
                    _flatten_local_models[client_idx] = flatten_local_model

            # average corresponding local models.
            self.conf.logger.log(
                f"Master uniformly average over {len(_flatten_local_models)} received models ({arch})."
            )

            fedavg_model = self._fedavg(flatten_local_models) # 平均算法
            archs_fedavg_models[arch] = fedavg_model
        return archs_fedavg_models


    def aggregate(self, flatten_local_models, selected_client_ids):

        # # 记录所有参与过训练的客户端
        # if not hasattr(self, 'participated_clients'):
        #     self.participated_clients = set()
            
        # # 将当前选中的客户端加入历史记录集合
        # self.participated_clients.update(selected_client_ids)

        # uniformly average local models with the same architecture.
        self.load_para2selectedmodels(flatten_local_models, selected_client_ids)    # 把收到参数放入self.clientmodels模型中
        
        # # 转换为列表，准备进行全局历史聚合
        # participated_list = list(self.participated_clients)
        # self.conf.logger.log(f"Master aggregates over {len(participated_list)} historically participated clients: {participated_list}")

        fedavg_models = self.recover_aggrevate(selected_client_ids)
        return fedavg_models

    def updata_selected_clients_models(self, selected_client_ids):
        # 注意检查变量名：之前你用的是 conf.list_rank 还是 conf.rank_list？
        # 假设之前保存的是 conf.list_rank
        rank_list = self.conf.rank_list 
        
        # 获取 Master 参数（放在 CPU 上以节省显存，如果都在 GPU 则不需要 .cpu()）
        master_model_state_dict = self.master_model.state_dict()

        for selected_client_id in selected_client_ids:
            model = self.client_models[selected_client_id][1] # 取出模型对象
            model.to('cuda')
            # -----------------------------------------------------------
            # 【步骤 1：结构对齐】
            # 在加载参数前，必须先检查模型是否处于分解状态。
            # 如果是分解状态（FactorizedConv），必须先 recover 回 Conv2d，
            # 否则 load_state_dict 会因为 Key 不匹配或形状不匹配而报错。
            # -----------------------------------------------------------
            if "resnet" in self.conf.arch:
                for m in model.modules():
                    if isinstance(m, MetaBasicBlock):
                        # 判断依据：如果 conv1 不是标准的 Conv2d，说明它是分解过的 FactorizedConv
                        if not isinstance(m.conv1, nn.Conv2d):
                            m.recover()
            elif "cnn" in self.conf.arch:
                # if model.meta:
                model.recover_model()
            model.to('cuda')
            # -----------------------------------------------------------
            # 【步骤 2：加载全量参数】
            # 现在 model 结构和 master 一模一样了，可以安全加载
            # -----------------------------------------------------------
            model.load_state_dict(master_model_state_dict)

            # -----------------------------------------------------------
            # 【步骤 3：按需分解】
            # 根据该客户端特定的 rank 进行 SVD 分解
            # -----------------------------------------------------------
            current_rank = rank_list[selected_client_id] # 获取该客户端对应的 rank (或 ratio)
            if "resnet" in self.conf.arch:
                for m in model.modules():
                    if isinstance(m, MetaBasicBlock):
                        # 这里的 decom 内部会执行 SVD 并把 Conv2d 替换为 FactorizedConv
                        m.decom(current_rank)
            elif "cnn" in self.conf.arch:
                model.decom_model(current_rank)
            model.to('cpu')


    # def recover_aggrevate(self, selected_client_ids):
    #     """
    #     1. 遍历 selected_client_ids 中的每个模型。
    #     2. 找到模型中所有的 MetaBasicBlock，调用其 recover() 方法将其恢复为标准卷积。
    #     3. 对恢复后的模型进行参数平均聚合。
    #     4. 返回聚合后的新模型。
    #     """
        
    #     # --- 第一步：恢复所有选中的模型 ---
    #     # 注意：这里会直接修改 self.client_models 中存储的模型对象结构
    #     for client_id in selected_client_ids:
    #         # 获取模型对象 (记得取元组的第2个元素)
    #         model = self.client_models[client_id][1]
            
    #         # 使用 modules() 递归遍历所有子模块，确保涵盖 body 和 personalized 中的所有块
    #         # 这里的 MetaBasicBlock 需要确保你的代码环境中能访问到该类定义
    #         for m in model.modules():
    #             if isinstance(m, MetaBasicBlock):
    #                 # 调用你提供的 recover 方法，它会将 FactorizedConv 替换回 Conv2d
    #                 m.recover()

    #     if not self.conf.train_fast:  # test all the selected_clients
    #         for client_idx in selected_client_ids:
    #             # _arch = self.clientid2arch[client_idx]
    #             # _model_state_dict = copy.deepcopy(self.client_models[client_idx][1].state_dict())
    #             # flatten_local_model.unpack(_model_state_dict.values())
    #             # real_arch = _arch[1] if isinstance(_arch, tuple) else _arch
    #             # _, test_model = create_model.define_model(self.conf, to_consistent_model=False, client_id=client_idx , arch=real_arch)
    #             # test_model.load_state_dict(_model_state_dict)
    #             test_model = copy.deepcopy(self.client_models[client_idx][1])
    #             master_utils.do_validation(
    #                 conf=self.conf,
    #                 coordinator=self.local_coordinator[client_idx],
    #                 model=test_model,
    #                 criterion=self.criterion,
    #                 metrics=self.metrics,
    #                 data_loaders=self.test_loaders,
    #                 label=f"aggregated_test_loader_{client_idx}",
    #             )
    #         self.additional_validation()
    #     # --- 第二步：初始化聚合容器 ---
    #     # 选取第一个模型作为聚合的“底板”
    #     base_client_id = selected_client_ids[0]
    #     base_model = self.client_models[base_client_id][1]
        
    #     # 深拷贝一份 state_dict 用于累加，避免修改原模型数据
    #     global_params = copy.deepcopy(base_model.state_dict())
        
    #     # 将容器清零，准备累加
    #     for key in global_params:
    #         global_params[key].zero_()

    #     # --- 第三步：累加所有模型的参数 ---
    #     for client_id in selected_client_ids:
    #         model = self.client_models[client_id][1]
    #         local_params = model.state_dict()
            
    #         for key in global_params:
    #             # 累加参数
    #             # 注意：需保证所有模型在同一设备上 (CPU/GPU)
    #             global_params[key] += local_params[key]

    #     # --- 第四步：取平均 ---
    #     num_models = len(selected_client_ids)
    #     for key in global_params:
    #         # 区分浮点数参数和整数参数 (如 BatchNorm 的 num_batches_tracked)
    #         if global_params[key].is_floating_point():
    #             global_params[key] /= num_models
    #         else:
    #             val_float = global_params[key].float() / num_models
    #             # 2. 根据该参数原本的类型，决定如何赋值回去
    #             if global_params[key].is_floating_point():
    #                 # 如果原本就是浮点数 (如 weight, bias)，直接赋值
    #                 global_params[key].copy_(val_float)
    #             else:
    #                 # 如果原本是整数 (如 num_batches_tracked)，需要四舍五入后转回整数
    #                 # 使用 .round() 避免地板除的偏差，然后转为 .long()
    #                 global_params[key].copy_(torch.round(val_float).long())

    #     # --- 第五步：构建返回的模型对象 ---
    #     # 我们深拷贝一个已经恢复结构的模型作为载体
    #     aggregated_model = copy.deepcopy(base_model)
    #     # 加载计算好的平均参数
    #     aggregated_model.load_state_dict(global_params)

    #     return aggregated_model

    def recover_aggrevate(self, selected_client_ids):
        """
        1. 遍历 selected_client_ids 中的每个模型。
        2. 找到模型中所有的 MetaBasicBlock，调用其 recover() 方法将其恢复为标准卷积。
        3. 对恢复后的模型进行参数平均聚合。
        4. 返回聚合后的新模型。
        """
        
        # --- 第一步：恢复所有选中的模型 ---
        # 注意：这里会直接修改 self.client_models 中存储的模型对象结构
        # 这一步必须保留，确保聚合的是完整卷积核 W，而不是分解因子 U/V
        for client_id in selected_client_ids:
            # 获取模型对象 (记得取元组的第2个元素)
            model = self.client_models[client_id][1]
            
            # 使用 modules() 递归遍历所有子模块，确保涵盖 body 和 personalized 中的所有块
            # 这里的 MetaBasicBlock 需要确保你的代码环境中能访问到该类定义
            if "resnet" in self.conf.arch:
                for m in model.modules():
                    if isinstance(m, MetaBasicBlock):
                        # 调用你提供的 recover 方法，它会将 FactorizedConv 替换回 Conv2d
                        m.recover()
            elif "cnn" in self.conf.arch:
                model.recover_model()

        # --- 第二步：聚合逻辑 (替换为 ModuleState 方式) ---
        
        # 1. 定义权重 (Origin逻辑: 默认为均匀平均)
        n_selected_clients = len(selected_client_ids)
        weights = [1.0 / n_selected_clients for _ in range(n_selected_clients)]

        # 2. 将所有选中的客户端模型状态封装为 ModuleState 对象
        # 这完全对应 Origin 代码中的 local_states = [ModuleState(...) for ...]
        local_states = []
        for client_id in selected_client_ids:
            # Modified 版本中模型存储在 list 的元组里，取 [1]
            local_model = self.client_models[client_id][1]
            # 关键：使用 deepcopy 确保数据独立，防止引用修改
            # 注意：此时模型已经是 recover() 过的状态，所以提取的是完整的卷积参数
            local_states.append(ModuleState(copy.deepcopy(local_model.state_dict())))

        # 3. 执行加权聚合 (完全照搬 Origin 的数学逻辑)
        # model_state = state[0] * w[0] + state[1] * w[1] + ...
        # ModuleState 内部全精度浮点运算，避免了整数地板除的问题
        model_state = local_states[0] * weights[0]
        
        for idx in range(1, len(local_states)):
            model_state += local_states[idx] * weights[idx]

        # 4. 将聚合后的状态复制回模型对象
        # 取第一个客户端的模型作为结构底板 (template)
        base_client_id = selected_client_ids[0]
        # 注意：这里深拷贝的 base_model 已经是 recover 过的结构（标准卷积）
        aggregated_model = copy.deepcopy(self.client_models[base_client_id][1])
        
        # 使用 ModuleState 自带的 copy_to_module 方法
        # 它会自动处理类型转换 (float -> long) 和设备放置
        model_state.copy_to_module(aggregated_model)

        return aggregated_model

    def load_para2selectedmodels(self, flatten_local_models, selected_client_ids):
        for client_id in selected_client_ids:
            # 获取对应的模型对象 (注意：需确认 self.client_models 的索引方式是否正确)
            # 如果 self.client_models 是列表且长度不够，这里可能会报错，请确保初始化时为每个 client_id 都预留了位置
            if isinstance(self.client_models, list):
                # 假设 client_id 是 1-based，列表是 0-based
                target_model = self.client_models[client_id ][1] 
            elif isinstance(self.client_models, dict):
                target_model = self.client_models[client_id][1]
            else:
                # 根据您的实际结构调整
                target_model = self.client_models[client_id][1]

            # 【修复重点】使用 state_dict().values() 接收所有参数（含 BN 统计量）
            # 获取 buffer 对象
            client_buffer = flatten_local_models[client_id]
            
            # 必须先获取 state_dict 的引用
            target_state_dict = target_model.state_dict()
            
            # 使用 TensorBuffer 自带的 unpack 方法填充 state_dict 的 values
            client_buffer.unpack(target_state_dict.values())
            
            # 将更新后的 state_dict 重新加载回模型（确保数据生效）
            target_model.load_state_dict(target_state_dict)



    def _aggregate_model_and_evaluate(self, flatten_local_models, selected_client_ids):
        # aggregate the local models.
        self.selected_client_ids = selected_client_ids
        aggregated_model = self.aggregate(
            flatten_local_models,
            selected_client_ids
        ) # 计算平均后的模型

        client_models = {0: aggregated_model}

        # self.master_model.load_state_dict(
        #     list(client_models.values())[0].state_dict()

        # )

        # =====================================================================
        # 新增：EMA (Exponential Moving Average) 聚合逻辑
        # =====================================================================
        # 优先从配置项中读取 ema_decay，如果没有设置，默认使用 0.8
        ema_decay = getattr(self.conf, 'ema_decay', 0) 
        self.conf.logger.log(f"Applying EMA to global model updating with decay rate: {ema_decay}")

        global_state_dict = self.master_model.state_dict()
        aggregated_state_dict = aggregated_model.state_dict()
        
        ema_state_dict = {}
        for key in aggregated_state_dict.keys():
            # 确保两个张量在同一个设备上 (防止 GPU 和 CPU tensor 相加报错)
            agg_param = aggregated_state_dict[key].to(global_state_dict[key].device)
            global_param = global_state_dict[key]
            
            # 只对浮点型参数（权重、偏置等）进行 EMA 计算
            if agg_param.dtype.is_floating_point:
                ema_state_dict[key] = ema_decay * global_param + (1.0 - ema_decay) * agg_param
            else:
                # 对于整型参数（例如 BatchNorm 的 num_batches_tracked），直接覆盖
                ema_state_dict[key] = agg_param

        
        self.master_model.load_state_dict(ema_state_dict)
        
                
         # 更新全局模型
        # for arch, _client_model in client_models.items():
        #     self.client_models[arch].load_state_dict(_client_model.state_dict())

        # for arch, _client_model in client_models.items():
        #     # arch 现在是 0
        #     if arch in self.client_models:
        #         target = self.client_models[arch]
                
        #         # 【修复重点】判断是否为元组，如果是，取第2个元素
        #         if isinstance(target, tuple):
        #             target[1].load_state_dict(_client_model.state_dict())
        #         else:
        #             target.load_state_dict(_client_model.state_dict())

        # evaluate the aggregated model on the test data.
        master_utils.do_validation( # 最终评估
            self.conf,
            self.coordinator,
            self.master_model,
            self.criterion,
            self.metrics,
            self.test_loaders,# cifar数据集使用测试集
            # [self.val_loader], # 针对tiny-imagenet，我们只在 val_loader 上评估，因为 test_loader 没有标签
            label=f"aggregated_test_loader_0",
        )

        # self.conf.train_fast=False
        # ================= 新增：记录并保存表现最好的模型 =================
        current_perf = self.coordinator.key_metric.cur_perf
        if not hasattr(self, 'best_perf') or current_perf > self.best_perf:
            self.best_perf = current_perf
            # 深拷贝保存最佳性能时的状态字典
            self.best_model_state_dict = copy.deepcopy(self.master_model.state_dict())
            self.conf.logger.log(f"New best model found with accuracy {self.best_perf:.4f}. Saved for t-SNE visualization.")


        # =================================================================
        if not self.conf.train_fast:  # test all the selected_clients
            for client_idx in selected_client_ids:
                # _arch = self.clientid2arch[client_idx]
                # _model_state_dict = copy.deepcopy(self.client_models[client_idx][1].state_dict())
                # flatten_local_model.unpack(_model_state_dict.values())
                # real_arch = _arch[1] if isinstance(_arch, tuple) else _arch
                # _, test_model = create_model.define_model(self.conf, to_consistent_model=False, client_id=client_idx , arch=real_arch)
                # test_model.load_state_dict(_model_state_dict)
                test_model = copy.deepcopy(self.client_models[client_idx][1])
                master_utils.do_validation(
                    conf=self.conf,
                    coordinator=self.local_coordinator[client_idx],
                    model=test_model,
                    criterion=self.criterion,
                    metrics=self.metrics,
                    data_loaders=self.test_loaders,
                    label=f"aggregated_test_loader_{client_idx}",
                )
            self.additional_validation()


        torch.cuda.empty_cache()
    def additional_validation(self):
        pass

    def _check_early_stopping(self):
        meet_flag = False

        # consider both of target_perf and early_stopping
        if self.conf.target_perf is not None:   # 是否设置目标性能
            assert 100 >= self.conf.target_perf > 0

            # meet the target perf.
            if (
                    self.coordinator.key_metric.cur_perf is not None
                    and self.coordinator.key_metric.cur_perf > self.conf.target_perf
            ):
                self.conf.logger.log("Master early stopping: meet target perf.")
                self.conf.meet_target = True
                meet_flag = True
            # or has no progress and early stop it.
            elif self.early_stopping_tracker(self.coordinator.key_metric.cur_perf):
                self.conf.logger.log(
                    "Master early stopping: not meet target perf but has no patience."
                )
                meet_flag = True
        # only consider the early stopping.
        else:
            if self.early_stopping_tracker(self.coordinator.key_metric.cur_perf):
                meet_flag = True

        if meet_flag:
            # we perform the early-stopping check:
            # (1) before the local training and (2) after the update of the comm_round.
            _comm_round = self.conf.graph.comm_round - 1
            self.conf.graph.comm_round = -1
            self._finishing(_comm_round)

    def _finishing(self, _comm_round=None):
        self.conf.logger.save_json()
        self.conf.logger.log(f"Master finished the federated learning.")
        self.conf.is_finished = True
        self.conf.finished_comm = _comm_round
        checkpoint.save_arguments(self.conf)
        os.system(f"echo {self.conf.checkpoint_root} >> {self.conf.job_id}")


def get_n_local_epoch(conf, n_participated):
    if conf.min_local_epochs is None:
        return [conf.local_n_epochs] * n_participated
    else:
        # here we only consider to (uniformly) randomly sample the local epochs.
        assert conf.min_local_epochs > 1.0
        random_local_n_epochs = conf.random_state.uniform(
            low=conf.min_local_epochs, high=conf.local_n_epochs, size=n_participated
        )
        return random_local_n_epochs
    
class DummyLayer:
    def __init__(self, dtype):
        self.weight = type('DummyTensor', (), {'dtype': dtype})()

class DummyVisual:
    def __init__(self, dtype):
        self.conv1 = DummyLayer(dtype)