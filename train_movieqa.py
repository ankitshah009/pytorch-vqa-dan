import sys
import os.path
import math
import json
import gc
import resource

import torch
import torch.nn as nn
import torch.optim as optim
from torch.autograd import Variable
import torch.backends.cudnn as cudnn
from tqdm import tqdm

import config
import movie
from dan import TextEncoder, MovieDAN
import utils

torch.backends.cudnn.enabled = False

def update_learning_rate(optimizer, iteration):
    lr = config.initial_lr * 0.5**(float(iteration) / config.lr_halflife)
    for param_group in optimizer.param_groups:
        param_group['lr'] = lr

def run(net, dataset, optimizer, train=False, prefix='', epoch=0):
    """ Run an epoch over the given loader """
    if train:
        net.train()
    else:
        net.eval()

    niter = int(len(dataset) / dataset.batch_size)
    tq = tqdm(dataset.loader(), desc='{} E{:03d}'.format(prefix, epoch), ncols=0, total=niter)

    criterion = nn.CrossEntropyLoss().cuda()
   
    total_count = 0
    total_acc = 0
    total_loss = 0
    total_iterations = 0
    
    for q, s, la, c in tq:
        var_params = {
            'requires_grad': False,
        }
#        q = Variable(q.cuda(async=True))
#       	s = Variable(s.cuda(async=True))
#        la = [ Variable(a.cuda(async=True)) for a in la ]
#        c = Variable(c.cuda(async=False)) # correct answers

        q = Variable(q).cuda()
       	s = Variable(s).cuda()
        la = [Variable(a).cuda() for a in la]
        c = Variable(c).cuda() # correct answers

#        import pdb; pdb.set_trace()
        out = net(q, s, la)
        loss = criterion(out, c)

     
        # Compute our own accuracy
        _, pred = out.data.max(dim=1)
        acc = (pred == c.data).float()

        if train:
            update_learning_rate(optimizer, total_iterations)

            optimizer.zero_grad()
            loss.backward()
            optimizer.step()

            total_iterations += 1

        total_count += acc.shape[0]
        total_loss += loss.data[0] * acc.shape[0]
        total_acc += acc.sum()

        for obj in gc.get_objects():
            try:
                if torch.is_tensor(obj) or (hasattr(obj, 'data') and torch.is_tensor(obj.data)):
                    pass
                    #print(type(obj), obj.size())
            except:
                pass

        gc.collect()
#        import pdb; pdb.set_trace()
        
        if total_iterations % 5 == 0:
            max_mem_used = resource.getrusage(resource.RUSAGE_SELF).ru_maxrss
#            print("{:.2f} MB".format(max_mem_used / 1024))
	
    
    acc = total_acc / total_count
    loss = total_loss / total_count
    print("loss: {} acc {}".format(loss, acc))

def main():
    if len(sys.argv) > 1:
        name = ' '.join(sys.argv[1:])
    else:
        from datetime import datetime
        name = datetime.now().strftime("%Y-%m-%d_%H:%M:%S")
    target_name = os.path.join('logs', '{}.pth'.format(name))
    print('will save to {}'.format(target_name))

    cudnn.benchmark = True

    train_dataset = movie.get_dataset(train=True)
    val_dataset = movie.get_dataset(val=True)
    
    # Build Model
    vocab_size = len(train_dataset.vocab)
    model = MovieDAN(num_embeddings=vocab_size, 
                embedding_dim=config.embedding_dim, 
                hidden_size=config.hidden_size, 
                answer_size=config.movie_answer_size)

    net = nn.DataParallel(model).cuda()
    
    optimizer = optim.Adam([p for p in net.parameters() if p.requires_grad])

    config_as_dict = {k: v for k, v in vars(config).items() if not k.startswith('__')}

    for i in range(config.epochs):
        run(net, train_dataset, optimizer, train=True, prefix='train', epoch=i)
        run(net, val_dataset, optimizer, train=False, prefix='val', epoch=i)

if __name__ == '__main__':
    main()
