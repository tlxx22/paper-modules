import torch
import torch.nn as nn
import torch.nn.functional as F
from einops import rearrange


class Inter_CacheModulation(nn.Module):
    def __init__(self, in_c=3):
        super(Inter_CacheModulation, self).__init__()

        self.align = nn.AdaptiveAvgPool2d(in_c)
        self.conv_width = nn.Conv1d(in_channels=in_c, out_channels=2*in_c, kernel_size=1)                                              # 微信公众号:AI缝合术
        self.gatingConv = nn.Conv1d(in_channels=in_c, out_channels=in_c, kernel_size=1)                                              # 微信公众号:AI缝合术

    def forward(self, x1,x2):
        C = x1.shape[-1]
        x2_pW = self.conv_width(self.align(x2)+x1)
        scale,shift = x2_pW.chunk(2, dim=1)
        x1_p = x1*scale+shift
        x1_p = x1_p * F.gelu(self.gatingConv(x1_p))
        return x1_p


class Intra_CacheModulation(nn.Module):
    def __init__(self,embed_dim=48):
        super(Intra_CacheModulation, self).__init__()

        self.down = nn.Conv1d(embed_dim, embed_dim//2, kernel_size=1)
        self.up = nn.Conv1d(embed_dim//2, embed_dim, kernel_size=1)
        self.gatingConv = nn.Conv1d(in_channels=embed_dim, out_channels=embed_dim, kernel_size=1)                                              # 微信公众号:AI缝合术


    def forward(self, x1,x2):
        x_gated = F.gelu(self.gatingConv(x2+x1)) * (x2+x1)
        x_p = self.up(self.down(x_gated))  
        return x_p

class ReGroup(nn.Module):
    def __init__(self, groups=[1,1,2,4]):
        super(ReGroup, self).__init__()
        self.gourps = groups

    def forward(self, query,key,value):
        C = query.shape[1]
        channel_features = query.mean(dim=0)
        correlation_matrix = torch.corrcoef(channel_features)

        mean_similarity = correlation_matrix.mean(dim=1)
        _, sorted_indices = torch.sort(mean_similarity, descending=True) 

        query_sorted = query[:, sorted_indices, :]
        key_sorted = key[:, sorted_indices, :]
        value_sorted = value[:, sorted_indices, :]

        query_groups = []
        key_groups = []
        value_groups = []
        start_idx = 0
        total_ratio = sum(self.gourps)
        group_sizes = [int(ratio / total_ratio * C) for ratio in self.gourps]

        for group_size in group_sizes:
            end_idx = start_idx + group_size
            query_groups.append(query_sorted[:, start_idx:end_idx, :])  
            key_groups.append(key_sorted[:, start_idx:end_idx, :])  
            value_groups.append(value_sorted[:, start_idx:end_idx, :])  
            start_idx = end_idx

        return query_groups,key_groups,value_groups

def CalculateCurrentLayerCache(x,dim=128,groups=[1,1,2,4]):
    lens = len(groups)
    ceil_dim = dim #* max_value // sum_value 
    for i in range(lens):
        qv_cache_f = x[i].clone().detach()
        qv_cache_f=torch.mean(qv_cache_f,dim=0,keepdim=True).detach()
        update_elements = F.interpolate(qv_cache_f.unsqueeze(1), size=(ceil_dim, ceil_dim), mode='bilinear', align_corners=False)                                              # 微信公众号:AI缝合术
        c_i = qv_cache_f.shape[-1]
                
        if i==0:
            qv_cache = update_elements * c_i // dim
        else:
            qv_cache = qv_cache + update_elements * c_i // dim
                
    return qv_cache.squeeze(1)

class Attention(nn.Module):
    def __init__(self, dim, num_heads, bias):
        super(Attention, self).__init__()
        self.num_heads = num_heads
        self.temperature = nn.Parameter(torch.ones(4, 1, 1))

        self.qkv = nn.Conv2d(dim, dim*3, kernel_size=1, bias=bias)
        self.qkv_dwconv = nn.Conv2d(dim*3, dim*3, kernel_size=3, stride=1, padding=1, groups=dim*3, bias=bias)                                              # 微信公众号:AI缝合术
        self.project_out = nn.Conv2d(dim, dim, kernel_size=1, bias=bias)
        self.group =[1,2,2,3] 

        self.intra_modulator = Intra_CacheModulation(embed_dim=dim)

        self.inter_modulator1 = Inter_CacheModulation(in_c=1*dim//8)
        self.inter_modulator2 = Inter_CacheModulation(in_c=2*dim//8)
        self.inter_modulator3 = Inter_CacheModulation(in_c=2*dim//8)
        self.inter_modulator4 = Inter_CacheModulation(in_c=3*dim//8)
        self.inter_modulators = [self.inter_modulator1,self.inter_modulator2,self.inter_modulator3,self.inter_modulator4]                                              # 微信公众号:AI缝合术

        self.regroup = ReGroup(self.group)
        self.dim=dim

    def forward(self, x ,qv_cache=None):
        b,c,h,w = x.shape

        qkv = self.qkv_dwconv(self.qkv(x))
        q,k,v = qkv.chunk(3, dim=1)   
    
        q = rearrange(q, 'b c h w -> b c (h w)')
        k = rearrange(k, 'b c h w -> b c (h w)')
        v = rearrange(v, 'b c h w -> b c (h w)')

        qu,ke,va = self.regroup(q,k,v)
        attScore = []
        tmp_cache=[]
        for index in range(len(self.group)):

            query_head = qu[index]
            key_head   = ke[index]

            query_head = torch.nn.functional.normalize(query_head, dim=-1)
            key_head = torch.nn.functional.normalize(key_head, dim=-1)

            attn = (query_head @ key_head.transpose(-2, -1)) * self.temperature[index,:,:]                                              # 微信公众号:AI缝合术
            attn = attn.softmax(dim=-1)

            attScore.append(attn)#CxC
            t_cache = query_head.clone().detach()+key_head.clone().detach()
            tmp_cache.append(t_cache)
        
        tmp_caches = torch.cat(tmp_cache, 1)
        # Inter Modulation
        out=[]
        if qv_cache is not None:
            if qv_cache.shape[-1]!=c:
                
                qv_cache = F.adaptive_avg_pool2d(qv_cache,c)
        for i in range(4):
            if qv_cache is not None:
                inter_modulator = self.inter_modulators[i]
                attScore[i] = inter_modulator(attScore[i],qv_cache)+attScore[i]
                out.append(attScore[i] @ va[i])
            else:
                out.append(attScore[i] @ va[i])
                
        update_factor=0.9
        if qv_cache is not None:
            
            update_elements = CalculateCurrentLayerCache(attScore,c,self.group)
            qv_cache = qv_cache*update_factor + update_elements*(1-update_factor)
        else:
            qv_cache = CalculateCurrentLayerCache(attScore,c,self.group)
            qv_cache = qv_cache*update_factor

        out_all = torch.concat(out, 1)
        # Intra Modulation
        out_all = self.intra_modulator(out_all,tmp_caches)+out_all

        out_all = rearrange(out_all, 'b  c (h w) -> b c h w', h=h, w=w)
        out_all = self.project_out(out_all)
        return [out_all,qv_cache]
    

if __name__ == "__main__":
    # 模拟输入参数
    batch_size = 1
    channels = 64           # 输入通道数
    height, width = 32, 32  # 输入特征图大小
    num_heads = 4
    bias = True

    # 构造输入张量
    x = torch.randn(batch_size, channels, height, width)

    # 初始化 Attention 模块
    attention_module = Attention(dim=channels, num_heads=num_heads, bias=bias)

    # 前向传播测试（不带缓存）
    output, updated_cache = attention_module(x)

    # 打印输出
    print(attention_module)
    print("\n微信公众号:AI缝合术\n")
    print("输入张量形状:", x.shape)           # [B, C, H, W]
    print("输出张量形状:", output.shape)     # [B, C, H, W]
    print("更新后的缓存张量形状:", updated_cache.shape)  # [1, H, W] or [1, C, H, W] depending on pooling/interpolation                                              # 微信公众号:AI缝合术
