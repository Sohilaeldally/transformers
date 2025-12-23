import torch
import torch.nn as nn
from torch.utils.data import Dataset

class BilingualDataset(Dataset):
    def __init__(self,ds,tokenizer_src,tokenizer_tgt,src_lang,tgt_lang,seq_len):
        super().__init__()

        self.ds=ds
        self.toknizer_src=tokenizer_src
        self.tokenizer_tgt=tokenizer_tgt
        self.src_lang=src_lang
        self.tgt_lang=tgt_lang
        self.seq_len=seq_len

        self.sos_token=torch.tensor([tokenizer_tgt.token_to_id("[SOS]")],dtype=torch.int64)
        self.eos_token=torch.tensor([tokenizer_tgt.token_to_id("[EOS]")],dtype=torch.int64)
        self.pad_token=torch.tensor([tokenizer_tgt.token_to_id("[PAD]")],dtype=torch.int64)

    def __len__(self):
        return len(self.ds)
    
    def __getitem__(self, idx):
        src_tgt_pair=self.ds[idx]
        src_text=src_tgt_pair['translation'][self.src_lang]
        tgt_text=src_tgt_pair['translation'][self.tgt_lang]
        
        # transform the text into tokens
        enc_input_tokens=self.toknizer_src.encode(src_text).ids
        dec_input_tokens=self.tokenizer_tgt.encode(tgt_text).ids
        
        # Add sos, eos and padding to each sentence
        enc_num_padding_tokens = self.seq_len - len(enc_input_tokens) - 2 # we will add <s> and </s>
        dec_num_padding_tokens = self.seq_len - len(dec_input_tokens) - 1 # we will only add <s>,and </s> only on the label
 

        # number is padding is not negative. if it is ,the sentence is too long
        if enc_num_padding_tokens < 0 or dec_num_padding_tokens <0 :
            raise ValueError("Sentence is too long") 
        # Add <s> and </s>
        incoder_input = torch.cat(
            [
                self.sos_token,
                torch.tensor(enc_input_tokens,dtype=torch.int64),
                self.eos_token,
                torch.tensor([self.pad_token]*enc_num_padding_tokens,dtype=torch.int64)
            ],
            dim=0
        )
        # Add only <s> otken
        decoder_input = torch.cat(
            [
                self.sos_token,
                torch.tensor(dec_input_tokens,dtype=torch.int64),
                torch.tensor([self.pad_token]*dec_num_padding_tokens,dtype=torch.int64)
            ],
            dim=0
        )
        # Add only </s> otken
        label = torch.cat(
            [
                torch.tensor(dec_input_tokens,dtype=torch.int64),
                self.eos_token,
                torch.tensor([self.pad_token]*dec_num_padding_tokens,dtype=torch.int64)
            ],
            dim=0
        )

        assert incoder_input.size(0) == self.seq_len
        assert decoder_input.size(0) == self.seq_len
        assert label.size(0) == self.seq_len

        return {
            "encoder_input" : incoder_input, # (seq_len)
            "decoder_input" : decoder_input, # (seq_len)    
            "encoder_mask"  : (incoder_input !=  self.pad_token).unsqueeze(0).unsqueeze(0).int, # (1,1,seq_len)
            "decoder_mask" : (decoder_input != self.pad_token).unsqueeze(0).int() & causal_mask(decoder_input.size(0)) ,  # (1,seq_len) & (1,seq_len,seq_len)
        }

def causal_mask(size):
   mask =torch.triu(torch.ones(1,size,size),diagonal=1).int()
   return mask == 0