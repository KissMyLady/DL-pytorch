# coding:utf-8
# Author:mylady
# Datetime:2023/4/24 6:09
import torch
from torch import nn

import sys

sys.path.append(".")
sys.path.append("../..")
from d2lzh_pytorch.attention.transformer_unit import EncoderBlock


def get_tokens_and_segments(tokens_a, tokens_b=None):
    """Get tokens of the BERT input sequence and their segment IDs.
       获取BERT输入序列的词元及其段IDs。
    Defined in `sec_bert`

    定 义: 14.8 来自Transformers的双向编码器表示（BERT）
    简 介: 获取输入序列的词元及其片段索引
    作 用: 将一个句子或两个句子作为输入, 然后返回BERT输入序列的标记及其相应的片段索引

    """
    tokens = ['<cls>'] + tokens_a + ['<sep>']
    # 0 and 1 are marking segment A and B, respectively
    # 返回[0, 0, .., 1, 1, ..] 分别标记片段A和B
    segments = [0] * (len(tokens_a) + 2)
    if tokens_b is not None:
        tokens += tokens_b + ['<sep>']
        segments += [1] * (len(tokens_b) + 1)
    return tokens, segments


class BERTEncoder(nn.Module):
    """BERT encoder.
    Defined in `subsec_bert_input_rep`

    名 称: BERT编码器
    定 义: 14.8 来自Transformers的双向编码器表示（BERT）
    简 介: 与TransformerEncoder不同, BERTEncoder使用片段嵌入和可学习的位置嵌入。

    """

    def __init__(self, vocab_size, num_hiddens, norm_shape, ffn_num_input,
                 ffn_num_hiddens, num_heads, num_layers, dropout,
                 max_len=1000, key_size=768, query_size=768, value_size=768,
                 **kwargs):
        super(BERTEncoder, self).__init__(**kwargs)
        self.token_embedding = nn.Embedding(vocab_size, num_hiddens)
        self.segment_embedding = nn.Embedding(2, num_hiddens)
        self.blks = nn.Sequential()
        for i in range(num_layers):
            self.blks.add_module(f"{i}", EncoderBlock(key_size, query_size, value_size, num_hiddens, norm_shape,
                                                      ffn_num_input, ffn_num_hiddens, num_heads, dropout, True))
        # 在BERT中, 位置嵌入是可学习的, 因此我们创建一个足够长的位置嵌入参数
        self.pos_embedding = nn.Parameter(torch.randn(1, max_len,
                                                      num_hiddens))

    def forward(self, tokens, segments, valid_lens):
        # 在以下代码中, X的形状保持不变:（批量大小，最大序列长度，num_hiddens）
        X = self.token_embedding(tokens) + self.segment_embedding(segments)
        X = X + self.pos_embedding.data[:, :X.shape[1], :]
        for blk in self.blks:
            X = blk(X, valid_lens)
        return X


class MaskLM(nn.Module):
    """
    名 称: BERT的掩蔽语言模型任务
    定 义: 14.8 来自Transformers的双向编码器表示（BERT）
    """
    def __init__(self, vocab_size, num_hiddens, num_inputs=768, **kwargs):
        super(MaskLM, self).__init__(**kwargs)
        self.mlp = nn.Sequential(nn.Linear(num_inputs, num_hiddens),
                                 nn.ReLU(),
                                 nn.LayerNorm(num_hiddens),
                                 nn.Linear(num_hiddens, vocab_size))

    def forward(self, X, pred_positions):
        num_pred_positions = pred_positions.shape[1]
        pred_positions = pred_positions.reshape(-1)
        batch_size = X.shape[0]
        batch_idx = torch.arange(0, batch_size)
        # 假设batch_size=2，num_pred_positions=3 那么batch_idx是np.array（[0,0,0,1,1,1]）
        batch_idx = torch.repeat_interleave(batch_idx, num_pred_positions)
        masked_X = X[batch_idx, pred_positions]
        masked_X = masked_X.reshape((batch_size, num_pred_positions, -1))
        mlm_Y_hat = self.mlp(masked_X)
        return mlm_Y_hat


class NextSentencePred(nn.Module):
    """The next sentence prediction task of BERT.
    Defined in `subsec_mlm`
    定 义: 14.8 BERT的掩蔽语言模型任务
    功 能: BERT的下一句预测任务

    """
    def __init__(self, num_inputs, **kwargs):
        super(NextSentencePred, self).__init__(**kwargs)
        self.output = nn.Linear(num_inputs, 2)

    def forward(self, X):
        # X的形状：(batchsize,num_hiddens)
        return self.output(X)


class BERTModel(nn.Module):
    """The BERT model.
    Defined in `subsec_nsp`

    定 义: 14.8 来自Transformers的双向编码器表示
    功 能: 对BERT封装

    """
    def __init__(self, vocab_size, num_hiddens, norm_shape,
                 ffn_num_input, ffn_num_hiddens,
                 num_heads, num_layers,
                 dropout,
                 max_len=1000,
                 key_size=768, query_size=768, value_size=768,
                 hid_in_features=768,
                 mlm_in_features=768,
                 nsp_in_features=768):

        super(BERTModel, self).__init__()
        self.encoder = BERTEncoder(vocab_size,
                                   num_hiddens, norm_shape,
                                   ffn_num_input, ffn_num_hiddens,
                                   num_heads, num_layers,
                                   dropout,
                                   max_len=max_len,
                                   key_size=key_size,
                                   query_size=query_size,
                                   value_size=value_size
                                   )

        self.hidden = nn.Sequential(
            nn.Linear(hid_in_features, num_hiddens),
            nn.Tanh())
        self.mlm = MaskLM(vocab_size, num_hiddens, mlm_in_features)
        self.nsp = NextSentencePred(nsp_in_features)

    def forward(self, tokens, segments, valid_lens=None, pred_positions=None):
        encoded_X = self.encoder(tokens, segments, valid_lens)
        if pred_positions is not None:
            mlm_Y_hat = self.mlm(encoded_X, pred_positions)
        else:
            mlm_Y_hat = None
        # 用于下一句预测的多层感知机分类器的隐藏层，0是“<cls>”标记的索引
        nsp_Y_hat = self.nsp(self.hidden(encoded_X[:, 0, :]))
        return encoded_X, mlm_Y_hat, nsp_Y_hat

def main():
    pass


if __name__ == '__main__':
    main()
