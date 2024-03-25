from enum import Enum
from typing import Dict
import time
import torch
import torch.fx as fx
from typing import Dict, Any


class OP(str, Enum):
    CALL_FUNCTION = "call_function"
    CALL_MODULE = "call_module"
    CALL_METHOD = "call_method"
    GET_ATTR = "get_attr"
    OUTPUT = "output"
    PLACEHOLDER = "placeholder"


class GraphTraversalState(Enum):
    FORWARD = "forward"
    LOSS = "loss"
    BACKWARD = "backward"


# This is an example graph_profiler that extends the fx.Interpreter class, it
# will perform graph execution by running the graph node by node.


class GraphProfiler(fx.Interpreter):
    def __init__(self, module: fx.GraphModule, garbage_collect_values: bool = True):
        super().__init__(module, garbage_collect_values)

        # You should perform the static analysis of the graph here. In
        # particular you might want to find the intermediate
        # nodes/activations/feature_maps in the graph that will be defined as
        # those nodes which are not parameters (not placeholder node types) but
        # are created during the forward pass and are also used in the backward
        # pass for computation. 

        # The boundary between the forward pass and backward pass can be
        # identified by locating the node
        # '%sep : [num_users=1] =
        # call_function[target=torch.ops.separator.sep.default]' which will 
        # define the end of the forward pass. You will see the loss function
        # after thsi operation and then you will encounter a node named,
        # '%sep_backward : [num_users=1] =
        # call_function[target=torch.ops.separator.sep_backward.default]'. This
        # node marks the beginning of the backward pass. 

        # For these intermediate nodes in the graph, you will record their last
        # use in the forward pass and their first use in the backward pass.

        # The parameters of the models are the placeholder (input) nodes of the
        # graph. Note that not all the placeholder nodes of the graph are
        # parameters. The number of parameters of the graphs and the gradients
        # should be equal.

        # You will also see several operators of the type 
        #' %tag_grad :[num_users=1] =
        # call_function[target=torch.ops.dummy.tag_grad.default]'. These are
        # also dummy operations added after every gradient produced in the
        # backward pass. 

        # Printing the input nodes, node users and node names.

        for node in self.module.graph.nodes:
            print ("Node name: ", node.name)
            print ("Node type: ", node.op)
            print ("Node target: ", node.target)
            print ("Input to this node", node.all_input_nodes)
            print ("Users of this node: ", node.users)
            print ("\n")

        self.graph_state = GraphTraversalState.FORWARD
        self.stats_time = {}
        self.stats_memory = {}
        self.first_use_time = {}
        self.last_use_time = {}

    def run(
        self,
        *args,
        initial_env: Dict[fx.Node, Any] | None = None,
        enable_io_processing: bool = True
    ) -> torch.Any:
        return super().run(
            *args, initial_env=initial_env, enable_io_processing=enable_io_processing
        )

    def run_node(self, n: fx.Node) -> Any:
        if n.op == OP.CALL_FUNCTION:
            breakpoint()

        if n.name == "sep":
            # Graph state should move from forward to loss computation
            assert self.graph_state == GraphTraversalState.FORWARD
            self.graph_state = GraphTraversalState.LOSS
        elif n.name == "sep_backward":
            # Graph state should move from loss computation to backward
            assert self.graph_state == GraphTraversalState.LOSS
            self.graph_state = GraphTraversalState.BACKWARD

        # If you are in the backward pass region and one of the feature maps 'x'
        # was swapped out, and if node 'n' will use this feature map 'x' as one
        # of its inputs then you swap 'x' back to the GPU memory here.


        # you can start measuring the run-time of a node here
        if torch.cuda.is_available():
            result = super().run_node(n)
        else:
            start_time = time.time()
            result = super().run_node(n)
            end_time = time.time()
            self.stats_time[n.name] = end_time - start_time
        # you can end measuring the run-time of a node here
        # HINT: Use torch.cuda.Events for doing time measurements of operations.


        # If you are in the forward pass region and if the current node 'n' is
        # the last user of a feature map 'x', then it should be swapped out to
        # the CPU memory here.

        return result
