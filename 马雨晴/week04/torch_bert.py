import torch.nn as nn
from collections import defaultdict
from transformers import BertModel
import torch
import numpy as np
import math

model_path = r"D:\AI大模型课程\第六周 语言模型\week6 语言模型和预训练\下午\bert-base-chinese\google-bert\bert-base-chinese"
bert = BertModel.from_pretrained(model_path, return_dict=False)
state_dict = bert.state_dict()
bert.eval()
x = np.array([2450, 15486, 102, 2110])   #假想成4个字的句子
torch_x = torch.LongTensor([x])          #pytorch形式输入
seqence_output, pooler_output = bert(torch_x)
print(seqence_output.shape, pooler_output.shape)

class diybert:
    def __init__(self,state_dict):
        self.num_attention_heads = 12
        self.hidden_size = 768
        self.num_layers = 12
        self.load_weights(state_dict)

    def load_weights(self, state_dict):
        #embedding部分
        self.word_embeddings = state_dict["embeddings.word_embeddings.weight"]
        self.position_embeddings = state_dict["embeddings.position_embeddings.weight"]
        self.token_type_embeddings = state_dict["embeddings.token_type_embeddings.weight"]
        self.embeddings_layer_norm_weight = state_dict["embeddings.LayerNorm.weight"]
        self.embeddings_layer_norm_bias = state_dict["embeddings.LayerNorm.bias"]
        self.transformer_weights = []
        #transformer部分，有多层
        for i in range(self.num_layers):
            q_w = state_dict["encoder.layer.%d.attention.self.query.weight" % i]
            q_b = state_dict["encoder.layer.%d.attention.self.query.bias" % i]
            k_w = state_dict["encoder.layer.%d.attention.self.key.weight" % i]
            k_b = state_dict["encoder.layer.%d.attention.self.key.bias" % i]
            v_w = state_dict["encoder.layer.%d.attention.self.value.weight" % i]
            v_b = state_dict["encoder.layer.%d.attention.self.value.bias" % i]
            attention_output_weight = state_dict["encoder.layer.%d.attention.output.dense.weight" % i]
            attention_output_bias = state_dict["encoder.layer.%d.attention.output.dense.bias" % i]
            attention_layer_norm_w = state_dict["encoder.layer.%d.attention.output.LayerNorm.weight" % i]
            attention_layer_norm_b = state_dict["encoder.layer.%d.attention.output.LayerNorm.bias" % i]
            intermediate_weight = state_dict["encoder.layer.%d.intermediate.dense.weight" % i]
            intermediate_bias = state_dict["encoder.layer.%d.intermediate.dense.bias" % i]
            output_weight = state_dict["encoder.layer.%d.output.dense.weight" % i]
            output_bias = state_dict["encoder.layer.%d.output.dense.bias" % i]
            ff_layer_norm_w = state_dict["encoder.layer.%d.output.LayerNorm.weight" % i]
            ff_layer_norm_b = state_dict["encoder.layer.%d.output.LayerNorm.bias" % i]
            self.transformer_weights.append([q_w, q_b, k_w, k_b, v_w, v_b, attention_output_weight, attention_output_bias,
                                             attention_layer_norm_w, attention_layer_norm_b, intermediate_weight, intermediate_bias,
                                             output_weight, output_bias, ff_layer_norm_w, ff_layer_norm_b])
        #pooler层
        self.pooler_dense_weight = state_dict["pooler.dense.weight"]
        self.pooler_dense_bias = state_dict["pooler.dense.bias"]
    
    def get_embedding(self, embedding_matrix, x):
        return embedding_matrix[x]
    
    def layer_norm(self, x, w, b):
        mean = x.mean(dim=-1, keepdim=True)
        std = x.std(dim=-1, keepdim=True)
        return (x - mean) / (std + 1e-12) * w + b
    
    def softmax(self, x, dim=-1):
        return torch.softmax(x, dim=dim)
    
    def gelu(self, x):
        return 0.5 * x * (1 + torch.tanh(math.sqrt(2 / math.pi) * (x + 0.044715 * torch.pow(x, 3))))
    
    def embedding_forward(self,x):
        word = self.get_embedding(self.word_embeddings, x)
        position_ids = torch.arange(len(x), dtype=torch.long, device=x.device)
        position = self.get_embedding(self.position_embeddings, position_ids)
        segment_ids = torch.zeros(len(x), dtype=torch.long, device=x.device)
        segment = self.get_embedding(self.token_type_embeddings, segment_ids)
        embedding = word + position + segment
        embedding = self.layer_norm(embedding, self.embeddings_layer_norm_weight, self.embeddings_layer_norm_bias)
        return embedding
    
    #执行全部的transformer层计算
    def all_transformer_layer_forward(self, x):
        for i in range(self.num_layers):
            x = self.single_transformer_layer_forward(x, i)
        return x

    #执行单层transformer层计算
    def single_transformer_layer_forward(self, x, layer_index):
        weights = self.transformer_weights[layer_index]
        #取出该层的参数，在实际中，这些参数都是随机初始化，之后进行预训练
        q_w, q_b, \
        k_w, k_b, \
        v_w, v_b, \
        attention_output_weight, attention_output_bias, \
        attention_layer_norm_w, attention_layer_norm_b, \
        intermediate_weight, intermediate_bias, \
        output_weight, output_bias, \
        ff_layer_norm_w, ff_layer_norm_b = weights
        #self attention层
        attention_output = self.self_attention(x,
                                q_w, q_b,
                                k_w, k_b,
                                v_w, v_b,
                                attention_output_weight, attention_output_bias,
                                self.num_attention_heads,
                                self.hidden_size)
        #bn层，并使用了残差机制
        x = self.layer_norm(x + attention_output, attention_layer_norm_w, attention_layer_norm_b)
        #feed forward层
        feed_forward_x = self.feed_forward(x,
                              intermediate_weight, intermediate_bias,
                              output_weight, output_bias)
        #bn层，并使用了残差机制
        x = self.layer_norm(x + feed_forward_x, ff_layer_norm_w, ff_layer_norm_b)
        return x

    # self attention的计算
    def self_attention(self,
                       x,
                       q_w,
                       q_b,
                       k_w,
                       k_b,
                       v_w,
                       v_b,
                       attention_output_weight,
                       attention_output_bias,
                       num_attention_heads,
                       hidden_size):
        q = torch.matmul(x, q_w.T) + q_b  # shape: [max_len, hidden_size]      W * X + B lINER
        k = torch.matmul(x, k_w.T) + k_b  # shpae: [max_len, hidden_size]
        v = torch.matmul(x, v_w.T) + v_b  # shpae: [max_len, hidden_size]
        attention_head_size = int(hidden_size / num_attention_heads)
        # q.shape = num_attention_heads, max_len, attention_head_size
        q = self.transpose_for_scores(q, attention_head_size, num_attention_heads)
        # k.shape = num_attention_heads, max_len, attention_head_size
        k = self.transpose_for_scores(k, attention_head_size, num_attention_heads)
        # v.shape = num_attention_heads, max_len, attention_head_size
        v = self.transpose_for_scores(v, attention_head_size, num_attention_heads)
        # qk.shape = num_attention_heads, max_len, max_len
        qk = torch.matmul(q, k.swapaxes(1, 2))  
        qk /= math.sqrt(attention_head_size)
        qk = self.softmax(qk)
        # qkv.shape = num_attention_heads, max_len, attention_head_size
        qkv = torch.matmul(qk, v)
        # qkv.shape = max_len, hidden_size
        qkv = qkv.swapaxes(0, 1).reshape(-1, hidden_size)
        # attention.shape = max_len, hidden_size
        attention = torch.matmul(qkv, attention_output_weight.T) + attention_output_bias
        return attention

    #多头机制
    def transpose_for_scores(self, x, attention_head_size, num_attention_heads):
        # hidden_size = 768  num_attent_heads = 12 attention_head_size = 64
        max_len, hidden_size = x.shape
        x = x.view(max_len, num_attention_heads, attention_head_size)
        x = x.permute(1, 0, 2)
        return x

    #前馈网络的计算
    def feed_forward(self,
                     x,
                     intermediate_weight,  # intermediate_size, hidden_size
                     intermediate_bias,  # intermediate_size
                     output_weight,  # hidden_size, intermediate_size
                     output_bias,  # hidden_size
                     ):
        # output shpae: [max_len, intermediate_size]
        x = torch.matmul(x, intermediate_weight.T) + intermediate_bias
        x = self.gelu(x)
        # output shpae: [max_len, hidden_size]
        x = torch.matmul(x, output_weight.T) + output_bias
        return x

    #链接[cls] token的输出层
    def pooler_output_layer(self, x):
        x = torch.matmul(x, self.pooler_dense_weight.T) + self.pooler_dense_bias
        x = torch.tanh(x)
        return x

    #最终输出
    def forward(self, x):
        x = self.embedding_forward(x)
        sequence_output = self.all_transformer_layer_forward(x)
        pooler_output = self.pooler_output_layer(sequence_output[0])
        return sequence_output, pooler_output

db = diybert(state_dict)
diy_sequence_output, diy_pooler_output = db.forward(torch_x.squeeze(0))
#torch
torch_sequence_output, torch_pooler_output = bert(torch_x)

print(diy_sequence_output)
print(torch_sequence_output)
    
